# analysis paper tex preaudit — Part 1 of 2

**Observe but Don’t Optimize: Structural Rewards Trigger Goodhart Effects in Neurosymbolic Reasoning** · Worker execution logs

[Transcript overview](../analysis-paper-tex-preaudit.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/08/089e3b3d919628dad423.json)

## Before a recorded user message

## Before a recorded user message

17 recorded events


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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
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
    "mcp__agent-ml-research__detect_image",
    "mcp__agent-ml-research__kill_job",
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
  "uuid": "2c43dfcd-c678-414b-b495-2d608058c722",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/memory/"
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
    "resetsAt": 1778872200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "bfac0eaa-dd51-46c0-a7e3-6e4b4a036505",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the registry and the paper framing document, then SSH to read the TeX files. I'll do the first two in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "ea805419-b548-4a6a-9b3e-696e3bfea6a7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qyb41fyrNS7iWv9dLYXboh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13654,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13654
      },
      "output_tokens": 22,
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

开始论文数字一致性预审。先并行获取 registry 数据和 paper_framing.md。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "585700a4-ee4a-4621-bf40-3468c306671e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qyb41fyrNS7iWv9dLYXboh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13654,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13654
      },
      "output_tokens": 22,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01AXgVqZ3fyQA3pXcWpKnTeL`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__ssh_execute",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "5ea33183-e7c9-4ca8-bc7a-8793cd6e7c08",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qyb41fyrNS7iWv9dLYXboh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13654,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13654
      },
      "output_tokens": 22,
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

_source line 7 · 2026-05-15T14:55:42.910Z_

<details><summary>↩ Tool result · `toolu_01AXgVqZ3fyQA3pXcWpKnTeL`</summary>

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

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_read_only"
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
  "tool_name": "mcp__agent-ml-research__ssh_execute"
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "6dc03c5a-8ac5-45ad-889f-9957a59fea03",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__ssh_execute"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__ssh_execute",
    "total_deferred_tools": 29
  }
}
```

</details>

---


### Tool call

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01UrMsLEfTrtn4ZJEqgVYGNC`</summary>

```json
{
  "fields": [
    "*"
  ],
  "limit": 0,
  "project": "solver-trace-ablation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "3d5760de-e9fa-4fdc-9cf3-ec55b430344d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C3knBaWYvdYqAGNqehCL1K",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2043,
      "cache_read_input_tokens": 25495,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2043
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

_source line 9 · 2026-05-15T14:55:46.434Z_

<details><summary>↩ Tool result · `toolu_01UrMsLEfTrtn4ZJEqgVYGNC`</summary>

```text
Error: result (186,152 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "f1f37702-9847-4257-bd7a-1e25685569d5",
  "tool_use_result": {
    "content": "Error: result (186,152 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan002-additive-b01-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:17.298Z\", \"updated_at\": \"2026-05-15T14:39:36.660Z\", \"hypothesis\": \"ISR β=0.1 seed=44 多 seed 验证：exec-only s44 是 tautological collapse (PR=98%, ISR=0.57 fake)，ISR β=0.1 能否防止 tautological collapse？3-seed mean±std 用于论文 Claim 2。\", \"parent\": \"plan002-additive-b01-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T08:45:11.826Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s44\\\"\", \"finished_at\": \"2026-05-14T09:28:10.836Z\", \"training_hours\": 0.72}, \"spec\": {\"command\": \"python3 scripts/train_grpo.py --mode additive_bonus --isr_beta 0.1 --seed 44\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"466540\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s44.log\", \"submitted_at\": \"2026-05-14T08:46:23.037Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"wall_clock_seconds\": 2950.3, \"gpu_hours\": 0.82}, \"pid\": \"466540\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:28:12.416418+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.89, \"eval_mean_isr\": 0.803, \"eval_isr_std\": null, \"eval_proved_only_isr\": 0.902, \"eval_n_proved\": 89, \"eval_n_problems\": 100, \"h7_count\": 89, \"h7_rate\": 1, \"h1_count\": 0, \"h1_rate\": 0, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 0, \"genuine_rate\": 0, \"component_mean\": 4.33, \"comp_2_ratio\": 0.022, \"h7_fn_correction\": \"12 former genuine reclassified as H7: all n_prem=1 false negatives (normalization mismatch prevented conclusion matching)\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s44\", \"notes\": \"H7 FN correction: 12 samples with n_prem=1 misclassified as genuine. Mismatch types: 11 vacuous_quantifier_wrapping (∃x(P(x)) vs ∃x(∃y(P(y)))), 1 structural_simplification. Not simple whitespace/case but logically equivalent structural variants. Evidence file: /root/autodl-tmp/outputs/isr_s44_fn_evidence.json. Source eval: /root/runs/solver-trace-ablation/plan002-additive-b01-s44-eval.json\", \"completed_at\": \"2026-05-14T09:35:33.310Z\", \"h7_count\": 77, \"h1_count\": 0, \"genuine_count\": 12, \"h7_fn_correction\": \"vacuous quantifier wrapping (11/12) + structural simplification (1/12); model-learned obfuscation, not classifier bug\", \"h7a_count\": 77, \"h7b_count\": 12, \"taxonomy_note\": \"D085 H7a/H7b split: 77 H7a (text-match) + 12 H7b (obfuscated: 11 vacuous quantifier wrapping auto-detected + 1 structural simplification folio_304 manually confirmed tautological per FN evidence). genuine=0. Script: /root/solver-trace-ablation/scripts/classify_h7.py\"}, \"plan002-additive-b01-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T05:29:08.138Z\", \"updated_at\": \"2026-05-15T14:38:00.829Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"262261\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42.log\", \"submitted_at\": \"2026-05-14T05:32:32.415Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"plan002\", \"reward_formula\": \"r_exec * (1 + 0.1 * ISR)\", \"num_steps\": 500, \"wall_clock_seconds\": 4493.9, \"gpu_hours\": 1.25, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s42\"}, \"parent\": \"plan002-additive-b03-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"262261\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42\\\"\", \"finished_at\": \"2026-05-14T06:37:58.285Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T06:37:59.656631+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"eval_prove_rate\": 0.81, \"eval_mean_isr\": 0.3365, \"eval_isr_std\": 0.3227, \"eval_proved_only_isr\": 0.4154, \"eval_median_isr\": 0.2, \"eval_n_proved\": 81, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_component_count_mean\": 5.58, \"h7_rate\": 0.16, \"h7_count\": 13, \"h1_rate\": 0.519, \"h1_count\": 42, \"h8_conjunction_collapse_count\": 12, \"h8_conjunction_collapse_rate\": 0.148, \"genuine_rate\": 0.173, \"genuine_count\": 14, \"tautological_collapse\": false, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse audit completed. 12/81 proved samples are H8. Genuine 26→14 (32.1%→17.3%). H8 JSON at /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json\"}, \"notes\": \"H8 re-audit (2026-05-15): 81 proved samples. H7 (single premise=conclusion): 13/81=16.1%, H1 (multi-prem conclusion embedding): 42/81=51.9%, H8 (conjunction collapse): 12/81=14.8%, content-independent: 19/81=23.5%. Genuine (proved - H7 - H1 - H8): 14/81=17.3%. Pre-H8 genuine was 26/81=32.1% — H8 removed 12 samples. Combined conclusion duplication+conjunction = 82.7%. Eval source: proofwriter_fol_100.jsonl (backup at /root/autodl-tmp/eval_results_backup/). H8 JSON: /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json. ⚠️ RECLASSIFIED negative (Reviewer WARNING): 500步快照 genuine 30.9%（H8 未扣除，为上界），1000步崩塌至 2.2%，表明 Goodhart collapse 已在 500 步启动但未完成。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s42\", \"completed_at\": \"2026-05-14T06:47:26.358Z\", \"genuine_count\": 14, \"h1_near_count\": null, \"taxonomy_note\": \"H1-near analysis infeasible: eval_sta deleted; genuine=14 computed from aggregated H7+H1_exact+H8 exclusion per D084. H1-near is supplementary-only (per-sample data available only for Random s42).\"}, \"plan002-additive-b01-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:08:50.639Z\", \"updated_at\": \"2026-05-15T14:32:57.668Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode execution_sta --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"171076\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42-1000.log\", \"submitted_at\": \"2026-05-15T07:29:48.253Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4944.1, \"gpu_hours\": 1.37}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"171076\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42-1000.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode execution_sta --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T08:44:46.526Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T08:44:51.343174+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s42_1000\", \"metrics\": {\"eval_prove_rate\": 0.9, \"eval_mean_isr\": 0.7892, \"eval_isr_std\": 0.3424, \"eval_proved_only_isr\": 0.8769, \"eval_median_isr\": 1, \"eval_n_proved\": 90, \"eval_n_problems\": 100, \"eval_component_count_mean\": 2.889, \"tautological_collapse\": true, \"train_final_prove_rate\": 0.855, \"train_final_mean_isr\": 0.532, \"h7_count\": 87, \"h7_rate\": 0.9667, \"h1_count\": 0, \"h1_rate\": 0, \"h1_near_count\": 1, \"h1_near_rate\": 0.0111, \"h8_conjunction_collapse_count\": 2, \"h8_conjunction_collapse_rate\": 0.0222, \"genuine_count\": 1, \"genuine_rate\": 0.0111, \"taxonomy_standard\": \"D084: genuine = proved - H7 - H1_exact - H8\", \"taxonomy_note\": \"2026-05-15 D084 re-audit: H7 83→87 (deeper paren normalization), H1_exact 4→0 (reclassified as H7), H8 1→2 (+folio_1255 shared-antecedent conjunction), genuine 2→1. H1_near=1 (folio_990, retained as genuine per C013). Taxonomy JSON: /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000_taxonomy_unified.json\"}, \"completed_at\": \"2026-05-15T08:52:12.385Z\", \"genuine_count\": 1, \"genuine_rate\": 0.0111, \"h8_count\": 2, \"notes\": \"D084 taxonomy re-audit (2026-05-15): 90 proved → H7=87 (96.7%), H1_exact=0, H1_near=1, H8=2 (2.2%), genuine=1 (1.1%). Changes vs prior: H7 +4 (paren normalization), H1 -4→0 (reclassified H7), H8 +1 (folio_1255 shared-antecedent conjunction missed), genuine -1. Tautological collapse confirmed. Taxonomy JSON: /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000_taxonomy_unified.json\"}, \"plan002-additive-b01-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:16.367Z\", \"updated_at\": \"2026-05-15T14:27:04.296Z\", \"hypothesis\": \"ISR β=0.1 seed=43 多 seed 验证：plan002-b01-s42 (PR=0.81, ISR=0.337) 在 s43 下是否可复现？exec-only s43 是 degraded seed (PR=14%)，ISR β=0.1 能否拯救 bad seed？3-seed mean±std 用于论文 Claim 2 统计支撑。\", \"parent\": \"plan002-additive-b01-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T08:45:10.999Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43\\\"\", \"finished_at\": \"2026-05-14T09:41:23.932Z\", \"training_hours\": 0.94}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"466128\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s43.log\", \"submitted_at\": \"2026-05-14T08:45:54.837Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4096.6, \"gpu_hours\": 1.14}, \"pid\": \"466128\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s43.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:41:25.536028+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.61, \"eval_n_proved\": 61, \"eval_n_problems\": 100, \"eval_proved_only_isr\": 0.83, \"h7_count\": 59, \"h7_rate\": 0.9672, \"h1_count\": 0, \"h1_rate\": 0, \"h1_near_count\": 0, \"h1_near_rate\": 0, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 2, \"genuine_rate\": 0.0328, \"proved_single_premise_ratio\": 1, \"taxonomy_note\": \"structurally determined: proved_single_premise_ratio=1.0, all taxonomy categories except H7 are zero by construction. eval file lost but classification derivable from structure.\"}, \"conclusion\": \"negative\", \"notes\": \"NEGATIVE: conclusion duplication hacking 确认。100% proved 样本仅 1 premise，97% premise=conclusion（重言式 P→P）。ISR=0.506 是 artifact（唯一 premise 必然 necessary）。与 s44 相同失败模式。3-seed 中 s42 唯一可能 genuine（待验证），s43/s44 均 collapse。β=0.1 additive bonus 多 seed 可靠性不足。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s43/checkpoint-500\", \"completed_at\": \"2026-05-14T09:54:11.468Z\", \"h7_count\": 59, \"h1_count\": 0, \"genuine_count\": 2}, \"plan002-additive-b01-s43-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:21:58.445Z\", \"updated_at\": \"2026-05-15T14:21:58.445Z\", \"spec\": {\"hypothesis\": \"ISR β=0.1 seed=43 重训（r2）：原始实验 checkpoint+eval 全部丢失，registry 有 genuine=2/h7=59 但缺 h1/h8。重训+完整 eval+H7/H1/H8 taxonomy，补全所有字段。\", \"parent\": \"plan002-additive-b01-s43\", \"server\": \"westd-39279\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"reward_formula\": \"r = r_exec * (1 + 0.1 * ISR)\", \"plan_id\": \"plan002\", \"num_steps\": 500}}, \"plan018-additive-random-b01-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:55:48.888Z\", \"updated_at\": \"2026-05-15T14:21:07.952Z\", \"hypothesis\": \"β=0.1 random control: r = r_exec·(1+0.1·random[0,1]). 与 plan002-b01 (additive ISR β=0.1, PR=0.81, ISR=0.337) 同 β 对照。如果 ISR β=0.1 >> random β=0.1 → ISR 信号在低剂量下有结构价值; 如果 ISR ≈ random → ISR 信号在低剂量下也仅是 variance regularization。D031 紧急实验。\", \"parent\": \"plan002-additive-b01-s42\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"377678\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42.log\", \"submitted_at\": \"2026-05-14T06:55:59.287Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"plan018\", \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"num_steps\": 500, \"checkpoint_source\": \"N/A (training, not eval)\", \"eval_data\": \"N/A (training, not eval)\", \"wall_clock_seconds\": 5160.4, \"gpu_hours\": 1.43, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T08:09:07.662Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T08:09:09.188407+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"eval_prove_rate\": 0.79, \"eval_mean_isr\": 0.1038, \"eval_isr_std\": 0.1369, \"eval_median_isr\": 0.0357, \"eval_proved_only_isr\": 0.1314, \"eval_n_proved\": 79, \"eval_n_problems\": 100, \"tautological_collapse\": false, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 56, \"h1_rate\": 0.7089, \"h1_near_count\": 8, \"h1_near_rate\": 0.1013, \"h8_conjunction_collapse_count\": 3, \"h8_conjunction_collapse_rate\": 0.038, \"genuine_count_exact_h1\": 23, \"genuine_rate_exact_h1\": 0.2911, \"genuine_count_strict\": 12, \"genuine_rate_strict\": 0.1519, \"taxonomy_verification\": \"2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12).\"}, \"notes\": \"Random control β=0.1 vs ISR β=0.1 (plan002-b01) 对照。conclusion=negative: random control的ISR远低于ISR-guided。\\n\\n对比 plan002-b01 (ISR β=0.1):\\n- PR: 0.79 vs 0.81 (≈持平, Δ=0.02)\\n- Mean ISR: 0.104 vs 0.337 (ISR 3.2x higher)\\n- Proved-only ISR: 0.131 vs 0.415 (ISR 3.2x higher)\\n- Median ISR: 0.036 vs plan002未记录\\n- Component count: 8.46 vs 5.58 (random组更多冗余)\\n- ISR=0占比(proved): 36.7% (random组大量proof无结构)\\n- Tautological collapse: 无 (component_2_ratio=0)\\n\\n关键发现: PR几乎相同说明β=0.1 random噪声不影响证明能力。但ISR差3.2倍，证明ISR reward提供genuine structural guidance而非仅variance regularization。这强力支持Claim 2: ISR信号在低剂量下有结构价值。\\n\\nEval output: /root/autodl-tmp/outputs/plan018_additive_random_b01_s42/eval_results.json\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42\", \"completed_at\": \"2026-05-14T08:21:59.737Z\", \"h7_count\": 0, \"h1_count\": 56, \"genuine_count\": 23}, \"plan018-additive-random-b01-s44-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:17:54.315Z\", \"updated_at\": \"2026-05-15T14:18:24.439Z\", \"spec\": {\"hypothesis\": \"Random β=0.1 s44 重训(r2): 原实验数据全部丢失(eval+checkpoint)，genuine=18 从未直接测量。重训以获取可溯源的 genuine 分解数据。训练参数与原实验完全一致。\", \"parent\": \"plan018-additive-random-b01-s44\", \"server\": \"westd-39279\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"plan_id\": \"plan018\", \"num_steps\": 500, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s44_r2\\\"\"}}, \"plan018-additive-random-b01-s43-r3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:17:51.220Z\", \"updated_at\": \"2026-05-15T14:18:20.461Z\", \"spec\": {\"hypothesis\": \"Random β=0.1 s43 重训(r3): 原 r2 数据全部丢失(eval+checkpoint)，重训以恢复论文所需的 genuine 溯源数据。训练参数与 r2 完全一致。\", \"parent\": \"plan018-additive-random-b01-s43-r2\", \"server\": \"westd-39279\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"plan_id\": \"plan018\", \"num_steps\": 500, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r3\\\"\"}}, \"exp1-isr-b03-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:52:06.992Z\", \"updated_at\": \"2026-05-15T14:15:06.019Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"β=0.3 ISR seed 43: supplement for 3-seed statistics in Table 1. Reference: plan002-additive-b03-s42\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * ISR)\", \"num_steps\": 500, \"beta\": 0.3, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"963576\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43/checkpoint-500/\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:07:44.402Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:07:45.360Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:07:50.234603+00:00\"}]}, \"notes\": \"D062/D063 INVALIDATED: eval used test_100.jsonl (wrong test set). Checkpoint deleted, cannot re-eval. Retrain as exp1-isr-b03-s43-r4.\", \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.91, \"mean_isr\": 0.2575, \"isr_std\": 0.2363, \"median_isr\": 0.3333, \"proved_only_mean_isr\": 0.283, \"hacking_rate_strict_h7\": 0.022, \"hacking_rate_functional\": 0.3297, \"genuine_rate\": 0.6703, \"genuine_count\": 61, \"n_proved\": 91, \"n_problems\": 100, \"h1_conclusion_in_premise\": 0.747, \"eval_data\": \"test_100.jsonl\", \"eval_output\": \"/root/autodl-tmp/outputs/eval_sta_exp1_isr_b03_s43.json\"}, \"eval_metrics\": {\"prove_rate\": 0.91, \"mean_isr\": 0.2575, \"isr_std\": 0.2363, \"proved_only_isr\": 0.283, \"n_proved\": 91, \"h7_rate\": 0.022, \"h7_count\": 2, \"h1_rate\": 0.747, \"h1_count\": 68, \"genuine_rate\": 0.231, \"genuine_count\": 21, \"single_premise_rate\": 0.044, \"eval_data\": \"test_100.jsonl\"}, \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s43.log\"}, \"plan009-sft-baseline-s44-1000-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:55:38.775Z\", \"updated_at\": \"2026-05-15T14:14:37.264Z\", \"hypothesis\": \"SFT 1000步 seed=44（第三次重试）：r1/r2 均因 --gpu 0 覆盖 CUDA_VISIBLE_DEVICES 导致 OOM。本次用 --gpu 1 直接指定物理 GPU 1。验证 SFT 在 1000 步的 genuine rate 稳定性，完成 3-seed 统计。\", \"parent\": \"plan009-sft-baseline-s44-1000-r2\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44}, \"pid\": \"353656\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 1\\\"\", \"finished_at\": \"2026-05-15T13:24:08.251Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:24:12.025706+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.15, \"eval_n_proved\": 15, \"eval_n_problems\": 100, \"eval_mean_isr\": 0.0884, \"eval_isr_std\": 0.2268, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5892, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_method\": \"eval_sta.py full STA\", \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 1, \"h1_rate\": 0.0667, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 14, \"genuine_rate\": 0.9333, \"eval_by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 15, \"prove_rate\": 0.441, \"mean_isr\": 0.26}, \"false\": {\"count\": 25, \"proved\": 0, \"prove_rate\": 0, \"mean_isr\": 0}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0, \"mean_isr\": 0}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000\", \"completed_at\": \"2026-05-15T14:11:36.232Z\"}, \"plan009-sft-baseline-s44-1000\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T12:47:54.021Z\", \"updated_at\": \"2026-05-15T14:14:35.970Z\", \"hypothesis\": \"SFT 1000步 seed=44：与 s42/s43 相同配置的第三个 seed，验证 SFT 在 1000 步的 genuine rate 稳定性。3-seed 统计支撑 Goodhart collapse 是 RL (GRPO) 特有现象的 claim。\", \"parent\": \"plan009-sft-baseline-s42-r4\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T12:49:08.008Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 1\\\"\", \"finished_at\": \"2026-05-15T12:50:00.305Z\", \"training_hours\": 0.01}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 742.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 100.25 MiB is free. Process 352142 has 62.36 GiB memory in use. Including non-PyTorch memory, this process has 32.51 GiB memory in use. Of the allocate\", \"completed_at\": \"2026-05-15T12:50:04.083Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:50:14.696431+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44}, \"pid\": \"352970\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r3.log\", \"conclusion\": \"success\", \"metrics\": {\"prove_rate\": 0.15, \"n_proved\": 15, \"n_problems\": 100, \"mean_isr\": 0.0884, \"isr_std\": 0.2268, \"median_isr\": 0, \"proved_only_mean_isr\": 0.5892, \"max_isr\": 0.8571, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 15, \"prove_rate\": 0.4412}, \"false\": {\"count\": 25, \"proved\": 0, \"prove_rate\": 0}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0}}, \"genuine_count\": 14, \"genuine_rate\": 0.9333, \"h7_strict_count\": 0, \"h7_strict_rate\": 0, \"h1_strict_count\": 1, \"h1_strict_rate\": 0.0667, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"conclusion_in_premise_count\": 1, \"conclusion_in_premise_rate\": 0.0667, \"content_independent_count\": 0, \"content_independent_rate\": 0, \"isr_1_count\": 0, \"isr_1_rate\": 0, \"train_final_loss\": 0.0171, \"train_avg_loss\": 0.1544, \"train_token_accuracy\": 0.995, \"train_runtime_s\": 1580.97, \"eval_elapsed_s\": 391.8}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000/checkpoint-1000\", \"notes\": \"SFT s44 1000步 r3 成功（r1 OOM 因 GPU 冲突）。prove_rate=0.15 略高于 s42(0.13)/s43(0.11)，genuine_rate=93.3% 稳定高。3-seed SFT 均 genuine_rate>90% 无 Goodhart collapse。\"}, \"plan009-sft-baseline-s43-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:28:46.064Z\", \"updated_at\": \"2026-05-15T14:14:34.522Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43}, \"hypothesis\": \"SFT 1000步 seed=43：与 s42 相同配置的第二个 seed，验证 SFT 在 1000 步的 genuine rate 稳定性。与 GRPO 各条件 1000步对比，确认 Goodhart collapse 是 RL 特有现象。\", \"parent\": \"plan009-sft-baseline-s43\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"352137\", \"log_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000/checkpoint-1000/trainer_state.json\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000 --num_steps 1000 --seed 43 --no_wandb --gpu 0\\\"\", \"finished_at\": \"2026-05-15T13:15:26.388Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:15:29.227018+00:00\"}]}, \"metrics\": {\"prove_rate\": 0.11, \"n_proved\": 11, \"n_problems\": 100, \"mean_isr\": 0.0699, \"isr_std\": 0.2155, \"median_isr\": 0, \"proved_only_mean_isr\": 0.6352, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 11, \"prove_rate\": 0.3235}, \"false\": {\"count\": 25, \"proved\": 0, \"prove_rate\": 0}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0}}, \"genuine_count\": 10, \"genuine_rate\": 0.9091, \"h7_strict_count\": 0, \"h7_strict_rate\": 0, \"h1_strict_count\": 1, \"h1_strict_rate\": 0.0909, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"conclusion_in_premise_count\": 1, \"conclusion_in_premise_rate\": 0.0909, \"content_independent_count\": 0, \"content_independent_rate\": 0, \"isr_1_count\": 1, \"isr_1_rate\": 0.0909, \"train_final_loss\": 0.0167, \"train_avg_loss\": 0.1551, \"train_token_accuracy\": 0.9954, \"train_runtime_s\": 1584.79, \"eval_elapsed_s\": 326.1}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000/checkpoint-1000\", \"conclusion\": \"success\", \"notes\": \"SFT s43 1000步结果与 s42 高度一致：prove_rate 11% vs 13%（-2pp），mean_isr 0.0699 vs 0.0738，final_loss 0.0167 vs 0.0168。差异在 seed 方差范围内。SFT baseline 稳定。注意：eval_sta.py 当前版本不输出 h7/h1/h8/genuine 分类指标。\", \"completed_at\": \"2026-05-15T13:25:00.854Z\"}, \"plan009-sft-baseline-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:32:29.554Z\", \"updated_at\": \"2026-05-15T14:14:33.719Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"188375\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44 --num_steps 500 --seed 44 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T08:25:36.539Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T08:25:40.098764+00:00\"}]}, \"metrics\": {\"train_final_loss\": 0.2397, \"train_last_step_loss\": 0.0328, \"train_token_accuracy\": 0.9928, \"train_epochs\": 7.94, \"train_runtime_sec\": 729.05, \"train_steps\": 500, \"eval_prove_rate\": 0.17, \"eval_n_proved\": 17, \"eval_n_problems\": 100, \"eval_mean_isr\": 0.0974, \"eval_isr_std\": 0.2409, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5729, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_method\": \"eval_sta.py full STA\", \"eval_output_path\": \"/root/autodl-tmp/outputs/eval_sta_plan009_sft_s44.json\", \"eval_tautological_collapse\": false, \"eval_h7_count\": 0, \"eval_h7_rate\": 0, \"eval_h1_count\": 2, \"eval_h1_rate\": 0.118, \"eval_genuine_count\": 15, \"eval_genuine_rate\": 0.882, \"eval_by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 15, \"prove_rate\": 0.441, \"mean_isr\": 0.257}, \"false\": {\"count\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.027}, \"unknown\": {\"count\": 41, \"proved\": 1, \"prove_rate\": 0.024, \"mean_isr\": 0.008}}, \"eval_correction_note\": \"Corrected 2026-05-15: previous eval used test_100.jsonl (50/44/6 distribution), re-evaled with proofwriter_fol_100.jsonl (34/25/41)\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s44\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T08:32:34.374Z\"}, \"plan009-sft-baseline-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:08:54.164Z\", \"updated_at\": \"2026-05-15T14:14:22.594Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"171222\", \"log_path\": \"/root/runs/solver-trace-ablation/plan009-sft-baseline-s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s43 --num_steps 500 --seed 43 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T07:42:41.848Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:42:44.711163+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s43\", \"metrics\": {\"train_loss\": 0.2391, \"train_token_accuracy\": 0.9938, \"train_epochs\": 7.94, \"train_runtime_sec\": 677.14, \"train_steps\": 500, \"eval_prove_rate\": 0.15, \"eval_mean_isr\": 0.0895, \"eval_isr_std\": 0.2338, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5967, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 1, \"h1_rate\": 0.067, \"genuine_count\": 14, \"genuine_rate\": 0.933, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 13, \"prove_rate\": 0.382, \"mean_isr\": 0.234}, \"false\": {\"count\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.027}, \"unknown\": {\"count\": 41, \"proved\": 1, \"prove_rate\": 0.024, \"mean_isr\": 0.008}}, \"eval_data_path\": \"data/proofwriter_fol_100.jsonl\", \"eval_output_path\": \"/root/autodl-tmp/outputs/eval_sta_plan009_sft_s43.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T07:52:31.794Z\"}, \"plan001-exec-only-s44-1000-r2\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:51:03.762Z\", \"updated_at\": \"2026-05-15T13:51:38.874Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=44（r2 重跑）：r1 因磁盘满被 kill。磁盘已清理（92GB 可用），从 step 0 重跑。\", \"parent\": \"plan001-exec-only-s44-1000\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T13:51:35.383Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2\\\"\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"363840\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000-r2.log\", \"submitted_at\": \"2026-05-15T13:51:37.012Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"pid\": \"363840\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000-r2.log\"}, \"plan001-exec-only-s43-1000-r2\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:51:02.684Z\", \"updated_at\": \"2026-05-15T13:51:33.353Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=43（r2 重跑）：r1 因磁盘满在 step 150 崩溃。磁盘已清理（92GB 可用），从 step 0 重跑。\", \"parent\": \"plan001-exec-only-s43-1000\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T13:51:29.890Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2\\\"\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"363692\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000-r2.log\", \"submitted_at\": \"2026-05-15T13:51:32.190Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"pid\": \"363692\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000-r2.log\"}, \"plan001-exec-only-s44-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:22:45.226Z\", \"updated_at\": \"2026-05-15T13:50:32.148Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=44：与 plan016(s42) 相同配置的第三个 seed。完成 3-seed exec-only 1000步统计，与 SFT 1000步 3-seed 对照，统计支撑 Goodhart collapse 是 RL 特有现象的 claim。\", \"parent\": \"plan016-extended-1000-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"357074\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000.log\", \"submitted_at\": \"2026-05-15T13:28:02.714Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1335.7, \"gpu_hours\": 0.37}, \"pid\": \"357074\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000\\\"\", \"finished_at\": \"2026-05-15T13:50:19.963Z\"}, \"conclusion\": \"failed\", \"failure_reason\": \"磁盘满 (/dev/md0 250G/250G)，进程被手动 kill 防止 checkpoint 损坏。需从 step 0 重跑。\", \"completed_at\": \"2026-05-15T13:50:18.432Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:50:24.979972+00:00\"}]}}, \"plan001-exec-only-s43-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:22:44.661Z\", \"updated_at\": \"2026-05-15T13:48:08.794Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=43：与 plan016(s42) 相同配置的第二个 seed。3-seed exec-only 1000步统计，验证 Goodhart collapse（genuine→0%）在 exec-only 条件下的可重复性。与 SFT 1000步 3-seed 对照，确认 collapse 是 RL(GRPO) 特有现象。\", \"parent\": \"plan016-extended-1000-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T13:23:32.864Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000\\\"\", \"finished_at\": \"2026-05-15T13:45:01.320Z\", \"training_hours\": 0.36}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"356071\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000.log\", \"submitted_at\": \"2026-05-15T13:23:35.275Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1288.0, \"gpu_hours\": 0.36}, \"pid\": \"356071\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000.log\", \"failure_reason\": \"磁盘满 (os error 28): /root/autodl-tmp/ 250G/250G (100%)，step 150 保存 checkpoint 时 safetensors serialize 失败。checkpoint-100 完整可用(15GB)，checkpoint-150 不完整(仅2/4 shards)。分类: disk_full, retryable。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T13:45:03.313Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:45:05.583858+00:00\"}]}}, \"plan018-additive-random-b01-s42-1000-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:26:49.094Z\", \"updated_at\": \"2026-05-15T13:16:03.636Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000_r3 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"269147\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r3.log\", \"submitted_at\": \"2026-05-15T10:27:08.529Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6985.6, \"gpu_hours\": 1.94}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"269147\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000_r3 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T12:05:43.550Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:05:46.554124+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000_r3/checkpoint-1000\", \"metrics\": {\"eval_prove_rate\": 0.97, \"eval_mean_isr\": 0.6892, \"eval_isr_std\": 0.2037, \"eval_median_isr\": 0.75, \"eval_proved_only_isr\": 0.7105, \"eval_n_proved\": 97, \"eval_n_problems\": 100, \"genuine_count\": 0, \"genuine_rate\": 0, \"h1_count\": 97, \"h1_rate\": 0.97, \"h7_count\": 0, \"h7_rate\": 0, \"tautological_collapse\": true, \"train_final_prove_rate\": 0.827, \"train_final_mean_isr\": 0.5213, \"train_loss\": 0.00671, \"train_final_entropy\": 0.003, \"train_runtime_seconds\": 5783, \"train_steps\": 1000, \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 25, \"prove_rate\": 1, \"mean_isr\": 0.7533}, \"unknown\": {\"count\": 41, \"proved\": 39, \"prove_rate\": 0.951, \"mean_isr\": 0.6565}, \"true\": {\"count\": 34, \"proved\": 33, \"prove_rate\": 0.971, \"mean_isr\": 0.6814}}, \"n_premise_distribution\": {\"1\": 97}, \"pattern_description\": \"All 97 proved: 1 premise identical to conclusion (P therefore P). ISR varies by structural decomposition, not reasoning quality.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T12:23:34.170Z\"}, \"plan009-sft-baseline-s44-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:53:24.774Z\", \"updated_at\": \"2026-05-15T12:56:27.871Z\", \"hypothesis\": \"SFT 1000步 seed=44（重试）：r1 因 CUDA_VISIBLE_DEVICES 未设导致 OOM 失败。与 s42/s43 相同配置的第三个 seed，验证 SFT 在 1000 步的 genuine rate 稳定性。3-seed 统计支撑 Goodhart collapse 是 RL (GRPO) 特有现象的 claim。\", \"parent\": \"plan009-sft-baseline-s44-1000\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 0\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"353256\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r2.log\", \"submitted_at\": \"2026-05-15T12:53:53.733Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 32.2, \"gpu_hours\": 0.01}, \"pid\": \"353256\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 0\\\"\", \"finished_at\": \"2026-05-15T12:54:24.026Z\"}, \"failure_reason\": \"CUDA OOM: 重试 r2 在已被 plan009-sft-baseline-s43-1000 (PID 352142) 占用的 GPU 0 上启动，仅剩 100.25 MiB 可用显存。原始实验 plan009-sft-baseline-s44-1000 仍在 cuda:1 正常运行，此 r2 为冗余重试，无需再次重试。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T12:54:25.923Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:54:28.360459+00:00\"}]}}, \"plan009-sft-baseline-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T11:57:52.856Z\", \"updated_at\": \"2026-05-15T12:48:03.859Z\", \"hypothesis\": \"SFT 1000步延伸：验证 SFT（无 reward optimization）在 1000 步是否维持 genuine rate。500 步 SFT 已达 93% genuine，若 1000 步仍保持高 genuine → Goodhart collapse 是 RL (GRPO) 特有现象，非一般 finetuning 退化。与 exec-only/ISR/random 1000步形成对比。\", \"parent\": \"plan009-sft-baseline-s42-r4\", \"completed_at\": \"2026-05-15T12:25:32.031Z\", \"eval_prove_rate\": 0.13, \"eval_mean_isr\": 0.0738, \"eval_isr_std\": 0.2077, \"eval_proved_only_isr\": 0.5677, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 1, \"h1_rate\": 7.7, \"genuine_count\": 12, \"genuine_rate\": 92.3, \"extra\": {\"previous_failure\": {\"conclusion\": \"success\"}}, \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000 --num_steps 1000 --seed 42 --no_wandb --bf16\", \"server\": \"westd-39279\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"submitted_at\": \"2026-05-15T19:58:15+08:00\", \"wall_clock_seconds\": 1415, \"gpu_hours\": 0.39, \"checkpoint_source\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/checkpoint-1000\", \"eval_data\": \"data/proofwriter_fol_100.jsonl\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/checkpoint-1000\", \"log_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/checkpoint-1000/trainer_state.json\", \"metrics\": {\"train_final_loss\": 0.0168, \"train_last_step_loss\": 0.0168, \"train_token_accuracy\": 0.9955, \"train_epochs\": 15.88, \"train_runtime_sec\": 1415, \"train_steps\": 1000, \"eval_prove_rate\": 0.13, \"eval_n_proved\": 13, \"eval_n_problems\": 100, \"eval_mean_isr\": 0.0738, \"eval_isr_std\": 0.2077, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5677, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_method\": \"eval_sta.py full STA\", \"eval_output_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/eval_sta_results.json\", \"h7_strict_count\": 0, \"h7_strict_rate\": 0, \"h1_strict_count\": 1, \"h1_strict_rate\": 0.0769, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 12, \"genuine_rate\": 0.9231, \"conclusion_in_premise_count\": 1, \"conclusion_in_premise_rate\": 0.0769, \"isr_1_count\": 0, \"content_independent_count\": 0, \"eval_by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 12, \"prove_rate\": 0.353, \"mean_isr\": 0.209}, \"false\": {\"count\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.011}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0, \"mean_isr\": 0}}}, \"conclusion\": \"success\", \"notes\": \"SFT 1000步 (15.88 epochs): train loss 降至 0.0168（严重过拟合），但 eval genuine_rate=92.31% 与 500步的 92.9% 基本持平。prove_rate 从 0.14 微降至 0.13，h7=0，h1=1。结论：SFT 即使过拟合也不产生 Goodhart collapse（h7/h8=0），验证了 Goodhart 是 RL(GRPO) reward optimization 特有现象。Unknown 类全部 0/41 未 prove（与 500步一致），SFT 不具备泛化到 unknown 类的能力。\"}, \"plan002-additive-b03-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:24:47.843Z\", \"updated_at\": \"2026-05-15T12:45:27.465Z\", \"spec\": {\"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Additive ISR bonus r=r_exec*(1+β*ISR) with β=0.3: ISR can only boost reward, never penalize. Should preserve prove_rate (unlike convex combination penalty in plan005) while improving structural quality.\", \"plan_id\": \"plan_002\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * ISR)\", \"beta\": 0.3, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_beta03_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"161819\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T03:24:44.110Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T03:24:48.666027+00:00\"}]}, \"metrics\": {\"total_steps\": 500, \"duration_min\": 56.7, \"overall_prove_rate\": 0.34025, \"overall_isr\": 0.11527, \"last100_prove_rate\": 0.5525, \"eval_prove_rate\": 0.18, \"eval_mean_isr\": 0.0257, \"eval_isr_std\": 0.0742, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.1427, \"eval_n_proved\": 18, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.778, \"h1_count\": 14, \"h8_conjunction_collapse_count\": 3, \"h8_conjunction_collapse_rate\": 0.1667, \"genuine_rate\": 0.0556, \"genuine_count\": 1, \"eval_by_type_false_pr\": 0.12, \"eval_by_type_false_isr\": 0.0102, \"eval_by_type_unknown_pr\": 0.195, \"eval_by_type_unknown_isr\": 0.0422, \"eval_by_type_true_pr\": 0.206, \"eval_by_type_true_isr\": 0.0172, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse added. genuine 4→1.\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_beta03_s42\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b03-s42.log\", \"notes\": \"ISR 为 binary 近似 (_fast_fn)，不可用于论文跨 run 对比，需 eval_sta.py 统一评估真实 ISR。prove_rate 轨迹 0.13→0.095→0.185→0.375→0.476→0.553，呈稳步上升趋势，尚未完全饱和（仅 52/500 步 ≥0.85），与 plan001/plan013 的强饱和模式不同。\", \"conclusion\": \"negative\", \"eval_prove_rate\": 0.18, \"eval_mean_isr\": 0.0257, \"eval_isr_std\": 0.0742, \"eval_proved_only_isr\": 0.1427, \"eval_median_isr\": 0, \"eval_isr_pr_ratio\": 0.1427, \"completed_at\": \"2026-05-14T04:27:38.822Z\", \"genuine_count\": 1, \"genuine_rate\": 0.056, \"h8_count\": 3}, \"plan001-exec-only-s42-r2\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T22:40:41.773Z\", \"updated_at\": \"2026-05-15T12:45:21.831Z\", \"completed_at\": \"2026-05-13T23:46:00Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:46:01.596431+00:00\"}]}, \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s42\", \"server\": \"westd-39279\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"500-step exec-only baseline for STA comparison (K=8)\", \"pid\": \"84901\", \"gpu\": [\"cuda:0\"], \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s42-r2.log\", \"submitted_at\": \"2026-05-13T22:42:40.204Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 3820, \"gpu_hours\": 1.06}, \"notes\": \"Cron 误判 DONE/failed（因 --help|grep 前缀命令的 PID 84896 退出，实际训练子进程 PID 84901 仍在运行）。已手动恢复 RUNNING。严禁在 cuda:0 启动新进程直到 r2 自然完成。⚠️ Reviewer 中期审查标注: 训练日志中 ISR=0.8612 为 binary approximation (_fast_fn)，非真实 ISR。最终可比 ISR 需通过 eval_sta.py (full STA) 重新评估。\", \"reproduce\": {\"finished_at\": \"2026-05-13T23:46:00.369Z\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s42/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s42/reward_log.jsonl\", \"metrics\": {\"eval_prove_rate\": 0.93, \"eval_mean_isr\": 0.1232, \"eval_isr_std\": 0.1887, \"eval_proved_only_isr\": 0.1324, \"eval_median_isr\": 0, \"eval_n_proved\": 93, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.871, \"h1_count\": 81, \"h8_conjunction_collapse_count\": 6, \"h8_conjunction_collapse_rate\": 0.0645, \"genuine_rate\": 0.0753, \"genuine_count\": 7, \"genuine_mean_isr\": 0.3141, \"h1_mean_isr\": 0.1055, \"conclusion_embedding_total\": 0.871, \"content_independent_predicates_count\": 1, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse added. genuine 12→7.\"}, \"genuine_count\": 7, \"genuine_rate\": 0.075, \"h8_count\": 6}, \"plan004-o1-ablation-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T04:37:39.643Z\", \"updated_at\": \"2026-05-15T12:06:55.592Z\", \"hypothesis\": \"O(1) binary ISR (fast_isr_fol) vs O(N) full STA ablation: 100-step pilot showed binary ISR ≈ exec-only (all proved samples ISR=1). 500-step full run confirms O(1) is ineffective at scale — the LOO ablation (O(N)) is necessary for ISR to carry structural signal. Negative result strengthens paper's methodological contribution.\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T04:39:03.284Z\"}, \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_fast_isr_ablation.yaml --output_dir /root/autodl-tmp/outputs/plan004_fast_isr_s42 --num_steps 500 --num_generations 8 --no_wandb\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"155099\", \"log_path\": \"/root/runs/solver-trace-ablation/plan004-o1-ablation-s42.log\", \"submitted_at\": \"2026-05-15T12:50:15Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"O(1) binary ISR (fast_isr_fol) vs O(N) full STA ablation. fast_sta_reward returns 1.0 for all proved samples, losing partial redundancy signal. Expected negative result.\", \"reward_formula\": \"r = 0.5 * exec + 0.5 * fast_ISR\", \"plan_id\": \"plan004\", \"output_dir\": \"/root/autodl-tmp/outputs/plan004_fast_isr_s42\"}, \"metrics\": {\"prove_rate\": 0.63, \"mean_isr\": 0.0072, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 63, \"h1_rate\": 1, \"h8_conjunction_collapse_count\": 2, \"h8_conjunction_collapse_rate\": 0.0317, \"genuine_count\": 0, \"genuine_rate\": 0, \"content_independent_predicates_count\": 3, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse added. genuine unchanged (0).\"}, \"conclusion\": \"negative\", \"notes\": \"NEGATIVE (expected): O(1) binary ISR (fast_isr) 训练 500 步后 eval ISR=0.0072（本质为0）。模型生成大量冗余 premise（如62+重复 ground facts），per-clause ablation 删任一重复不影响结果，ISR趋近0。与 exec-only 的 ISR 崩塌模式一致（ISR=0.003）。确认 O(1) binary ISR 退化为 exec-only——LOO ablation (O(N)) 是 ISR 携带结构信号的必要条件。此负向结果强化论文方法论贡献：O(N) 复杂度有其必要性。PR=63% 低于 exec-only s42 (93%) 和 ISR β=0.1 s42 (81%)。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan004_fast_isr_s42/checkpoint-500\", \"log_path\": \"/root/runs/solver-trace-ablation/plan004-o1-ablation-s42.log\", \"completed_at\": \"2026-05-15T06:21:42.630Z\"}, \"exp1-isr-b03-s42-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:31:37.813Z\", \"updated_at\": \"2026-05-15T11:52:23.241Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"224651\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000-r2.log\", \"submitted_at\": \"2026-05-15T09:32:05.796Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7320.6, \"gpu_hours\": 2.03}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"224651\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T11:27:09.017Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T11:27:13.616148+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.95, \"eval_mean_isr\": 0.734, \"eval_isr_std\": 0.2575, \"eval_median_isr\": 0.6, \"eval_proved_only_isr\": 0.7726, \"eval_n_proved\": 95, \"eval_n_problems\": 100, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 25, \"prove_rate\": 1, \"mean_isr\": 0.824}, \"unknown\": {\"count\": 41, \"proved\": 38, \"prove_rate\": 0.927, \"mean_isr\": 0.673}, \"true\": {\"count\": 34, \"proved\": 32, \"prove_rate\": 0.941, \"mean_isr\": 0.741}}, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 54, \"h1_rate\": 0.568, \"genuine_count\": 0, \"genuine_rate\": 0, \"tautological_collapse\": true, \"isr_1_count\": 41, \"isr_1_rate\": 0.432, \"single_premise_count\": 0, \"train_final_prove_rate\": 0.829, \"train_final_mean_isr\": 0.727, \"train_loss\": 0.0041, \"train_runtime_seconds\": 6280, \"train_final_entropy\": 9e-06, \"completions_mean_length\": 47, \"h8_conjunction_collapse_count\": 41, \"h8_conjunction_collapse_rate\": 0.432, \"content_independent_predicates\": true}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s42_1000\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T11:34:06.399Z\"}, \"plan018-additive-random-b01-s42-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:31:40.077Z\", \"updated_at\": \"2026-05-15T11:31:44.382Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000/checkpoint-350 --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"224797\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r2.log\", \"submitted_at\": \"2026-05-15T09:32:10.554Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7173.8, \"gpu_hours\": 1.99}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"224797\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000/checkpoint-350 --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T10:23:56.400Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T10:23:59.009335+00:00\"}]}, \"metrics\": {\"train_final_prove_rate\": 0.989, \"train_final_mean_isr\": 0.353, \"train_final_reward\": 1.062, \"train_steps\": 1000, \"train_runtime_seconds\": 2957, \"eval_prove_rate\": 1, \"eval_mean_isr\": 0.3333, \"eval_isr_std\": 0, \"eval_median_isr\": 0.3333, \"eval_proved_only_isr\": 0.3333, \"eval_n_proved\": 100, \"eval_n_problems\": 100, \"eval_component_count_mean\": 3, \"genuine_rate\": 0, \"genuine_count\": 0, \"tautological_collapse\": true, \"h7_rate\": null, \"h7_count\": null, \"h1_rate\": null, \"h1_count\": null}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000\", \"completed_at\": \"2026-05-15T11:31:44.382Z\"}, \"plan018-additive-random-b01-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:08:56.941Z\", \"updated_at\": \"2026-05-15T09:25:12.327Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"197860\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000.log\", \"submitted_at\": \"2026-05-15T08:28:46.060Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 3386.3, \"gpu_hours\": 0.94}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T08:28:44.610Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T09:25:10.249Z\", \"training_hours\": 0.94}, \"pid\": \"197860\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T09:25:12.327Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:25:17.262043+00:00\"}]}}, \"exp1-isr-b03-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T08:55:55.364Z\", \"updated_at\": \"2026-05-15T09:24:46.558Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"219058\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000.log\", \"submitted_at\": \"2026-05-15T09:16:01.559Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 525.0, \"gpu_hours\": 0.15}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"219058\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T09:24:44.644Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T09:24:46.558Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:24:49.137230+00:00\"}]}}, \"exp1-random-b03-s43-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:44:48.792Z\", \"updated_at\": \"2026-05-15T08:29:42.001Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s43_r4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"117566\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43-r4.log\", \"submitted_at\": \"2026-05-15T02:44:48.579Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"Random beta=0.3 s43 retry #4: previous r2 killed, r3 OOM. Clean GPU now.\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"plan_id\": \"EXP-1\", \"output_dir\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43_r4\", \"wall_clock_seconds\": 6738.6, \"gpu_hours\": 1.87}, \"reproduce\": {\"finished_at\": \"2026-05-15T04:29:26.819Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:29:29.426423+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_step\": 500, \"prove_rate\": 0.5505, \"mean_isr\": 0.1358, \"parse_rate\": 1, \"train_loss\": 0.01365, \"train_runtime_sec\": 6161.1, \"epoch\": 2, \"eval_prove_rate\": 0.92, \"eval_mean_isr\": 0.1659, \"eval_isr_std\": 0.1147, \"eval_median_isr\": 0.1429, \"eval_proved_only_mean_isr\": 0.1803, \"eval_min_isr\": 0, \"eval_max_isr\": 0.5, \"eval_n_proved\": 92, \"eval_n_problems\": 100, \"eval_h7_strict_rate\": 0.076, \"eval_h7_strict_count\": 7, \"eval_h1_strict_rate\": 0.978, \"eval_h1_strict_count\": 90, \"eval_genuine_rate\": 0.022, \"eval_genuine_count\": 2, \"eval_isr0_count\": 6, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 23, \"prove_rate\": 0.92, \"mean_isr\": 0.156}, \"unknown\": {\"count\": 41, \"proved\": 37, \"prove_rate\": 0.902, \"mean_isr\": 0.184}, \"true\": {\"count\": 34, \"proved\": 32, \"prove_rate\": 0.941, \"mean_isr\": 0.151}}}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43_r4/checkpoint-500\", \"completed_at\": \"2026-05-15T04:37:07.139Z\", \"notes\": \"Training 500/500 steps, 1h42m. Final train: prove_rate=0.5505, mean_isr=0.1358, loss=0.01365. EVAL (proofwriter_fol_100.jsonl): PR=0.92, ISR=0.1659, H7=7/92(7.6%), H1=90/92(97.8%), genuine=2/92(2.2%). ANOMALY: massive seed variance vs s44-r2 (PR=0.23, ISR=0, H1=100%, genuine=0%). s43 learned high-PR hacking strategy with conclusion-in-premise; s44 barely proved anything. Both are random baseline — this variance weakens cross-seed claims.\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43-r4.log\", \"eval_h7_strict_count\": 0, \"eval_h1_strict_count\": 89, \"eval_genuine_count\": 3}, \"plan001-exec-only-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T03:57:09.690Z\", \"updated_at\": \"2026-05-15T08:29:40.375Z\", \"hypothesis\": \"Exec-only seed=44 第3 seed: 解决 s42(93% eval PR) vs s43(13% eval PR) 的跨 seed 不稳定问题，3-seed mean±std 是论文必需。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"226200\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44.log\", \"submitted_at\": \"2026-05-14T04:29:05.471Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2725.5, \"gpu_hours\": 0.76}, \"pid\": \"226200\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44\\\"\", \"finished_at\": \"2026-05-14T05:06:39.227Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T05:06:40.707032+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.98, \"eval_mean_isr\": 0.57, \"eval_isr_std\": 0.2013, \"eval_median_isr\": 0.5, \"eval_proved_only_isr\": 0.5816, \"eval_n_proved\": 98, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_component_count_mean\": 2.04, \"eval_component_count_2\": 94, \"eval_component_count_3\": 4, \"tautological_collapse\": true, \"h7_rate\": 1, \"h7_count\": 97, \"h1_rate\": 0, \"h1_count\": 0, \"genuine_rate\": 0, \"genuine_count\": 0, \"conclusion_embedding_total\": 1}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s44\", \"conclusion\": \"negative\", \"notes\": \"TAUTOLOGICAL COLLAPSE 确认。eval PR=98% 但 94% 样本仅 2 components (premise=conclusion tautology)，mean components=2.04，与 plan013 random reward 完全一致。ISR≈0.5 是 2-component artifact。s42 是唯一产生 genuine proofs (mean components=6.58) 的 seed。3-seed 结果：s42=genuine, s43=degraded(PR=13%), s44=tautological(PR=98% fake)。Exec-only reward 2/3 seeds 失败。\", \"completed_at\": \"2026-05-14T05:14:30.940Z\", \"h7_count\": 98}, \"plan018-additive-random-b01-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:01:24.111Z\", \"updated_at\": \"2026-05-15T06:39:54.823Z\", \"hypothesis\": \"Random β=0.1 seed=43 控制组 r2: 重试 (原 s43 step 200 磁盘满崩溃)。与 plan002-b01-s43 (ISR β=0.1) 同 seed 对照。3-seed mean±std 审稿硬性要求。\", \"parent\": \"plan018-additive-random-b01-s43\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\\\"\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"858386\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43-r2.log\", \"submitted_at\": \"2026-05-14T15:24:32.942Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\", \"wall_clock_seconds\": 6748.8, \"gpu_hours\": 1.87}, \"pid\": \"858386\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\\\"\", \"finished_at\": \"2026-05-14T16:43:53.042Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T16:43:54.952857+00:00\"}]}, \"metrics\": {\"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 93.2, \"h1_count\": 82, \"genuine_rate\": 6.8, \"genuine_count\": 6, \"eval_prove_rate\": 0.88, \"eval_mean_isr\": 0.058}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T17:17:01.774Z\"}, \"exp1-random-b03-s44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:42:02.173Z\", \"updated_at\": \"2026-05-15T03:07:35.496Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s44_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": 51297, \"log_path\": \"/root/autodl-tmp/outputs/eval_sta_exp1_random_b03_s44_r2.json\", \"submitted_at\": \"2026-05-15T00:42:39.447Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"hypothesis\": \"Random beta=0.3 s44: 3-seed random control for Claim 2\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"plan_id\": \"EXP-1\", \"parent\": \"exp1-random-b03-s44\", \"output_dir\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2\", \"wall_clock_seconds\": 8595.6, \"gpu_hours\": 2.39}, \"reproduce\": {\"finished_at\": \"2026-05-15T02:26:26.919Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T02:26:39.221668+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_prove_rate\": 0.23, \"eval_proved_only_mean_isr\": 0, \"eval_mean_isr\": 0, \"eval_isr_std\": 0, \"eval_median_isr\": 0, \"eval_n_proved\": 23, \"eval_n_problems\": 100, \"eval_h7_strict_rate\": 0, \"eval_h7_strict_count\": 0, \"eval_h1_strict_rate\": 1, \"eval_h1_strict_count\": 23, \"eval_genuine_rate\": 0, \"eval_genuine_count\": 0, \"eval_data\": \"proofwriter_fol_100.jsonl\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2/reward_log.jsonl\", \"completed_at\": \"2026-05-15T03:05:55.070Z\"}, \"exp1-isr-b03-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:02:10.292Z\", \"updated_at\": \"2026-05-15T02:39:55.709Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"pid\": 58051, \"log_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3/reward_log.jsonl\", \"submitted_at\": \"2026-05-15T01:02:18.804Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"output_dir\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3\", \"wall_clock_seconds\": 4321.2, \"gpu_hours\": 1.2}, \"conclusion\": \"success\", \"notes\": \"Training completed 500/500 steps in 69min. Final stats: prove_rate=0.56125, mean_isr=0.1515, parse_rate=1.0. Checkpoint saved at checkpoint-500. EVAL: PR=0.86 (greedy), mean_ISR=0.2535, H7_strict=4/86(4.7%), H1_strict=59/86(68.6%), total_hacking=63/86(73.3%), genuine=23/86(26.7%). Hacking pattern: predominantly H1 (conclusion embedding in multi-premise), NOT H7 (unlike s44's 100% H7). Data: proofwriter_fol_100.jsonl.\", \"completed_at\": \"2026-05-15T02:14:19.967Z\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3/checkpoint-500\", \"log_path\": \"/root/runs/solver-trace-ablation/exp1-isr-b03-s43-r3.log\", \"metrics\": {\"final_step\": 500, \"prove_rate\": 0.56125, \"mean_isr\": 0.1515, \"parse_rate\": 1, \"train_loss\": 0.0176, \"train_runtime_sec\": 4153.6, \"epoch\": 2, \"eval_prove_rate\": 0.86, \"eval_mean_isr\": 0.2535, \"eval_isr_std\": 0.2406, \"eval_median_isr\": 0.3333, \"eval_proved_only_mean_isr\": 0.2948, \"eval_min_isr\": 0, \"eval_max_isr\": 0.75, \"eval_n_proved\": 86, \"eval_n_problems\": 100, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_h7_strict_rate\": 0.047, \"eval_h7_strict_count\": 4, \"eval_h1_strict_rate\": 0.686, \"eval_h1_strict_count\": 59, \"eval_conclusion_in_premise_rate\": 0.733, \"eval_conclusion_in_premise_count\": 63, \"eval_genuine_rate\": 0.267, \"eval_genuine_count\": 23, \"eval_single_premise_rate\": 0.058, \"eval_single_premise_count\": 5, \"eval_isr_1_count\": 0, \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 23, \"prove_rate\": 0.92, \"mean_isr\": 0.334}, \"unknown\": {\"count\": 41, \"proved\": 35, \"prove_rate\": 0.854, \"mean_isr\": 0.199}, \"true\": {\"count\": 34, \"proved\": 28, \"prove_rate\": 0.824, \"mean_isr\": 0.26}}}}, \"exp1-random-b03-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:34:11.247Z\", \"updated_at\": \"2026-05-15T02:37:49.701Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"114576\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43-r3.log\", \"submitted_at\": \"2026-05-15T02:34:10.754Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"beta=0.3 random s43 retry: supplement for 3-seed random statistics\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"plan_id\": \"EXP-1\", \"output_dir\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43_r3\", \"wall_clock_seconds\": 218.9, \"gpu_hours\": 0.06}, \"reproduce\": {\"finished_at\": \"2026-05-15T02:37:46.271Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 28.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 24.25 MiB is free. Process 113293 has 81.17 GiB memory in use. Including non-PyTorch memory, this process has 13.77 GiB memory in use. Of the allocated \", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T02:37:49.701Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T02:37:52.575206+00:00\"}]}}, \"plan015-linear-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:05:37.944Z\", \"updated_at\": \"2026-05-15T02:36:29.622Z\", \"spec\": {\"command\": \"killed-cleanup\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"60030\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T01:05:52.053Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 5429.0, \"gpu_hours\": 1.51}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T02:36:21.092Z\"}, \"exp1-isr-b03-s43-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:07:39.840Z\", \"updated_at\": \"2026-05-15T02:36:28.581Z\", \"spec\": {\"command\": \"killed-cleanup\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"61219\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T01:07:48.622Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 5311.2, \"gpu_hours\": 1.48}, \"conclusion\": \"killed\", \"notes\": \"Duplicate of exp1-isr-b03-s43-r3 (already RUNNING on cuda:0). Created during D068 chaos, confirmed redundant at Loop #10.\", \"completed_at\": \"2026-05-15T02:36:19.862Z\"}, \"exp1-random-b03-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:30:55.259Z\", \"updated_at\": \"2026-05-15T02:36:22.901Z\", \"spec\": {\"command\": \"killed-cleanup\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"113288\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T02:31:28.051Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 294.9, \"gpu_hours\": 0.08}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T02:36:22.901Z\"}, \"plan017-additive-random-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T03:11:14.694Z\", \"updated_at\": \"2026-05-15T02:10:30.226Z\", \"hypothesis\": \"Additive random control: r = r_exec·(1+0.3·random). 隔离 ISR structural signal vs variance regularization. 若 ISR > random > exec-only → signal+regularization 均贡献; 若 ISR > random ≈ exec-only → ISR signal 是关键; 若 ISR ≈ random → ISR 无结构价值。\", \"parent\": \"plan013-random-reward-s42-r4\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan017_additive_random_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Additive random control: r = r_exec·(1+0.3·random)\", \"plan_id\": \"plan017\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"beta\": 0.3}, \"pid\": \"207116\", \"log_path\": \"~/runs/solver-trace-ablation/plan017-additive-random-s42.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan017_additive_random_s42\\\"\", \"finished_at\": \"2026-05-14T05:17:13.920Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T05:17:18.376399+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan017_additive_random_s42\", \"notes\": \"Eval结果: PR=0.48, mean_ISR=0.0453, proved_only_ISR=0.0943, mean_components=9.56 (3+比例100%, 无tautological collapse). 但33%已证明样本ISR=0 (n_necessary=0, conclusion trivially provable). 与plan013的不同failure mode: additive random防止了2-component坍缩, 但模型转向生成复杂但无用的formalization (多premises但conclusion不依赖任何premise). Variance regularization不足以产生genuine proofs.\", \"metrics\": {\"eval_prove_rate\": 0.48, \"eval_mean_isr\": 0.0453, \"eval_isr_std\": 0.0759, \"eval_median_isr\": 0, \"eval_max_isr\": 0.2857, \"eval_proved_only_isr\": 0.0943, \"eval_n_proved\": 48, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_component_count_mean\": 9.6, \"eval_component_count_2_ratio\": 0, \"tautological_collapse\": false, \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 1, \"h1_count\": 48, \"genuine_rate\": 0, \"genuine_count\": 0}, \"completed_at\": \"2026-05-14T05:30:46.783Z\"}, \"exp1-random-b03-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:52:08.290Z\", \"updated_at\": \"2026-05-15T01:30:34.704Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"β=0.3 random seed 43: supplement for 3-seed statistics in Table 1. Reference: plan017-additive-random-s42\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"num_steps\": 500, \"beta\": 0.3, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"963653\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43/\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:35:47.399Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:35:48.354Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:35:52.992924+00:00\"}]}, \"notes\": \"D062/D063 INVALIDATED: eval used test_100.jsonl (wrong test set). Checkpoint deleted, cannot re-eval. Retrain as exp1-random-b03-s43-r2.\", \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.79, \"mean_isr\": 0.1745, \"isr_std\": 0.1628, \"median_isr\": 0.1667, \"proved_only_mean_isr\": 0.2209, \"hacking_rate_strict_h7\": 0, \"hacking_rate_functional\": 0.1013, \"genuine_rate\": 0.8987, \"genuine_count\": 71, \"n_proved\": 79, \"n_problems\": 100, \"h1_conclusion_in_premise\": 0.759, \"eval_data\": \"test_100.jsonl\", \"eval_output\": \"/root/autodl-tmp/outputs/eval_sta_exp1_random_b03_s43.json\"}, \"eval_metrics\": {\"prove_rate\": 0.79, \"mean_isr\": 0.1745, \"isr_std\": 0.1628, \"proved_only_isr\": 0.2209, \"n_proved\": 79, \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.759, \"h1_count\": 60, \"genuine_rate\": 0.241, \"genuine_count\": 19, \"single_premise_rate\": 0, \"eval_data\": \"test_100.jsonl\"}}, \"exp1-isr-b03-s44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:21:38.601Z\", \"updated_at\": \"2026-05-15T01:09:36.604Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"hypothesis\": \"β=0.3 ISR seed 44 retry: original failed due to orphan process OOM on GPU 0. Same config as exp1-isr-b03-s44.\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * ISR)\", \"num_steps\": 500, \"beta\": 0.3, \"parent\": \"exp1-isr-b03-s44\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s44_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"10597\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s44-r2.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T00:15:28.410Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:15:30.528573+00:00\"}]}, \"eval_metrics\": {\"prove_rate\": 0.98, \"mean_isr\": 0.7275, \"isr_std\": 0.1184, \"proved_only_isr\": 0.7423, \"n_proved\": 98, \"h7_rate\": 1, \"h7_count\": 98, \"h1_rate\": 0, \"h1_count\": 0, \"genuine_rate\": 0, \"genuine_count\": 0, \"single_premise_rate\": 1, \"eval_data\": \"test_100.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"prove_rate\": 0.95, \"mean_isr\": 0.705, \"isr_std\": 0.172, \"proved_only_isr\": 0.7421, \"n_proved\": 95, \"n_problems\": 100, \"h7_rate\": 1, \"h7_count\": 95, \"h1_rate\": 0, \"h1_count\": 0, \"genuine_rate\": 0, \"genuine_count\": 0, \"single_premise_rate\": 1, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_note\": \"Re-eval with correct test set (D062). Previous test_100.jsonl results invalidated.\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s44_r2/checkpoint-500/\", \"completed_at\": \"2026-05-15T00:35:22.489Z\", \"notes\": \"D062/D063: eval_metrics used test_100.jsonl (invalidated). metrics field contains re-eval with proofwriter_fol_100.jsonl (valid). eval_invalidated applies only to eval_metrics.\"}, \"exp1-random-b03-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:06:04.388Z\", \"updated_at\": \"2026-05-15T00:36:20.012Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"hypothesis\": \"β=0.3 random seed 44: supplement for 3-seed statistics in Table 1. Reference: plan017-additive-random-s42\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"num_steps\": 500, \"beta\": 0.3, \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s44\"}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"finished_at\": \"2026-05-15T00:36:18.060Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T00:36:20.012Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:36:27.151961+00:00\"}]}}, \"exp1-isr-b03-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:06:01.473Z\", \"updated_at\": \"2026-05-14T23:21:59.279Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"7303\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s44.log\", \"submitted_at\": \"2026-05-14T23:16:22.350Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 139.8, \"gpu_hours\": 0.04}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"7303\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s44\\\"\", \"finished_at\": \"2026-05-14T23:18:40.671Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 44.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 12.25 MiB is free. Process 5480 has 83.06 GiB memory in use. Including non-PyTorch memory, this process has 11.89 GiB memory in use. Of the allocated me\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T23:18:42.116Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:18:43.961885+00:00\"}]}, \"notes\": \"OOM on first submission: GPU 0 was occupied by orphan PID 5480 (exp1-isr-b03-s43-r2 training process survived tmux kill). Pending resubmission after GPU 0 cleared.\"}, \"exp1-isr-b03-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:09:49.339Z\", \"updated_at\": \"2026-05-14T23:15:53.081Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"5475\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s43-r2.log\", \"submitted_at\": \"2026-05-14T23:14:05.147Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 107.9, \"gpu_hours\": 0.03}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"5475\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s43-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43_r2\\\"\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T23:15:53.081Z\"}, \"exp2-exec-s43-greedy\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:46:57.466Z\", \"updated_at\": \"2026-05-14T23:06:25.776Z\", \"spec\": {\"command\": \"eval_sta.py --greedy on plan001-exec-only-s43-r4 checkpoint\", \"server\": \"westd-39279\", \"data_path\": \"data/eval_100.jsonl\", \"data_count\": 100, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"EXP-2: Greedy re-eval of exec-only s43 to verify decoding invariance\", \"checkpoint_source\": \"plan001-exec-only-s43-r4\", \"eval_data\": \"data/eval_100.jsonl\", \"parent\": \"plan001-exec-only-s43-r4\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"N/A (eval only)\", \"metrics\": {\"greedy_pr\": 0.13, \"greedy_isr_star\": 0, \"greedy_h1_pct\": 100, \"greedy_h7_pct\": 0, \"greedy_genuine_pct\": 0, \"sampling_pr\": 0.14, \"sampling_isr_star\": 0, \"conclusion_text\": \"s43 collapse is decoding-invariant. Both greedy and sampling show ISR*=0, H1=100%, genuine=0%\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:06:15.509Z\"}, \"exp4-100step-h1h7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:47:55.686Z\", \"updated_at\": \"2026-05-14T23:06:24.790Z\", \"spec\": {\"command\": \"H1/H7 classification on plan003 (100-step exec-only checkpoint) eval outputs\", \"server\": \"westd-39279\", \"data_path\": \"plan003_eval_exec_only_r5.json\", \"data_count\": 100, \"model_name\": \"Qwen3-4B (100-step checkpoint)\", \"seed\": 42, \"hypothesis\": \"EXP-4: If hacking exists at 100-step PR=32%, supports RL-specific claim independent of PR level\", \"checkpoint_source\": \"sta-phase1-exec-only-r5\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp4_100step_h1h7_classification.json\", \"log_path\": \"N/A\", \"metrics\": {\"pr\": 0.32, \"isr_star\": 0.642, \"h7_pct\": 28.1, \"h1_pct\": 3.1, \"total_hacking_pct\": 31.2, \"genuine_pct\": 68.8, \"n_proved\": 32, \"h7_count\": 9, \"h1_count\": 1}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:06:14.584Z\"}, \"plan001-exec-only-s43-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:40:37.808Z\", \"updated_at\": \"2026-05-14T22:08:48.945Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_r4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"136339\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-r4.log\", \"submitted_at\": \"2026-05-14T01:40:37.746Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"Exec-only seed=43 replication: confirm plan001-r2 (seed=42) prove_rate convergence is reproducible across seeds\", \"plan_id\": \"plan001\", \"wall_clock_seconds\": 10020.8, \"gpu_hours\": 2.78}, \"reproduce\": {\"finished_at\": \"2026-05-14T03:13:08.926Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T03:13:12.957272+00:00\"}]}, \"metrics\": {\"eval_sampling_prove_rate\": 0.14, \"eval_sampling_mean_isr\": 0, \"eval_sampling_n_proved\": 14, \"eval_sampling_temperature\": 0.7, \"eval_sampling_method\": \"do_sample=True, temperature=0.7\", \"eval_sampling_by_answer\": {\"true\": {\"count\": 34, \"proved\": 6, \"prove_rate\": 0.176}, \"false\": {\"count\": 25, \"proved\": 2, \"prove_rate\": 0.08}, \"unknown\": {\"count\": 41, \"proved\": 6, \"prove_rate\": 0.146}}, \"eval_greedy_prove_rate\": 0.13, \"eval_greedy_mean_isr\": 0, \"eval_greedy_proved_only_isr\": 0, \"eval_greedy_n_proved\": 13, \"eval_greedy_method\": \"eval_sta.py default (do_sample=False)\", \"eval_greedy_by_answer\": {\"true\": {\"count\": 34, \"proved\": 4, \"prove_rate\": 0.118}, \"false\": {\"count\": 25, \"proved\": 5, \"prove_rate\": 0.2}, \"unknown\": {\"count\": 41, \"proved\": 4, \"prove_rate\": 0.0976}}, \"eval_greedy_h7_count\": 0, \"eval_greedy_h7_rate\": 0, \"eval_greedy_h1_count\": 13, \"eval_greedy_h1_rate\": 1, \"eval_greedy_genuine_rate\": 0, \"eval_greedy_n_premises_proved_mean\": 17.92, \"eval_greedy_mean_components_proved\": 18.92, \"eval_greedy_n_premises_all_mean\": 32.67, \"eval_sampling_h1_rate\": 1, \"eval_sampling_h7_rate\": 0, \"eval_sampling_genuine_rate\": 0, \"eval_sampling_mean_components_proved\": 18.5, \"eval_greedy_vs_sampling_delta_pr\": -0.01, \"eval_method_note\": \"Greedy and sampling agree on failure profile (ISR*=0, H1=100%, components~18.5-18.9). s43 collapse is decoding-invariant.\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_r4\", \"log_path\": \"/root/runs/solver-trace-ablation/plan001-exec-only-s43-r4.log\", \"conclusion\": \"negative\", \"notes\": \"EXP-2 (2026-05-15): greedy eval (T=0) on same 100 held-out problems also done with eval_sta.py defaults (do_sample=False). Result: PR=0.13, ISR*=0.0, H1=100% (13/13), H7=0%, genuine=0%, mean components (proved)=18.92. Sampling (T=0.7) baseline: PR=0.14, ISR*=0.0, H1=100% (14/14), components~18.5. ΔPR=-0.01, both ISR*=0 → s43 collapse is decoding-invariant, NOT a sampling artifact. ~85% of inputs hit max_new_tokens with long repeated-clause outputs; the ~15% that do parse contain the conclusion verbatim among 14-30 premises (n_necessary=0 by per-clause ablation → ISR=0). 训练 PR(last100)=0.883 但 eval PR=13-14% across decoders, ISR=0。与 s42 (eval PR=93%) 形成极端跨 seed 不稳定。Checkpoint 已删除（C003）。Report: outputs/h7_classification/exp2_s43_greedy_vs_sample.txt.\", \"completed_at\": \"2026-05-14T04:27:38.542Z\"}, \"plan006-prolog-sta-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:19:39.743Z\", \"updated_at\": \"2026-05-14T18:47:53.131Z\", \"hypothesis\": \"Prolog exec+STA GRPO seed=44: 第三 seed。3-seed mean±std 用于论文 Claim 3 跨 logic type 统计支撑。\", \"notes\": \"Reviewer 独立核实: query-as-fact gaming, 0% genuine. 97/97 proved 样本中 95/97 n_necessary=1（功能性 H7）。模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。PR=0.97, ISR=0.885 是 gaming artifact（高 ISR 因单 clause = query）。第三种 Goodhart pathway（vs s42 clean H7, s43 degenerate syntax H1）。对照: s42=negative (clean H7=100%), s43=negative (uppercase pseudo-Prolog H1=97.4%), s44=negative (query-as-fact gaming, functional H7=95/97).\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T16:46:42.163Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s44\\\"\", \"finished_at\": \"2026-05-14T18:17:19.877Z\", \"training_hours\": 1.51}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"908945\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s44.log\", \"submitted_at\": \"2026-05-14T16:52:27.078Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 5546.5, \"gpu_hours\": 1.54}, \"pid\": \"908945\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:17:22.483042+00:00\"}]}, \"metrics\": {\"pass_rate\": 0.97, \"isr_mean\": 0.885, \"isr_n_cl_ge3\": \"N/A (0 samples)\", \"n_clauses_dist\": \"78/100 single-clause, 22/100 two-clause\", \"h7_functional_rate\": 0.979, \"genuine_rate\": 0, \"premise_count_analysis\": \"100% artifact - zero samples with n_clauses>=3, model exclusively generates 1-2 clause programs\", \"failure_mode\": \"query-as-fact gaming (total H7 collapse)\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s44/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:24:53.618Z\"}, \"plan006-prolog-sta-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:19:39.141Z\", \"updated_at\": \"2026-05-14T18:20:56.947Z\", \"hypothesis\": \"Prolog exec+STA GRPO seed=43: 跨 seed 稳定性检查。与 exec-only s43 对照。\", \"notes\": \"Eval: PR=0.38, ISR=0.185 proved-only. Strict classifier: H7=0%, H1=0%, Genuine=100%. 但功能分析显示所有 38 proved 样本 n_necessary=1（功能性 H7）。模型生成大写伪 Prolog（如 MARY_IS_AN_AVADEOTE.）—— 非标准语法，strict classifier 无法匹配 conclusion。与 s42 (clean H7=100%) 不同的 Goodhart 路径，但同样是 hacking。磁盘 240G/250G 需清理。\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"901135\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s43.log\", \"submitted_at\": \"2026-05-14T16:36:41.878Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s43\", \"wall_clock_seconds\": 6158.3, \"gpu_hours\": 1.71}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"901135\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s43\\\"\", \"finished_at\": \"2026-05-14T18:03:44.715Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:03:46.512937+00:00\"}]}, \"metrics\": {\"train\": {\"final_prove_rate\": 0.769, \"final_mean_isr\": 0.129, \"final_loss\": 0.0155, \"final_entropy\": 0.09, \"final_reward\": 0.573, \"completion_length_mean\": 143, \"train_runtime_seconds\": 5095, \"train_runtime_minutes\": 84.9}, \"eval\": {\"n_problems\": 100, \"n_proved\": 38, \"prove_rate\": 0.38, \"mean_isr\": 0.0704, \"isr_std\": 0.1263, \"median_isr\": 0, \"proved_only_mean_isr\": 0.1853, \"min_isr\": 0, \"max_isr\": 1, \"by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 11, \"prove_rate\": 0.44, \"mean_isr\": 0.1003}, \"unknown\": {\"count\": 41, \"proved\": 11, \"prove_rate\": 0.268, \"mean_isr\": 0.0394}, \"true\": {\"count\": 34, \"proved\": 16, \"prove_rate\": 0.471, \"mean_isr\": 0.0859}}}, \"h7_classification\": {\"h7_strict\": 0, \"h7_rate\": 0, \"h1_strict\": 37, \"h1_rate\": 0.974, \"conclusion_in_premise_total\": 37, \"conclusion_in_premise_rate\": 0.974, \"genuine_count\": 0, \"genuine_rate\": 0, \"isr_1_count\": 1, \"note\": \"1 pseudo-genuine sample (folio_1415) has query embedded in single mega-clause; all 38/38 proved samples are tautological\"}}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:19:20.203Z\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s43\"}, \"plan016-extended-1000-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T05:29:47.634Z\", \"updated_at\": \"2026-05-14T17:34:52.375Z\", \"hypothesis\": \"Extended training 1000 steps exec-only: plan001-s42 500步 PR=93% 是真收敛还是 lucky early convergence? 1000步观察 PR 和 ISR 在更长 horizon 的行为。s43(14%)/s44(98% tautological) 在 500 步均失败，延长训练是否能改善？\", \"parent\": \"plan001-exec-only-s42-r2\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --output_dir /root/autodl-tmp/outputs/plan016_extended_1000_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Extended training 1000 steps exec-only: plan001-s42 500步 PR=93% 是真收敛还是 lucky early convergence?\", \"plan_id\": \"plan016\", \"reward_formula\": \"r = r_exec (exec-only)\", \"num_steps\": 1000}, \"pid\": \"263268\", \"log_path\": \"~/runs/solver-trace-ablation/plan016-extended-1000-s42.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --output_dir /root/autodl-tmp/outputs/plan016_extended_1000_s42\\\"\", \"finished_at\": \"2026-05-14T08:02:31.805Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T08:02:33.434519+00:00\"}]}, \"metrics\": {\"prove_rate\": 0.96, \"isr\": 0.003, \"n_proved\": 96, \"components\": 18.55, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 96, \"h1_rate\": 1, \"genuine_count\": 0, \"genuine_rate\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan016_extended_1000_s42\", \"completed_at\": \"2026-05-14T08:13:51.754Z\", \"notes\": \"Extended training to 1000 steps CONFIRMS ISR collapse worsens monotonically.\\\\n\\\\n## 500 vs 1000 step comparison (eval_sta.py):\\\\n| Metric | plan001-s42 (500步) | plan016 (1000步) | Change |\\\\n|--------|-------------------|-----------------|--------|\\\\n| eval PR | 0.93 | 0.96 | +3.2% |\\\\n| eval ISR | 0.123 | 0.0027 | -97.8% |\\\\n| proved_only ISR | 0.132 | 0.0028 | -97.9% |\\\\n| components | 6.58 | 18.55 | +182% |\\\\n| ISR=0 ratio | - | 94.8% | - |\\\\n| n_necessary=0 ratio | - | 94.8% | - |\\\\n\\\\n## Key findings:\\\\n1. PR improves (+3%) but ISR collapses near-zero (0.0027). The model gets BETTER at proving while becoming WORSE at faithful reasoning.\\\\n2. Component count nearly tripled (6.58→18.55). Model generates longer proofs with more components, but 94.8% have ZERO necessary components.\\\\n3. NOT tautological collapse (comp=2 ratio=0). Instead: contradiction-based collapse — model embeds P(a) and ¬P(a) among many irrelevant premises, making anything provable via explosion.\\\\n4. Windowed ISR trend is monotonically decreasing: 0.1115 (101-200) → 0.0433 (401-500) → 0.0200 (601-700) → 0.0144 (901-1000). No recovery signal.\\\\n5. The exec-only reward creates a pure reward hacking incentive: the model discovers that contradictions + trivially true conclusions always satisfy the prover.\\\\n\\\\n## Implication for paper:\\\\nExtended training is a clean ablation showing exec-only reward's failure mode worsens over time. The 500-step ISR of 0.123 was not a floor — it was a snapshot of ongoing collapse.\"}, \"plan006-prolog-sta-s42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-14T09:19:38.117Z\", \"updated_at\": \"2026-05-14T16:49:42.052Z\", \"hypothesis\": \"Prolog exec+STA GRPO seed=42: ISR reward 在 Prolog logic type 上的效果。与 plan006-prolog-exec-s42 (exec-only) 对照，验证 STA/ISR 的 hacking 检测和 Goodhart 效应是否跨 logic type 泛化。\", \"server\": \"westd-39279\", \"gpu\": \"\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T09:49:40.272Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s42\\\"\", \"finished_at\": \"2026-05-14T10:38:13.891Z\", \"training_hours\": 0.81}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-14T09:46:00.917Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:46:02.621139+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T10:38:15.900825+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"第二次启动失败。根因：config reward_mode=execution_sta (0.5*exec+0.5*ISR) 可能与 FOL 实验不匹配，待 Director 确认后修复重启。cuda:1 释放给 plan018。\"}}, \"account\": \"root\", \"notes\": \"Eval metrics provenance: eval 在训练完成后立即在 westd-39279 服务器上运行 eval_sta.py，checkpoint 路径 /root/autodl-tmp/outputs/plan006_prolog_sta_s42/。Eval 结果由 Worker 从服务器 SSH 读取 eval_results.json 并手动录入 registry。Checkpoint 可能已被磁盘清理删除（C003 save_total_limit=1）。训练日志: ~/runs/solver-trace-ablation/plan006-prolog-sta-s42.log。H7 分类由 classify_h7.py 在 eval 目录上运行。\", \"spec\": {\"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s42\\\"\", \"pid\": \"506117\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s42.log\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s42/ (may be cleaned up per C003)\", \"metrics\": {\"cumulative_prove_rate\": 0.848, \"cumulative_mean_isr\": 0.787, \"final_prove_rate\": 1, \"final_isr\": 1, \"final_reward\": 1, \"saturation_onset_step\": 100, \"train_loss\": 0.00716, \"training_hours\": 0.78, \"final_entropy\": 0.01, \"final_completion_length\": 27, \"initial_completion_length\": 120, \"steps_at_perfect_reward\": 400, \"train_runtime_sec\": 2791, \"eval_prove_rate\": 0.5, \"eval_mean_isr\": 0.5, \"eval_proved_only_isr\": 1, \"eval_h7_rate\": 1, \"eval_h7_count\": 50, \"eval_proved_count\": 50, \"eval_total_count\": 100, \"eval_n_clauses_mean\": 1, \"eval_isr_distribution\": \"binary: 50x0 + 50x1\"}}, \"plan006-prolog-exec-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:13:35.647Z\", \"updated_at\": \"2026-05-14T16:27:18.570Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=44: third seed for Prolog exec-only. Together with s42 (PR=83%, ISR=0.031) and s43, provides 3-seed evidence for cross-logic generalization claim (Claim 3). 3-seed mean±std required for paper.\", \"notes\": \"Eval 完成。PR=21% (3-seed 最低), ISR=0.081, proved_only_ISR=0.387 (max_ISR=1.0)。与 s42/s43 不同模式：PR 极低但 proved_only_ISR 较高，可能有少量样本 ISR=1 (H7-like)。Prolog exec-only 3-seed 汇总：s42 PR=83%/ISR=0.031, s43 PR=56%/ISR=0.008, s44 PR=21%/ISR=0.081。Mean PR=53.3%±31.1%, Mean ISR=0.040±0.037。跨 seed 极不稳定（PR std=31pp），与 FOL exec-only 一致。ISR 始终极低（<0.1），确认 Prolog exec-only 不产生 genuine reasoning traces。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T13:43:55.707Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s44\\\"\", \"finished_at\": \"2026-05-14T15:20:42.126Z\", \"training_hours\": 1.61}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"479357\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s44.log\", \"submitted_at\": \"2026-05-14T13:43:57.850Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9800.7, \"gpu_hours\": 2.72}, \"pid\": \"479357\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:20:44.093424+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.21, \"eval_mean_isr\": 0.0812, \"eval_isr_std\": 0.2343, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.3866, \"eval_min_isr\": 0, \"eval_max_isr\": 1, \"eval_n_proved\": 21, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_elapsed_seconds\": 683.9, \"eval_by_type_false_pr\": 0.04, \"eval_by_type_false_isr\": 0.04, \"eval_by_type_unknown_pr\": 0.317, \"eval_by_type_unknown_isr\": 0.099, \"eval_by_type_true_pr\": 0.206, \"eval_by_type_true_isr\": 0.09, \"solver\": \"PrologSolver\", \"logic_type\": \"prolog\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_exec_s44/checkpoint-500\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T16:27:18.570Z\"}, \"plan009-sft-baseline-s42-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:40:28.142Z\", \"updated_at\": \"2026-05-14T16:27:01.864Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B, same model as all GRPO experiments) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. r4: fix CUDA_VISIBLE_DEVICES + --gpu + --no_wandb.\", \"parent\": \"plan009-sft-baseline-s42-r2\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s42 --num_steps 500 --seed 42 --no_wandb --gpu 1\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42/checkpoint-500/\"}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"notes\": \"r4 训练完成 (500 steps, TRL SFT). Checkpoint 实际保存在 plan009_sft_baseline_s42（非 plan009_sft_s42_r4）。两卡满载 (cuda:0 80GB, cuda:1 80GB)，eval 待 GPU 释放。checkpoint-500/ 含 15GB optimizer.pt 可在 eval 后清理。\", \"reproduce\": {\"finished_at\": \"2026-05-14T12:18:55.639Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:18:57.313588+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42/checkpoint-500/\", \"log_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42/checkpoint-500/trainer_state.json\", \"metrics\": {\"eval_prove_rate\": 0.14, \"eval_mean_isr\": 0.08, \"eval_isr_std\": 0.214, \"eval_median_isr\": 0, \"eval_max_isr\": 0.833, \"eval_proved_only_isr\": 0.571, \"eval_n_proved\": 14, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"train_final_loss\": 0.0287, \"train_token_accuracy\": 0.9935, \"train_epochs\": 7.94, \"train_runtime_sec\": 789.6, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 13, \"pr\": 0.382, \"isr\": 0.226}, \"unknown\": {\"count\": 41, \"proved\": 1, \"pr\": 0.024, \"isr\": 0.008}, \"false\": {\"count\": 25, \"proved\": 0, \"pr\": 0, \"isr\": 0}}, \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.071, \"h1_count\": 1, \"genuine_rate\": 0.929, \"genuine_count\": 13, \"hacking_patterns\": \"near-zero (1/14 H1, 0 H7, 92.9% genuine)\", \"tautological_collapse\": false}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:20:25.035Z\"}, \"plan006-prolog-exec-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:38:23.818Z\", \"updated_at\": \"2026-05-14T16:16:56.523Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=43 r3: warmup_ratio=0.0 与 s42 一致。r2 因残留进程 OOM 失败，cuda:1 已清理。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T13:44:06.728Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r3\\\"\", \"finished_at\": \"2026-05-14T15:54:25.754Z\", \"training_hours\": 2.17}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"483820\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r3.log\", \"submitted_at\": \"2026-05-14T13:44:08.516Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9168.0, \"gpu_hours\": 2.55}, \"pid\": \"483820\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r3.log\", \"notes\": \"Eval 完成。PR=56% (远低于 s42 的 83%), ISR=0.0084 (与 s42 的 0.031 同量级，均极低)。proved_only_ISR=0.015。Prolog exec-only 跨 seed 表现：s42 PR=83%/ISR=0.031, s43 PR=56%/ISR=0.008。s43 prove_rate 显著下降但 ISR 模式一致（极低，ground fact enumeration hacking）。与 FOL exec-only 类似，存在跨 seed 不稳定性（FOL: s42=93%, s43=14%, s44=98%）。等 s44 eval 完成后计算 3-seed mean±std。\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:54:27.521808+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.56, \"eval_mean_isr\": 0.0084, \"eval_isr_std\": 0.0221, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.015, \"eval_min_isr\": 0, \"eval_max_isr\": 0.1, \"eval_n_proved\": 56, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_elapsed_seconds\": 868.2, \"eval_by_type_false_pr\": 0.48, \"eval_by_type_false_isr\": 0.0043, \"eval_by_type_unknown_pr\": 0.6585, \"eval_by_type_unknown_isr\": 0.0114, \"eval_by_type_true_pr\": 0.5, \"eval_by_type_true_isr\": 0.0078, \"solver\": \"PrologSolver\", \"logic_type\": \"prolog\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_exec_s43_r3/checkpoint-500\", \"completed_at\": \"2026-05-14T16:16:56.523Z\"}, \"plan018-additive-random-b01-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:18.722Z\", \"updated_at\": \"2026-05-14T15:00:09.178Z\", \"hypothesis\": \"Random β=0.1 seed=44 控制组：与 plan002-b01-s44 (ISR β=0.1) 同 seed 对照。验证 ISR 3.2x > random 的结论在 s44 下是否成立。\", \"parent\": \"plan018-additive-random-b01-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T11:34:13.338Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s44\\\"\", \"finished_at\": \"2026-05-14T13:37:42.200Z\", \"training_hours\": 2.06}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"564900\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"num_steps\": 500}, \"pid\": \"564900\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:37:43.236026+00:00\"}]}, \"metrics\": {\"prove_rate\": 0.89, \"mean_isr\": 0.0619, \"isr_std\": 0.1756, \"median_isr\": 0, \"proved_only_mean_isr\": 0.0695, \"n_proved\": 89, \"n_problems\": 100, \"max_isr\": 1, \"min_isr\": 0, \"isr_pr_ratio\": 0.0695, \"isr_zero_count\": 72, \"isr_one_count\": 2, \"by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 21, \"prove_rate\": 0.84, \"mean_isr\": 0.0533}, \"unknown\": {\"count\": 41, \"proved\": 40, \"prove_rate\": 0.976, \"mean_isr\": 0.0892}, \"true\": {\"count\": 34, \"proved\": 28, \"prove_rate\": 0.824, \"mean_isr\": 0.0353}}, \"elapsed_seconds\": 1012.7, \"eval_method\": \"eval_sta.py with Prover9Solver, FOL\"}, \"conclusion\": \"success\", \"notes\": \"DONE (success). Random β=0.1 s44 对照分析完成: PR=0.89/ISR=0.062 (clean) vs ISR β=0.1 s44 PR=0.89/ISR=0.803 (H7=86.5% inflated). 同 PR 下 ISR reward 导致 conclusion duplication，random 无此问题。与 s42 结论一致: ISR s42 genuine ISR=0.337 vs Random s42 ISR=0.104 (3.2x)。Random 2/3 seeds done, 等 s43 (plan018-random-b01-s43-r2 QUEUED)。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s44/checkpoint-500\", \"completed_at\": \"2026-05-14T14:29:21.226Z\"}, \"plan009-sft-baseline-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:51:58.328Z\", \"updated_at\": \"2026-05-14T14:20:43.363Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. Same model as all GRPO experiments for fair comparison.\", \"conclusion\": \"killed\", \"notes\": \"模型必须改为 Qwen3-4B（与 GRPO 实验一致）。用 Qwen2.5-1.5B 无法作为 fair baseline——模型不同无法隔离训练方法差异。修正模型后重新注册提交。\", \"completed_at\": \"2026-05-14T14:20:42.452Z\"}, \"plan006-prolog-exec-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:32:37.140Z\", \"updated_at\": \"2026-05-14T13:43:01.701Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=43 r2: 修正 warmup_ratio=0.0 与 s42 一致。cross-seed stability check for Prolog logic type.\", \"parent\": \"plan006-prolog-exec-s43\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"712243\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r2.log\", \"submitted_at\": \"2026-05-14T12:33:05.887Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 136.2, \"gpu_hours\": 0.04}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"712243\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r2\\\"\", \"finished_at\": \"2026-05-14T12:35:20.730Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 48.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 40.25 MiB is free. Process 587160 has 78.09 GiB memory in use. Including non-PyTorch memory, this process has 16.83 GiB memory in use. Of the allocated \", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T12:35:22.121Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:35:23.802887+00:00\"}]}, \"notes\": \"OOM 诊断：非 batch size 问题。根因是 kill_job 只杀了 tmux 包装进程 (PID 587155)，训练子进程 587159/587160 残留在 cuda:1 上占 78.09 GiB 显存。s43-r2 启动时 cuda:1 仅剩 40 MiB free，首次前向传播即 OOM (尝试分配 48 MiB)。教训：kill_job 后必须 SSH 确认子进程也已终止（ps aux grep + nvidia-smi），不能只看 PID 返回成功。\"}, \"plan006-prolog-exec-s42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-14T07:13:34.169Z\", \"updated_at\": \"2026-05-14T12:33:17.845Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=42: STA/ISR hacking patterns generalize across logic types? Prolog uses rule ablation (vs FOL axiom ablation). If same degeneration modes appear → STA is logic-agnostic diagnostic.\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T09:49:36.534Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s42\\\"\", \"finished_at\": \"2026-05-14T11:29:25.346Z\", \"training_hours\": 1.66}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-14T09:47:36.390Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:47:38.546001+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:29:27.709792+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"失败原因: FileNotFoundError — data/prolog/train_500_seed42.jsonl 不存在 | error_type: data | 同一原因影响所有 plan006 实验 (exec/sta × s42/s43/s44) | 建议: 需先生成 Prolog 训练数据再重试\"}}, \"account\": \"root\", \"notes\": \"Eval (eval_sta.py) 完成。PR=83%, mean_ISR=0.031, proved_only_ISR=0.037, H7=0%, H1=0%。与 sta-s42 (PR=50%, ISR=1.0, H7=100%) 形成鲜明对比。exec-only 产生完全不同的 hacking 模式：ground fact enumeration（倾泻大量无关 ground facts，query 作为其中一个 fact 平凡成功），而非 sta-s42 的 tautological collapse。两种 reward signal 驱动两种不同的 hacking 策略。对论文是 positive finding：强化 Claim 1 且揭示 reward-specific hacking 机制。\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"506020\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42}, \"metrics\": {\"eval_prove_rate\": 0.83, \"eval_mean_isr\": 0.031, \"eval_proved_only_isr\": 0.037, \"eval_median_isr\": 0, \"eval_max_isr\": 0.2, \"eval_isr_std\": 0.0534, \"h7_rate\": 0, \"h1_rate\": 0, \"isr_1_rate\": 0, \"single_premise_rate\": 0, \"by_answer_type\": {\"true\": {\"proved\": 37, \"count\": 40, \"pr\": 0.925, \"isr\": 0.037}, \"false\": {\"proved\": 21, \"count\": 29, \"pr\": 0.724, \"isr\": 0.038}, \"unknown\": {\"proved\": 25, \"count\": 31, \"pr\": 0.806, \"isr\": 0.016}}}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_exec_s42/checkpoint-500\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s42.log\"}, \"plan006-prolog-exec-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:13:35.078Z\", \"updated_at\": \"2026-05-14T12:32:13.799Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=43: cross-seed stability check for Prolog logic type. FOL showed extreme cross-seed variance (s42 genuine vs s43 degraded vs s44 tautological). Prolog exec-only s42 showed PR=83%, ISR=0.031. s43 tests if Prolog also has seed instability.\", \"notes\": \"KILLED at step 36/500: warmup_ratio=0.1 与 s42 (0.0) 不一致，3-seed 对比无效。重启为 plan006-prolog-exec-s43-r2 (warmup_ratio=0.0)。\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43 --warmup_ratio 0.1\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"587155\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43.log\", \"submitted_at\": \"2026-05-14T12:22:08.915Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"wall_clock_seconds\": 602.2, \"gpu_hours\": 0.17}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"587155\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43 --warmup_ratio 0.1\\\"\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T12:32:11.136Z\"}, \"plan009-sft-baseline-s42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:37:49.306Z\", \"updated_at\": \"2026-05-14T11:48:05.087Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B, same model as all GRPO experiments) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. Compare eval PR/ISR/hacking taxonomy against GRPO exec-only and exec+ISR conditions.\", \"parent\": \"plan009-sft-baseline-s42-r2\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_s42_r3 --num_steps 500 --seed 42 --bf16 --wandb_project solver-trace-ablation --wandb_run plan009-sft-s42-r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"566690\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s42-r3.log\", \"submitted_at\": \"2026-05-14T11:39:19.395Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18.5, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"566690\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s42-r3.log\", \"wandb_run_id\": \"plan009-sft-s42-r3\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_s42_r3 --num_steps 500 --seed 42 --bf16 --wandb_project solver-trace-ablation --wandb_run plan009-sft-s42-r3\\\"\", \"wandb_run_id\": \"plan009-sft-s42-r3\", \"finished_at\": \"2026-05-14T11:39:36.697Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T11:39:37.935Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:39:39.416777+00:00\"}]}, \"notes\": \"r3 crash root cause: wandb.init() failed because no W&B API key configured on server (no .netrc, no WANDB_API_KEY). Fix: add --no_wandb flag. Secondary issue: both GPUs currently near-full, need to wait for GPU availability before r4. Correct r4 command: export CUDA_VISIBLE_DEVICES=N && ... python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_s42_r4 --num_steps 500 --seed 42 --no_wandb\"}, \"plan009-sft-baseline-s42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:02:25.369Z\", \"updated_at\": \"2026-05-14T11:43:20.347Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B, same model as all GRPO experiments) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. Compare eval PR/ISR/hacking taxonomy against GRPO exec-only and exec+ISR conditions.\", \"plan_id\": \"plan_009\", \"notes\": \"SFT baseline with Qwen3-4B (same model as GRPO experiments). Replaces killed plan009-sft-baseline-s42 which incorrectly used Qwen2.5-1.5B. cuda:1, seed=42, 500 steps, FOLIO data (data/train_500_seed42.jsonl). Dream 审稿三档均指出缺 SFT baseline 是 gap。**FAILED**: 两个问题：(1) W&B API key 未配置，trainer.train() 启动时 wandb callback 报 UsageError; (2) device_map='auto' 把模型分到多 GPU，需改为单卡绑定。修复方案：加 WANDB_MODE=disabled + 改 train_sft.py 的 device_map 为单卡。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s42 --num_steps 200 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"548527\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s42-r2.log\", \"submitted_at\": \"2026-05-14T11:08:22.511Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 236.8, \"gpu_hours\": 0.07}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T11:12:19.306Z\", \"failure_reason\": \"OOM: 缺少 CUDA_VISIBLE_DEVICES 显式设置，device_map='auto' 跨 GPU 侵入 cuda:0 (plan006)，导致双卡 OOM。修复：(1) 启动命令加 --gpu 1，(2) device_map 改为 {\\\"\\\": 0} 或 .to(\\\"cuda\\\")，(3) num_steps 改为 500\"}, \"plan018-additive-random-b01-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:18.260Z\", \"updated_at\": \"2026-05-14T11:42:09.950Z\", \"hypothesis\": \"Random β=0.1 seed=43 控制组：与 plan002-b01-s43 (ISR β=0.1) 同 seed 对照。验证 ISR 3.2x > random 的结论在 s43 下是否成立。\", \"parent\": \"plan018-additive-random-b01-s42\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"540910\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43.log\", \"submitted_at\": \"2026-05-14T10:58:27.110Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"checkpoint_source\": \"plan018-additive-random-b01-s42\", \"eval_data\": \"data/train_500_seed42.jsonl\", \"wall_clock_seconds\": 1929.4, \"gpu_hours\": 0.54}, \"reproduce\": {\"finished_at\": \"2026-05-14T11:30:34.690Z\"}, \"failure_reason\": \"磁盘满 (No space left on device): /root/autodl-tmp/ 250G/250G 100% 占满。训练在 step 200/500 保存 checkpoint-200 时 safetensors 序列化失败 (os error 28)。根因: 多个已完成实验的 checkpoint 未清理。可重试——清理磁盘后重跑。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T11:30:36.549Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:30:40.886615+00:00\"}]}, \"notes\": \"Disk full (os error 28) at step 200/500 during checkpoint save. Training ran fine for 200 steps but safetensors serialization failed with \\\"No space left on device\\\". No checkpoint saved. Disk now has 109G free. Retryable as-is.\"}, \"plan012-hacking-taxonomy\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:06:38.613Z\", \"updated_at\": \"2026-05-14T09:07:42.314Z\", \"spec\": {\"command\": \"rule-based hacking taxonomy classification on eval_sta outputs\", \"server\": \"westd-39279\", \"data_path\": \"eval_results.json from plan002-b01-s42 + plan018-b01-s42\", \"data_count\": 160, \"model_name\": \"N/A (rule-based analysis)\", \"seed\": \"N/A\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (analysis task)\", \"log_path\": \"artifacts/hacking_taxonomy_comparison.md\", \"completed_at\": \"2026-05-14T09:07:12.765Z\", \"hypothesis\": \"ISR β=0.1 vs Random β=0.1 hacking taxonomy 对比：ISR reward 能否减少 hacking 模式比例、增加 genuine proof 比例？5 种 hacking 分类（conclusion embedding, repetition collapse, tautological collapse, complexity-without-utility, premise padding）。\", \"metrics\": {\"isr_b01_genuine_rate\": 0.259, \"random_b01_genuine_rate\": 0.177, \"genuine_rate_delta_pp\": 8.2, \"isr_b01_conclusion_embedding_rate\": 0.728, \"random_b01_conclusion_embedding_rate\": 0.785, \"isr_b01_genuine_mean_isr\": 0.6723, \"random_b01_genuine_mean_isr\": 0.3427, \"isr_b01_complexity_wo_utility_rate\": 0, \"random_b01_complexity_wo_utility_rate\": 0.038, \"isr_b01_hacking_rate\": 0.741, \"random_b01_hacking_rate\": 0.823}, \"notes\": \"D037/D038 完成。Conclusion embedding 是主导 hacking 模式（ISR 72.8% vs Random 78.5%）。ISR β=0.1 genuine proof +8.2pp (25.9% vs 17.7%)，genuine ISR 质量 0.67 vs 0.34。ISR 消除 complexity-without-utility hacking。LLM-as-judge 跳过（D038），记入 Discussion/Future Work。Artifact: art_20260514_bf31aa。\"}, \"plan005-sta-low-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:20:47.812Z\", \"updated_at\": \"2026-05-14T06:31:05.119Z\", \"spec\": {\"model_name\": \"Qwen3-4B\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-13T23:55:02.341Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:55:06.559440+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan005_sta_low_s42/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/plan005_sta_low_s42/reward_log.jsonl\", \"completed_at\": \"2026-05-13T23:59:25.396Z\", \"metrics\": {\"total_steps\": 500, \"duration_min\": 71, \"parse_rate\": 1, \"overall_prove_rate\": 0.5657, \"overall_isr\": 0.1682, \"last50_prove_rate\": 0.77, \"last50_isr\": 0.2559, \"last100_prove_rate\": 0.7725, \"last100_isr\": 0.2299, \"last100_loss\": 0.022752, \"overall_loss\": 0.017296, \"last100_isr_pr_ratio\": 0.298, \"last100_isr_lt_pr_count\": \"99/100\", \"first_rolling10_pr_ge_0.8\": 178, \"first_rolling10_pr_ge_0.9\": 439, \"max_rolling10_pr\": 0.9375, \"max_rolling10_isr\": 0.3282, \"windowed\": {\"1-50\": {\"pr\": 0.1775, \"isr\": 0.0906}, \"51-100\": {\"pr\": 0.1775, \"isr\": 0.0835}, \"101-200\": {\"pr\": 0.5062, \"isr\": 0.1463}, \"201-300\": {\"pr\": 0.6713, \"isr\": 0.1791}, \"301-400\": {\"pr\": 0.7013, \"isr\": 0.1984}, \"401-500\": {\"pr\": 0.7725, \"isr\": 0.2299}}}, \"notes\": \"conclusion=negative 基于 prove_rate 下降（last100 0.7725 vs exec-only 0.865）。但结构性发现：ISR/PR ratio=0.298，99/100 步 ISR &lt; PR，说明 STA=0.1 维持了 ISR 与 PR 的持续分离——模型未通过 hacking prove_rate 绕过 STA penalty。此观察支持论文 \\\"STA 抑制 reward hacking\\\" claim。windowed ISR/PR: 1-50 (0.51), 51-100 (0.47), 101-200 (0.29), 201-300 (0.27), 301-400 (0.28), 401-500 (0.30) — 分离在100步后稳定。D030 决策：checkpoint 已删除，不重训。论文用训练曲线 windowed ISR/PR 数据作为证据。\"}, \"plan014-downstream-nli-s42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T03:43:37.925Z\", \"updated_at\": \"2026-05-14T04:29:48.645Z\", \"hypothesis\": \"Downstream NLI validation: 高ISR formalization 应在独立推理任务上表现更好(entailment accuracy)，Spearman ρ(ISR, accuracy) > 0.1 验证 ISR 作为 quality proxy 的实用价值。同时用 Z3 cross-solver agreement 验证 formalization 鲁棒性。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T03:49:52.891Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/eval_downstream.py --checkpoint_path /root/autodl-tmp/outputs/plan001_exec_only_s42 --base_model /root/autodl-tmp/models/Qwen3-4B --data_path data/proofwriter_fol_100.jsonl --output_path /root/autodl-tmp/outputs/plan014_downstream_nli.json --num_generations 8 --workers 4\\\"\", \"finished_at\": \"2026-05-14T04:26:05.334Z\", \"training_hours\": 0.6}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-14T03:51:18.427Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T03:51:19.514390+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:26:06.788787+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"r1 失败: checkpoint_path 多了 /checkpoint-500。save_total_limit=1 导致模型直接保存在 plan001_exec_only_s42/ 根目录。修正路径为 /root/autodl-tmp/outputs/plan001_exec_only_s42 即可。等 s43 re-eval 完成后重跑。\"}}, \"notes\": \"Negative: ISR 作为 downstream NLI quality proxy 无效。Spearman ρ(ISR, correct)=-0.049 (p=0.187)，Best-of-N ISR 仅 +0.9pp over random (不显著)。主因：模型严重 true-bias (false accuracy=0%)，NLI accuracy 天花板仅 34.1%，ISR 无区分空间。ISR bucket 层面有弱单调趋势 (high=75% > mid=37.7% > low=32.7%) 但 high bucket 仅 12 样本。quartile 分析非单调。\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/eval_downstream.py --checkpoint_path /root/autodl-tmp/outputs/plan001_exec_only_s42 --base_model /root/autodl-tmp/models/Qwen3-4B --data_path data/proofwriter_fol_100.jsonl --output_path /root/autodl-tmp/outputs/plan014_downstream_nli.json --num_generations 8 --workers 4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"216133\", \"log_path\": \"~/runs/solver-trace-ablation/plan014-downstream-nli-s42.log\", \"submitted_at\": \"2026-05-14T04:17:30.763Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 737.9, \"gpu_hours\": 0.2}, \"pid\": \"216133\", \"log_path\": \"~/runs/solver-trace-ablation/plan014-downstream-nli-s42.log\", \"conclusion\": \"negative\", \"metrics\": {\"overall_accuracy\": 0.341, \"proved_rate\": 0.915, \"proved_count\": 732, \"total_generations\": 800, \"parse_errors\": 0, \"accuracy_by_label\": {\"true\": 0.912, \"false\": 0, \"unknown\": 0.076}, \"spearman_rho\": -0.049, \"spearman_p\": 0.187, \"mann_whitney_U\": 17202, \"mann_whitney_p\": 0.288, \"bon_isr_accuracy\": 0.35, \"bon_random_accuracy\": 0.341, \"bon_oracle_accuracy\": 0.44, \"bon_prove_first_accuracy\": 0.35, \"isr_bucket_high_acc\": 0.75, \"isr_bucket_mid_acc\": 0.377, \"isr_bucket_low_acc\": 0.327, \"runtime_inference_s\": 408.8, \"runtime_eval_s\": 13.6}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan014_downstream_nli.json\"}, \"plan013-random-reward-s42-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:40:35.587Z\", \"updated_at\": \"2026-05-14T03:45:53.344Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1 --output_dir /root/autodl-tmp/outputs/plan013_random_reward_s42_r4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"136261\", \"log_path\": \"~/runs/solver-trace-ablation/plan013-random-reward-s42-r4.log\", \"submitted_at\": \"2026-05-14T01:40:35.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Random reward baseline: replacing ISR with random values should degrade structural quality while maintaining execution reward, proving ISR's causal contribution\", \"plan_id\": \"plan013\", \"wall_clock_seconds\": 2492.4, \"gpu_hours\": 0.69}, \"reproduce\": {\"finished_at\": \"2026-05-14T02:19:57.306Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T02:19:58.514969+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r4/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r4/reward_log.jsonl\", \"metrics\": {\"eval_prove_rate\": 1, \"eval_mean_isr\": 0.535, \"eval_isr_std\": 0.1282, \"eval_proved_only_isr\": 0.535, \"eval_median_isr\": 0.5, \"eval_n_proved\": 100, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_note\": \"DEGENERATE: model generates trivial 2-component proofs (premise=conclusion, conclusion=conclusion), ISR=0.5 is artifact of trivial proof structure\"}, \"completed_at\": \"2026-05-14T02:22:07.933Z\", \"notes\": \"⚠️ 训练日志 ISR 为 binary approximation (_fast_fn)，ISR≈prove_rate，不含结构信息。真实 ISR 需通过 eval_sta.py (full STA) 在 checkpoint-500 上重新评估。final_mean_isr=0.6705 实为 binary 近似值，禁止用于论文或跨实验 ISR 对比。\"}, \"plan001-exec-only-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:02:31.830Z\", \"updated_at\": \"2026-05-14T01:41:28.427Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"133258\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"exec-only 500 steps seed 43 (r3), 3-seed baseline 2nd seed\", \"plan_id\": \"plan_001\"}, \"conclusion\": \"failed\", \"failure_reason\": \"OSError: [Errno 28] No space left on device — /root/autodl-tmp 磁盘满，TRL GRPOTrainer completions parquet 写入失败 at step 23\", \"checkpoint_path\": \"N/A (disk full crash at step 23)\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_r3/reward_log.jsonl\", \"completed_at\": \"2026-05-14T01:41:28.427Z\"}, \"plan013-random-reward-s42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:02:30.063Z\", \"updated_at\": \"2026-05-14T01:41:28.122Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1 --output_dir /root/autodl-tmp/outputs/plan013_random_reward_s42_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"133178\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Random reward baseline (r3): random value replaces ISR to isolate ISR-specific signal vs multi-objective regularization\", \"plan_id\": \"plan_013\", \"hyperparams\": {\"alpha\": 0.9, \"beta\": 0.1, \"K\": 8, \"num_steps\": 500, \"reward_type\": \"random_penalty\"}}, \"conclusion\": \"failed\", \"failure_reason\": \"OSError: [Errno 28] No space left on device — /root/autodl-tmp 磁盘满，TRL GRPOTrainer completions parquet 写入失败 at step 28\", \"checkpoint_path\": \"N/A (disk full crash at step 28)\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r3/reward_log.jsonl\", \"completed_at\": \"2026-05-14T01:41:28.122Z\"}, \"plan001-exec-only-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:22:12.292Z\", \"updated_at\": \"2026-05-14T01:01:56.416Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"126541\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-r2.log\", \"submitted_at\": \"2026-05-14T00:22:12.241Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"exec-only 500步 seed 43 (retry), 3-seed baseline 第2个 seed\", \"wall_clock_seconds\": 2384.2, \"gpu_hours\": 0.66}, \"checkpoint_path\": \"N/A (crashed after submission)\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_r2/reward_log.jsonl\", \"conclusion\": \"failed\", \"failure_reason\": \"Process crashed after submission (PID 126546 not found, tmux session dead). Worker verified 91% util at submission but process died within 30 min.\", \"completed_at\": \"2026-05-14T01:01:56.416Z\"}, \"plan013-random-reward-s42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:22:10.140Z\", \"updated_at\": \"2026-05-14T01:01:55.694Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1 --output_dir /root/autodl-tmp/outputs/plan013_random_reward_s42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"126461\", \"log_path\": \"~/runs/solver-trace-ablation/plan013-random-reward-s42-r2.log\", \"submitted_at\": \"2026-05-14T00:22:10.091Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Random reward baseline (retry): 用随机值替代 ISR，隔离 ISR-specific signal vs multi-objective regularization effect\", \"wall_clock_seconds\": 2385.6, \"gpu_hours\": 0.66}, \"checkpoint_path\": \"N/A (crashed after submission)\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r2/reward_log.jsonl\", \"conclusion\": \"failed\", \"failure_reason\": \"Process crashed after submission (PID 126466 not found, tmux session dead). Worker verified 91% util at submission but process died within 30 min.\", \"completed_at\": \"2026-05-14T01:01:55.694Z\"}, \"plan013-random-reward-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:56:44.062Z\", \"updated_at\": \"2026-05-14T00:21:05.430Z\", \"spec\": {\"hypothesis\": \"Random reward baseline: 用随机值替代 ISR，隔离 ISR-specific signal vs multi-objective regularization effect\", \"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1\\\"\", \"server\": \"westd-39279\", \"data_path\": \"data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"plan_013\", \"gpu\": \"cuda:0\", \"hyperparams\": {\"alpha\": 0.9, \"beta\": 0.1, \"K\": 8, \"num_steps\": 500, \"reward_type\": \"random_penalty\"}, \"pid\": 122796, \"output_dir\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42\", \"reward_mode\": \"random_reward\", \"exec_weight\": 0.9, \"sta_weight\": 0.1, \"num_steps\": 500}, \"checkpoint_path\": \"N/A (GPU overflow, no valid output)\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42.log\", \"conclusion\": \"failed\", \"failure_reason\": \"CUDA_VISIBLE_DEVICES not set (inline assignment not exported), GPU overflow to both GPUs\", \"completed_at\": \"2026-05-14T00:21:05.430Z\"}, \"plan001-exec-only-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:55:08.635Z\", \"updated_at\": \"2026-05-14T00:21:04.003Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"121275\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43.log\", \"submitted_at\": \"2026-05-13T23:55:08.544Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"exec-only 500步 seed 43, 3-seed baseline 第2个 seed。预期 prove_rate>0.80 (与 s42 一致)\", \"wall_clock_seconds\": 1555.5, \"gpu_hours\": 0.43}, \"checkpoint_path\": \"N/A (killed by OOM before completion)\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43.log\", \"conclusion\": \"failed\", \"failure_reason\": \"OOM by plan013 GPU overflow — plan013 未设 CUDA_VISIBLE_DEVICES 导致占用两张 GPU，plan001-s43 被 OOM kill\", \"completed_at\": \"2026-05-14T00:21:04.003Z\"}, \"plan001-exec-only-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:19:41.568Z\", \"updated_at\": \"2026-05-13T23:03:42.892Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"83029\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s42.log\", \"submitted_at\": \"2026-05-13T22:20:46.569Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"exec-only 500步训练 baseline\", \"wall_clock_seconds\": 2576.3, \"gpu_hours\": 0.72}, \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A (failed before checkpoint)\", \"completed_at\": \"2026-05-13T23:03:42.892Z\"}, \"plan003-eval-exec-only-r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:21:48.691Z\", \"updated_at\": \"2026-05-13T23:03:19.945Z\", \"spec\": {\"command\": \"eval_sta.py on r5 exec-only checkpoint\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"83690\", \"log_path\": \"~/runs/solver-trace-ablation/plan003-eval-exec-only-r5.log\", \"submitted_at\": \"2026-05-13T22:21:48.658Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_100.jsonl\", \"data_count\": 100, \"model_name\": \"Qwen3-4B (r5 exec-only checkpoint)\", \"seed\": 0, \"checkpoint_source\": \"sta-phase1-exec-only-r5\", \"eval_data\": \"proofwriter_fol_100\", \"hypothesis\": \"Full STA eval on exec-only 100-step checkpoint to measure formalization quality\", \"wall_clock_seconds\": 2490.2, \"gpu_hours\": 0.69}, \"metrics\": {\"prove_rate\": 0.32, \"mean_isr\": 0.2055, \"isr_std\": 0.3194, \"proved_only_isr\": 0.6423, \"isr_by_type\": {\"true\": 0.3598, \"false\": 0.1723, \"unknown\": 0.0979}, \"total_samples\": 100, \"proved_count\": 32, \"runtime_s\": 251.7}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan003_eval_exec_only_r5.json\", \"log_path\": \"~/runs/solver-trace-ablation/plan003-eval-exec-only-r5.log\", \"completed_at\": \"2026-05-13T23:03:18.848Z\"}, \"plan001-exec-only-s42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:42:40.242Z\", \"updated_at\": \"2026-05-13T23:03:11.395Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"85710\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s42-r3.log\", \"submitted_at\": \"2026-05-13T22:42:40.204Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"exec-only 500步训练 baseline (retry 3)\", \"wall_clock_seconds\": 1228.1, \"gpu_hours\": 0.34}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T23:03:08.298Z\", \"failure_reason\": \"OOM crash - duplicate submission while plan001-r2 was occupying cuda:0\"}, \"sta-phase1-exec-sta-r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:54:31.353Z\", \"updated_at\": \"2026-05-13T22:20:41.274Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=1 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"75968\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r5.log\", \"submitted_at\": \"2026-05-13T20:54:38.781Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Full STA continuous ISR (0.0-1.0) 作为 reward 组件，应在训练中产生与 execution-only 不同的 ISR 趋势——execution-only ISR 随 prove_rate 上升而虚高(reward hacking)，execution+STA ISR 维持真实水平(STA 抑制 hacking)\", \"wall_clock_seconds\": 3506.3, \"gpu_hours\": 0.97}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.1, \"mean_isr\": 0.04347, \"last20_prove_rate\": 0.15, \"last20_isr_mean\": 0.04956, \"first20_prove_rate\": 0.08125, \"first20_isr_mean\": 0.05182, \"overall_reward_mean\": 0.07174, \"last20_reward_mean\": 0.09978, \"training_steps\": 100, \"training_minutes\": 16.9, \"step_time_s\": 10.13, \"isr_pr_ratio_overall\": 0.43, \"isr_pr_ratio_last20\": 0.33, \"K\": 8}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_sta/\", \"log_path\": \"/root/autodl-tmp/outputs/grpo_exec_sta/reward_log.jsonl\", \"completed_at\": \"2026-05-13T21:53:05.068Z\"}, \"sta-phase1-exec-only-r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:54:27.505Z\", \"updated_at\": \"2026-05-13T21:53:04.486Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"75890\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r5.log\", \"submitted_at\": \"2026-05-13T20:54:37.293Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"K=8 增加 within-group variance，减少全零 reward batch，使 GRPO 有更多有效梯度信号\", \"wall_clock_seconds\": 3507.2, \"gpu_hours\": 0.97}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.15125, \"mean_isr\": 0.1475, \"last20_prove_rate\": 0.2, \"last20_isr_mean\": 0.2, \"first20_prove_rate\": 0.11875, \"first20_isr_mean\": 0.11875, \"overall_reward_mean\": 0.15125, \"last20_reward_mean\": 0.2, \"training_steps\": 100, \"training_minutes\": 15.7, \"step_time_s\": 9.44, \"isr_pr_ratio_last20\": 1, \"K\": 8}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_only/\", \"log_path\": \"/root/autodl-tmp/outputs/grpo_exec_only/reward_log.jsonl\", \"completed_at\": \"2026-05-13T21:53:04.486Z\"}, \"sta-phase1-exec-sta-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:28:22.778Z\", \"updated_at\": \"2026-05-13T20:52:58.761Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=1 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"70797\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r4.log\", \"submitted_at\": \"2026-05-13T20:28:32.091Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1404.7, \"gpu_hours\": 0.39}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T20:28:31.240Z\", \"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=1 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T20:45:55.480Z\", \"training_hours\": 0.29}, \"pid\": \"70797\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r4.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:45:56.962544+00:00\"}]}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.1575, \"mean_isr\": 0.1525, \"last20_prove_rate\": 0.2125, \"last20_isr_mean\": 0.2125, \"first20_reward_mean\": 0.119, \"training_steps\": 100, \"training_minutes\": 15}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_sta/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-13T20:51:56.799Z\", \"notes\": \"Phase 1 r4 完成但无差异。fast_isr_fol 二值信号(0/1)对 proved samples 几乎全部 ISR=1，exec+STA reward ≈ exec-only reward。连续 ISR 才能产生有意义的差异信号。→ r5 改用 full sta_reward (continuous ISR 0.0-1.0) + K=8\"}, \"sta-phase1-exec-only-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:28:18.040Z\", \"updated_at\": \"2026-05-13T20:52:56.416Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"70716\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r4.log\", \"submitted_at\": \"2026-05-13T20:28:30.420Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1405.8, \"gpu_hours\": 0.39}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T20:28:28.733Z\", \"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T20:45:53.506Z\", \"training_hours\": 0.29}, \"pid\": \"70716\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r4.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:45:54.294365+00:00\"}]}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.15125, \"mean_isr\": 0.1475, \"last20_prove_rate\": 0.2, \"last20_isr_mean\": 0.2, \"first20_reward_mean\": 0.119, \"training_steps\": 100, \"training_minutes\": 15}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_only/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-13T20:51:56.183Z\", \"notes\": \"Phase 1 r4 完成但无差异。fast_isr_fol 二值信号(0/1)对 proved samples 几乎全部 ISR=1，导致 exec+STA ≈ exec-only。prove_rate 从 baseline 12% → last20 20%（微弱提升）。K=4 导致大量全零 reward batch。→ r5 改用 full STA + K=8\"}, \"sta-phase1-exec-only-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:15:04.067Z\", \"updated_at\": \"2026-05-13T20:23:15.460Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"67225\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r3.log\", \"submitted_at\": \"2026-05-13T20:15:15.911Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 276.4, \"gpu_hours\": 0.08}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T20:15:14.333Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T20:19:51.612Z\", \"training_hours\": 0.08}, \"pid\": \"67225\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r3.log\", \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T20:19:52.268Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:19:52.981720+00:00\"}]}, \"notes\": \"EXIT_CODE=137 (OOM/SIGKILL) after ~276s. 同 sta-phase1-exec-sta-r3 一起诊断中\"}, \"sta-phase1-exec-sta-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:15:08.133Z\", \"updated_at\": \"2026-05-13T20:23:14.516Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"67306\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r3.log\", \"submitted_at\": \"2026-05-13T20:15:17.535Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 277.9, \"gpu_hours\": 0.08}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T20:15:16.704Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T20:19:54.409Z\", \"training_hours\": 0.08}, \"pid\": \"67306\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r3.log\", \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T20:19:55.400Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:19:56.549926+00:00\"}]}, \"notes\": \"EXIT_CODE=137 (OOM/SIGKILL) after ~278s. 诊断中: worker_diagnose_sta-phase1-r3-oom_20260513T202300\"}, \"sta-phase1-exec-sta-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:55:08.640Z\", \"updated_at\": \"2026-05-13T19:55:41.544Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"62364\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r2.log\", \"submitted_at\": \"2026-05-13T19:55:19.065Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 22.5, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T19:55:18.267Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T19:55:40.449Z\", \"training_hours\": 0.01}, \"pid\": \"62364\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r2.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:55:41.544Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:55:42.974865+00:00\"}]}}, \"sta-phase1-exec-only-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:55:04.711Z\", \"updated_at\": \"2026-05-13T19:55:37.426Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"62283\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r2.log\", \"submitted_at\": \"2026-05-13T19:55:17.509Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 19.9, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T19:55:16.037Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T19:55:36.845Z\", \"training_hours\": 0.01}, \"pid\": \"62283\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r2.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:55:37.426Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:55:38.155358+00:00\"}]}}, \"sta-phase1-exec-sta\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:26:53.258Z\", \"updated_at\": \"2026-05-13T19:33:03.905Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"59574\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta.log\", \"submitted_at\": \"2026-05-13T19:32:47.783Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 16.1, \"gpu_hours\": 0.0}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T19:30:58.981Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T19:33:03.170Z\", \"training_hours\": 0.03}, \"pid\": \"59574\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta.log\", \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:33:03.905Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:33:05.009356+00:00\"}]}}, \"sta-phase1-exec-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:26:46.351Z\", \"updated_at\": \"2026-05-13T19:33:01.169Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"59274\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only.log\", \"submitted_at\": \"2026-05-13T19:32:30.340Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 30.8, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T19:32:28.753Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T19:33:00.602Z\", \"training_hours\": 0.01}, \"pid\": \"59274\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only.log\", \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:33:01.169Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:33:01.864437+00:00\"}]}}, \"sta-gt-isr-baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:11:13.283Z\", \"updated_at\": \"2026-05-13T18:12:44.147Z\", \"spec\": {\"command\": \"python3 scripts/gt_isr_baseline.py\", \"server\": \"westd-39279\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_100.jsonl\", \"data_count\": 100, \"model_name\": \"ground-truth-fol\", \"seed\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/solver-trace-ablation/outputs/gt_isr_baseline.json\", \"log_path\": \"/root/solver-trace-ablation/outputs/gt_isr_baseline.json\", \"completed_at\": \"2026-05-13T18:12:43.141Z\", \"metrics\": {\"gt_prove_rate\": 0.18, \"gt_mean_isr\": 0.5588, \"gt_isr_std\": 0.2582, \"gt_isr_median\": 0.6125, \"solver_execution_rate\": 1, \"true_prove_rate\": 0.5, \"true_mean_isr\": 0.5833}}, \"sta-phase0-baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T17:51:48.853Z\", \"updated_at\": \"2026-05-13T18:10:40.982Z\", \"spec\": {\"hypothesis\": \"锚定 base Qwen3-4B 的 ISR baseline，后续判断 GRPO 训练是否导致 ISR 下降（reward hacking）\", \"model_name\": \"Qwen3-4B\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_100.jsonl\", \"data_count\": 100, \"server\": \"westd-39279\", \"data_source\": \"tasksource/folio\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 scripts/phase0_baseline.py --model_path models/Qwen3-4B --data_path data/proofwriter_fol_100.jsonl --output outputs/phase0_baseline.json\", \"seed\": 0, \"checkpoint_path\": \"N/A (inference only)\", \"log_path\": \"/root/solver-trace-ablation/outputs/phase0_baseline.json\", \"notes\": \"conclusion=success 但语义是 baseline_anchored（registry 不支持自定义 conclusion）。此实验是 baseline 锚定，非传统 success/failure。ISR 盲区：premise-conclusion 重复的 trivial formalization 可能获高 ISR，论文 Discussion 需讨论。\"}, \"log_path\": \"/tmp/phase0_baseline.log\", \"checkpoint_path\": \"/root/solver-trace-ablation/outputs/phase0_baseline.json\", \"metrics\": {\"mean_isr\": 0.0641, \"isr_std\": 0.1983, \"median_isr\": 0, \"isr_range\": [0, 0.889], \"prove_rate\": 0.12, \"proved_count\": 12, \"total_samples\": 100, \"xor_affected_samples\": 34, \"effective_prove_rate_no_xor\": 0.182, \"avg_time_per_sample_s\": 3.4, \"total_runtime_s\": 336, \"isr_by_answer\": {\"true\": {\"n\": 34, \"proved\": 9, \"prove_rate\": 0.265, \"mean_isr\": 0.1345}, \"false\": {\"n\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.024}, \"unknown\": {\"n\": 41, \"proved\": 2, \"prove_rate\": 0.049, \"mean_isr\": 0.0302}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T18:04:56.962Z\"}}, \"count\": 86, \"total\": 86, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3303}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01L2NmFxPPWgBHFNhTcVRDjB`</summary>

```json
{
  "project": "solver-trace-ablation",
  "file": "paper_framing.md",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "a86c4f60-1ca2-4da7-84e7-e5d391d36699",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C3knBaWYvdYqAGNqehCL1K",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2043,
      "cache_read_input_tokens": 25495,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2043
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

_source line 11 · 2026-05-15T14:55:46.778Z_

<details><summary>↩ Tool result · `toolu_01L2NmFxPPWgBHFNhTcVRDjB`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_framing.md\", \"content\": \"# Paper Framing — solver-trace-ablation\\n\\n## Target Venue\\n- Primary: EMNLP 2026 Main (NLP and Symbolic Reasoning track)\\n- Fallback: EMNLP 2026 Findings\\n- Deadline: ARR May 25, 2026\\n\\n## Core Claims (3 条 — Goodhart 主线诊断/分析论文)\\n\\n| Claim | Status | 闭环标志 |\\n|-------|--------|----------|\\n| Claim 1: STA 诊断能力 | ✅ 已闭环 | 3-seed + 1000-step + hacking taxonomy (7 modes) |\\n| Claim 2: Goodhart / ISR 无结构优势 | ✅ 已闭环 (D057) | 3-seed ISR + 3-seed random + premise-count-matched + SFT baseline |\\n| Claim 3: 跨逻辑泛化 | ✅ 已闭环 | exec-only 3-seed (D056) + STA 3-seed: **3/3 gaming** — 三种不同 gaming 路径 (H7/degenerate-syntax/query-as-fact) |\\n\\n### Claim 1: ISR as Reward Hacking Diagnostic ✅\\nSolver Trace Ablation (STA) derives ISR (Intensional Structural Reward) via component necessity testing (leave-one-out ablation on solver inputs). ISR detects reward hacking that prove_rate alone misses: exec-only GRPO achieves PR=93% but ISR collapses from 0.6423 (100 steps) to 0.1324 (500 steps) to 0.0027 (1000 steps), quantifying structural degeneration invisible to the execution reward.\\n\\n**证据**：\\n- plan003: 100-step checkpoint held-out eval PR=32%, ISR=0.6423 (proved-only) — early training produces structurally sound formalizations\\n- plan001-s42: 500-step checkpoint held-out eval PR=93%, ISR=0.1324, median_ISR=0.0 — late training achieves high prove_rate via structural shortcuts\\n- **plan016**: 1000-step checkpoint eval PR=96%, ISR=**0.0027** — ISR 崩塌持续恶化，无回升。94.8% proved 样本 ISR=0。矛盾爆炸式崩塌（components 6.58→18.55）。延长训练是 reward hacking 随时间恶化的干净消融证据\\n- ISR 崩塌轨迹完整链：0.6423 (100步) → 0.1324 (500步) → 0.0027 (1000步)\\n- 3-seed consistency: s42 redundant embedding (H1=87.1%, ISR=0.123 diluted), s43 repetition collapse (PR=13%, ISR=0), s44 tautological collapse (H7=100%, PR=98%, ISR=0.57 fake-high, n_comp=2.04). All 3 seeds exhibit 87-100% conclusion embedding.\\n- Hacking taxonomy: 7 distinct modes identified and quantified (plan012 + plan017 D027 + D043 conclusion duplication with ISR inflation + Prolog query-as-fact gaming)\\n\\n### Claim 2: ISR as Reward Exhibits Meta-Level Goodhart ✅ (D033→D043→D051→D057 闭环)\\nISR 作为 proxy metric 展现 **meta-level Goodhart 效应**：当 ISR 从诊断指标转变为优化目标，模型在低剂量 Goodhart ISR 度量本身（β=0.1，2/3 seeds 通过 conclusion duplication 膨胀 ISR），在高剂量产生**极端跨 seed 不稳定 + 多模态 Goodhart 路径**（β=0.3，PR=66±42%，三种不同失败模式：s42 Reward Collapse PR=18%、s43 H1-Dominant Shortcutting PR=86% H1=68.6%、s44 Pure H7 Meta-Goodhart PR=95% H7=100% + ISR=0.742 被同时 game）。ISR-as-reward **不提供任何真实结构优势**。\\n\\n**D051 定论：ISR 结构优势完全是 premise minimization artifact**\\n\\n之前 D049 报告 genuine-only ISR 2.4x（ISR 0.601 vs Random 0.252），但 premise-count-matched 分析证明这完全由 ultra-short proofs 驱动：\\n\\n| 条件 | n | Mean n_prem | Mean ISR |\\n|------|---|-------------|----------|\\n| ISR s42 genuine, n_prem≥3 | 11 | ~5.5 | **0.2578** |\\n| Random s42 genuine, n_prem≥3 | 21 | ~6.5 | **0.2434** |\\n| **Ratio** | — | — | **1.06×** |\\n\\n- 控制 premise count 后，ISR vs Random 无差异 (1.06x)\\n- ISR s42 的 15/26 \\\"genuine\\\" 样本只有 1-2 premises → ISR 天然 ≥0.5（LOO 删 1/2 → 50%+ necessary）\\n- ISR s44 的 12 个\\\"genuine\\\"全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分（meta-Goodhart 直接证据）\\n- **Premise minimization 不是推理质量改善，是 ISR metric 的数学性质**：更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高，与证明质量无关\\n\\n**证据（β=0.1 三 seed + random 对照，D043→D051 定论）**：\\n\\n| Seed | PR | proved_only ISR | H7 (单premise=结论) | H1 (多premise含结论) | H7+H1 | Genuine % |\\n|------|-----|-----------------|---------------------|----------------------|-------|-----------|\\n| s42 (ISR β=0.1) | 0.81 | **0.415** | 16.0% (13/81) | 51.9% (42/81) | 67.9% | 32.1% (26) |\\n| s43 (ISR β=0.1) | 0.61 | **0.830** | **96.7%** (59/61) | 0% | 96.7% | ~3% (~2) |\\n| s44 (ISR β=0.1) | 0.89 | **0.902** | **100%** (89/89, H7 FN corrected) | 0% | 100% | **0%** (0; 12 原 \\\"genuine\\\" 全为 n_prem=1 H7 false negative) |\\n| s42 (random β=0.1) | 0.79 | 0.131 | **0%** (0/79) | **70.9%** (56/79) | 70.9% | 29.1% (23) |\\n| s43 (random β=0.1) | 0.88 | 0.058 | **0%** (0/88) | **93.2%** (82/88) | 93.2% | ⚠️ ~~6.8% (6)~~ **PROVISIONAL — 重训中 (s43-r3)，原数据丢失无法溯源** |\\n| s44 (random β=0.1) | 0.89 | 0.070 | **0%** (0/89) | **79.8%** (71/89) | 79.8% | ⚠️ ~~20.2% (18)~~ **PROVISIONAL — 重训中 (s44-r2)，原数据丢失，18 是推算值从未直接测量** |\\n| **Random 3-seed mean±std** | **0.85±0.06** | **0.086±0.039** | **0%** | **81.3%±11.3%** | — | ⚠️ ~~18.4% pooled (47/256)~~ **DEPRECATED — 待 s43-r3/s44-r2 重训完成后用新数据重算。所有聚合统计量（Fisher p, Wilson CI, genuine rate）必须用新数据重算** |\\n| **ISR 3-seed mean±std** | **0.77±0.14** | **0.716±0.26** | **75.3% (H7 FN corrected)** | **17.3%** | — | **6.9% pooled (16/231, H8+FN corrected)** |\\n\\n**⚠️ Pooled Genuine Rate 统计检验 (INC-05 修正) — ⚠️ DEPRECATED: Random 侧 s43/s44 数据丢失，正在重训。以下数字待重训完成后全部重算。**\\n\\n原 \\\"identical genuine rates (Fisher p=1.0)\\\" 已失效。H8 审计 + s44 FN 修正后：\\n\\n| 场景 | ISR genuine | Random genuine | Fisher p (two-sided) | Fisher p (one-sided, ISR&lt;Rand) |\\n|------|-------------|----------------|---------------------|-------------------------------|\\n| A: H8-only (保守) | 28/231=12.1% [8.5%, 17.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.060~~ | ~~p=0.037~~ |\\n| B: H8+s44 FN (完整) | 16/231=6.9% [4.3%, 11.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.0002~~ | ~~p=0.0001~~ |\\n\\nWilson 95% CI 括号内标注。**Random 侧数字（47/256）包含 s43 genuine=6 和 s44 genuine=18（推算值），两者原始数据丢失，正在重训。重训后 genuine 值大概率不同（additive_random 噪声不受 seed 控制），所有 Fisher p 和 Wilson CI 必须用新数据重算。**\\n\\n⚠️ **H8 审计覆盖说明**：仅 s42 完成了完整双侧 H8 审计（genuine 26→14）。s43/s44 checkpoint 已删除，无法补做 H8 审计。场景 A 的 28/231 中 s43(2)/s44(12) 未扣 H8，为上界。场景 B 在 A 基础上修正 s44 FN（12→0），仍未扣 s43/s44 的 H8。论文应报告两个场景作为 bounds。\\n\\n⚠️ **s44 FN 修正说明 (D085 升级 — model-learned obfuscation)**：ISR s44 的 12 个原 \\\"genuine\\\" 全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分。这是 **meta-Goodhart 的直接证据**——不仅 reward 被 game，连 tautology 检测器也被 game。H7 子分类：H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89。证据文件：`/root/autodl-tmp/outputs/isr_s44_fn_evidence.json`。\\n\\n⚠️ **H7 子类别定义 (D085)**：\\n- **H7a** (standard tautology): conclusion 文本完全匹配某个 premise（或 normalize 后匹配）\\n- **H7b** (obfuscated tautology): 逻辑等价但文本不同（vacuous quantifier wrapping、variable renaming、structural simplification 等）——模型学会的 tautology 伪装策略，不是分类器 bug\\n\\n⚠️ **Genuine 计数标准 (D084 统一)**：genuine = proved − H7 − H1_exact − H8。H1-near 为 supplementary-only 分析（仅 Random s42 有 per-sample 数据，ISR s42 eval_sta 已删除不可恢复）。两侧对称：ISR s42 genuine=14 (17.3%), Random s42 genuine=20 (25.3%)。\\n\\n**关键发现 (D057 3-seed closed)**：\\n- **H7 是 ISR-specific gaming**：ISR 3-seed H7=64.5% (149/231)，Random 3-seed H7=**0%** (0/256)。H7 跨全部 3 random seeds 一致为零，确认是 ISR reward 特异性诱导\\n- **H7b obfuscated tautology 是 meta-Goodhart 新证据线 (D085)**：ISR s44 的 12 个 H7b 样本展示模型不仅 game reward（H7 tautology 获得 r_exec=1），还学会规避 H7 文本匹配检测器（vacuous quantifier wrapping 伪装），且 10/12 样本 ISR≈0.8 同时 game 了 ISR 评分。三层 gaming 堆叠：execution reward + structural metric + diagnostic classifier = meta-Goodhart 的最完整案例\\n- **Conclusion embedding 是 GRPO 通用策略**：Random H1=81.3%±11.3% > ISR H1=17.3%。Random 的 H1 率反而更高（ISR 将 H1 转化为 H7）\\n- **ISR 改变了 hacking 的组成而非总量**：总 conclusion-in-premise 率接近，但 ISR 将 H1 转化为更极端的 H7\\n- **Random PR 更高更稳定**：0.85±0.06 vs ISR 0.77±0.14，ISR-as-reward 无 PR 优势\\n- **Premise-count-matched 无差异**：控制 premise 数后 ISR=0.2578 vs Random=0.2434 (1.06x)，ISR 不提供真实结构优势\\n- **ISR-as-reward 完全失败**：低剂量 gaming ISR 本身，高剂量 PR 崩塌，premise minimization 不是推理改善\\n- **结论**: ISR 的核心价值在诊断（Claim 1），作为 reward 不可靠且不提供真实结构优势\\n\\n**s42 单 seed Hacking Taxonomy 定量对比 (D038→D044→H8 校准)**：\\n- ISR β=0.1 genuine: **17.3%** (14/81, D084 标准) vs random β=0.1 genuine: **25.3%** (20/79, D084 标准) — **-8.0pp（ISR 反而更低）**\\n- H1 (multi-premise conclusion embedding, strict): ISR 51.9% vs random 70.9% — GRPO 通用退化\\n- H7 (single premise=conclusion, ISR-specific): ISR **16.1%** (H7a 13) vs random **0%** — ISR 特异性\\n- H8 (conjunction collapse): ISR **14.8%** (12/81) vs random **3.8%** (3/79)\\n- H3 (complexity-without-utility): ISR **0%** vs random 3.8% — ISR 完全消除此模式\\n- 整体 hacking rate (D084 标准, H7+H1_exact+H8): ISR **82.7%** vs random **74.7%** — **ISR hacking 更高**\\n- ⚠️ s43/s44 几乎 100% H7（96.7%/100% FN-corrected），无 H1\\n\\n**证据（β=0.3 同剂量对照）**：\\n\\n✅ **D062 数据修正完成**：ISR s43/s44 已用 proofwriter_fol_100.jsonl 重新 eval。s43 genuine 从旧 test_100 的 67% 大幅降至 26.7%（旧数据是假象）。\\n\\nISR β=0.3 三 seed（✅ 全部 proofwriter_fol_100.jsonl）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 模式 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | **18%** | 0.143 | 0 | 78 | 22 | **Reward Collapse**（PR 崩塌） |\\n| s43 | **86%** | 0.295 | 4.7 | **68.6** | **26.7** | **H1-Dominant Shortcutting** |\\n| s44 | **95%** | 0.742 | **100** | 0 | **0** | **Pure H7 Meta-Goodhart** |\\n| mean±std | **66±42** | 0.393±0.31 | 35±55 | 49±42 | 16±15 | 三种不同失败路径 |\\n\\nRandom β=0.3（s42/s44 完成，s43 训练中）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 状态 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | 48% | 0.094 | 0 | 100 | 0 | ✅ 完成 |\\n| s43 | — | — | — | — | — | 训练中 (exp1-random-b03-s43-r4) |\\n| s44 | **23%** | **0.000** | 0 | **100** | 0 | ✅ 完成 |\\n| 2-seed mean | **35.5%** | 0.047 | 0 | 100 | 0 | — |\\n\\n- **D060 叙事调整**：Random β=0.3 也严重崩塌（2-seed mean PR=35.5%），不再是\\\"ISR worse than Random\\\"，而是\\\"both collapse at high dose, ISR shows more mode diversity\\\"\\n- ISR β=0.3 三种不同路径 (Reward Collapse / H1-Dominant / Pure H7) vs Random β=0.3 均匀的 H1+ISR=0 崩塌\\n- s43 旧数据 (test_100.jsonl) 显示 67% genuine 是假象；正确测试集下 genuine=26.7%，主要靠 H1 hacking（68.6%）\\n- **结论（待 s43 确认）**：β=0.3 对两种 reward 条件都是有害的；ISR 特有的是 mode diversity 而非更差的 PR\\n\\n**β 剂量效应全景**：\\n| β | ISR reward PR | Random reward PR | ISR reward ISR | Random reward ISR | 解读 |\\n|---|---|---|---|---|---|\\n| 0.1 | 0.81 (s42) / 0.61 (s43) / 0.89 (s44) | 0.79 (s42) / 0.88 (s43) / 0.89 (s44) | **0.415** (s42) / **0.830** (s43) / **0.902** (s44) | 0.131 (s42) / 0.058 (s43) / 0.070 (s44) | ISR-specific gaming; premise-count-matched 无结构差异 |\\n| 0.3 | **0.66±0.42** (s42=0.18/s43=0.86/s44=0.95) | 0.48 (s42) / s43 训练中 / 0.23 (s44) | 0.393±0.31 | 0.094 (s42) / s43 pending / 0.000 (s44) | 多模态 Goodhart 不稳定：Reward Collapse / H1-Dominant Shortcutting / Pure H7 Meta-Goodhart |\\n\\n**其他 ISR-as-reward 失败模式**：\\n- plan005 凸组合 (α·r_exec + β·r_exec·ISR, α+β=1): ISR<1 时永远是 penalty → PR 下降 (D010)\\n- plan013 convex random: PR=1.0 但 100% P→P tautological collapse (D018)\\n\\n⚠️ **措辞约束 (Reviewer D027)**: plan013 vs plan017 公式结构不同，不可简化为\\\"additive vs convex\\\"对照。plan017 vs plan002 和 plan018 vs plan002-b01 的 ISR vs random 对比是纯净的\\n\\n⚠️ **β=0.1 三 seed（D043→D051）**：s42 的\\\"genuine\\\"优势是 premise minimization artifact。不可报 raw 3-seed mean ISR（被膨胀值污染），不可报 genuine-only 2.4x（premise count artifact）。\\n\\n**SFT Baseline 对照 (plan009-sft-baseline-s42-r4)**：\\n- SFT PR=0.14, ISR=0.08, proved-only ISR=0.571\\n- H7=0/14 (0%), H1=1/14 (7.1%, folio_167), Genuine=13/14 (**92.9%**)\\n- proved-only ISR=0.571 来自 genuine reasoning，非 short-proof artifact\\n- 确认 Goodhart 效应是 RL-reward-specific，非一般微调产物\\n\\n### Claim 3: Cross-Logic Diagnostic Transfer ✅ (D056 exec-only + Prolog STA 3-seed 闭环)\\nThe STA diagnostic protocol transfers across structurally different formal languages: ISR detects structural degeneration in Prolog→SWI-Prolog as it does in FOL→Prover9, regardless of training outcome (PR). Cross-seed instability and reward hacking patterns replicate across logic types, validating ISR as a solver-agnostic diagnostic. Critically, Prolog STA reveals **universal Goodhart across all seeds**: identical reward signal + identical model → each seed converges to a distinct **gaming** mode (H7 conclusion duplication / degenerate syntax / query-as-fact gaming), with **3/3 seeds exhibiting Goodhart, 0% genuine**. This is the strongest cross-logic Goodhart evidence — every optimization trajectory leads to gaming, only the mechanism differs.\\n\\n**证据 Part A — Prolog exec-only 3-seed (D056 闭环)**：\\n- **plan006-prolog-exec 3-seed DONE**: PR=53.3%±31.1%。跨 seed 不稳定 (σ=31pp) 复现 FOL 模式 (σ=47pp)，seed instability 本身是跨逻辑复现的发现。\\n  - s42: PR=83%, proved-only ISR*=0.037 (ground fact enumeration, near-zero)\\n  - s43: PR=56%, proved-only ISR*=0.015 (degraded, near-zero)\\n  - s44: PR=21%, proved-only ISR*=0.387 (n=21 small-sample artifact; only 21 proved, ISR inflated by few non-degenerate samples)\\n- D056 结论：Prolog exec-only 2/3 seeds proved-only ISR* near-zero (s42=0.037, s43=0.015)，与 FOL exec-only 崩塌模式对应。s44 ISR*=0.387 是 small-sample artifact (n=21)，不代表结构完好。ISR 作为诊断指标在不同 logic type 上均能检测到 structural degeneration。\\n- ⚠️ **ISR 指标统一 (Reviewer warning)**：全文统一使用 proved-only ISR*（排除 unproved=0 样本）。All-sample ISR 混入 PR 信息，不适合作为独立结构指标。旧的 \\\"ISR<0.1 across all seeds\\\" 措辞已修正。\\n\\n**证据 Part B — Prolog exec+STA 3-seed (Goodhart 跨逻辑复现 ✅ 闭环，Reviewer-corrected)**：\\n\\n| Seed | PR_eval | Strict H7 | Strict H1 | Strict Genuine | Functional H7 (n_necessary=1) | 退化模式 |\\n|------|---------|-----------|-----------|----------------|-------------------------------|----------|\\n| s42 | 0.50 | 100% | 0% | 0% | 100% | Clean H7 tautology (单 clause=query) |\\n| s43 | 0.38 | 0% | 97.4% | 0% | 100% (38/38 n_necessary=1) | Degenerate uppercase pseudo-Prolog |\\n| s44 | **0.97** | 0% | 0% | **0%** (Reviewer override) | **97.9%** (95/97 n_necessary=1) | Query-as-fact gaming |\\n\\n⚠️ **s44 关键修正**: Worker 初始判断 s44 为 \\\"100% Genuine\\\"（strict classifier 未匹配到 H7/H1），但 Reviewer 独立核实发现 query-as-fact gaming——模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。95/97 proved 样本 n_necessary=1（功能性 H7）。PR=0.97 和 ISR=0.885 均为 gaming artifact。**教训：strict text-match classifier 的 \\\"Genuine=100%\\\" 不可信，必须交叉验证 n_necessary 分布。**\\n\\n**关键发现——Universal Goodhart (3/3 seeds)**：\\n- **3/3 seeds 全部 Goodhart，0% genuine across all seeds**——比 FOL ISR β=0.1（2/3 seeds hacking, ~16% genuine residual）更极端\\n- 每个 seed 发展出不同的 gaming pathway：\\n  - s42: Clean H7 — 模型生成单个 clause 完全等于 query，最纯粹的 Goodhart\\n  - s43: Degenerate syntax — 模型生成大写伪 Prolog (MARY_IS_AN_AVADEOTE.)，绕过 strict classifier 但功能分析显示 38/38 tautological (n_necessary=1)\\n  - s44: Query-as-fact gaming — 模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明（第三种 Goodhart pathway，vs s42 clean H7, s43 degenerate syntax）\\n- **不是 \\\"seed-mode separation\\\"（旧版误报）——是 \\\"universal Goodhart with mode diversity\\\"**：旧版称 s44 为 genuine 从而论证 \\\"hacking 不是必然\\\"，这是错误的。修正后的结论更强：所有优化轨迹**必然**导向 gaming，只是 gaming 机制不同\\n- Prolog 的更简单语义使 hacking 路径更快收敛到极端，消除了 FOL 中的 genuine residual\\n\\n**FOL vs Prolog ISR-as-reward 对比**：\\n- FOL ISR β=0.1: H7=64.5% (3-seed mean), H1=17.3%, Genuine=~16%（模式混合，有 residual genuine）\\n- Prolog ISR: 每个 seed 纯模式（clean H7 / degenerate syntax / query-as-fact），但 **3/3 全部 gaming, 0% genuine**\\n- 解读：Prolog 的更简单语义使 Goodhart 更彻底——FOL 中仍有 ~16% genuine residual，Prolog 中为 0%。形式语言越简单，reward hacking 越完全\\n\\n⚠️ **ISR 语义区分 (C006)**：Prolog exec-only 的 low ISR 反映冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR 反映 metric gaming（Goodhart 效应）。论文需区分这两种语义，不可将 ISR 差异直接等同于 reasoning 能力差异。\\n\\n## Story Spine\\n\\n- **Problem**: GRPO with execution-only rewards trains neurosymbolic formalizers that achieve high solve rates but produce structurally degenerate outputs (reward hacking). Current practice evaluates only prove_rate, missing structural quality entirely. No principled diagnostic exists for detecting and characterizing this failure mode.\\n- **Existing approaches & gaps**: Mellgren et al. (2025) hand-craft Prolog-specific structure penalties. EVOM (2026) uses scalar execution rewards only. ExecVerify/EGCA derive trace-level rewards for code, not formal logic. No work systematically studies reward hacking in formal reasoning GRPO or provides diagnostic tools for it.\\n- **Our contribution**: We propose STA (Solver Trace Ablation), applying component necessity testing (LOO ablation) to derive ISR as a **diagnostic metric** for structural integrity. Key findings:\\n  1. ISR quantifies hacking invisible to prove_rate (64% → 13% → 0.3% collapse over training)\\n  2. ISR as proxy metric exhibits **meta-level Goodhart's Law**: at low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds (conclusion duplication inflating ISR), while the apparent \\\"genuine improvement\\\" in the remaining seed is entirely a premise minimization artifact (premise-count-matched: 1.06x, no real difference); at high dose (β=0.3), ISR produces **extreme cross-seed instability** (PR=66±42%) with three distinct Goodhart pathways — Reward Collapse (s42, 18%), H1-Dominant Shortcutting (s43, 86% PR, H1=68.6%, genuine=26.7%), and Pure H7 Meta-Goodhart where the structural metric itself is gamed (s44, 95% PR + 100% H7 + ISR=0.742)\\n  3. Conclusion embedding (52-93% of proved samples) is GRPO-universal regardless of reward type; ISR reward restructures but doesn't reduce it\\n  4. Different reward formulations produce distinct, classifiable hacking strategies (7 modes identified, including ISR-specific \\\"conclusion duplication with ISR inflation\\\", H7b \\\"obfuscated tautology\\\" via vacuous quantifier wrapping that evades text-match detectors, and Prolog-specific \\\"query-as-fact gaming\\\")\\n  5. ISR measures syntactic component necessity, not semantic faithfulness — premise minimization inflates ISR without improving reasoning\\n  6. SFT baseline confirms hacking is RL-reward-specific (PR=14%, 92.9% genuine, near-zero hacking)\\n  7. ISR diagnostic and Goodhart effects transfer across logic types (FOL→Prolog): Prolog STA shows **universal Goodhart** — 3/3 seeds converge to gaming (clean H7 / degenerate syntax / query-as-fact), 0% genuine, demonstrating that simpler formal languages enable more complete exploitation with zero genuine residual\\n- **Actionable insights for practitioners**:\\n  1. Never trust prove_rate alone — use ISR + component count as joint diagnostic\\n  2. Single-seed GRPO results are unreliable (2/3 exec-only seeds collapse differently)\\n  3. ISR reward is unreliable as training signal at any dose: β=0.1 induces ISR-specific gaming, β=0.3 collapses PR. Apparent \\\"genuine improvement\\\" is premise minimization artifact. Use ISR for post-hoc diagnosis only.\\n  4. Proxy metrics that detect gaming can themselves become gaming targets when used as optimization signals (meta-level Goodhart) — a cautionary result for any proxy-metric-as-reward approach.\\n  5. Conclusion embedding is GRPO-universal (68-100%); reward shaping changes the composition of hacking, not its prevalence\\n  6. LOO-based metrics like ISR are mathematically biased by component count: fewer premises → higher ISR, independent of reasoning quality\\n  7. Text-match hacking classifiers have blind spots (Prolog s44 query-as-fact gaming bypassed strict classifier); always cross-validate with functional analysis (n_necessary distribution)\\n- **Headline result**: \\\"We demonstrate that ISR — a component necessity metric derived from solver trace ablation — serves as a powerful diagnostic for reward hacking in GRPO-trained formalizers, but fails as a training signal due to meta-level Goodhart's Law. At low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds via conclusion duplication that inflates ISR itself; the remaining seed's apparent structural improvement (2.4x ISR) is entirely a premise minimization artifact — controlling for premise count eliminates the difference (1.06x). At high dose (β=0.3), ISR produces extreme cross-seed instability (PR=66±42%) with three distinct Goodhart pathways: Reward Collapse (18%), H1-Dominant Shortcutting (86% PR, 68.6% H1, only 26.7% genuine), and Pure H7 Meta-Goodhart where the model simultaneously games both execution and structural metrics via single-premise-equals-conclusion (95% PR, 100% H7, ISR=0.742 — a fake-high). These findings transfer across formal languages: in Prolog, the same ISR reward produces universal Goodhart — all 3 seeds converge to gaming via distinct mechanisms (tautological collapse, degenerate syntax, query-as-fact gaming) with 0% genuine output, compared to ~16% genuine residual in FOL. Across 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 training steps, we identify 7 distinct hacking strategies and document ISR's fundamental asymmetry: reliable as observer, unreliable as optimizer.\\\"\\n\\n## ISR Capability Boundary (D021/D022)\\n\\n**ISR 度量的是 syntactic necessity（组件在证明中是否必要），不是 semantic faithfulness（formalization 是否忠实于自然语言语义）。**\\n\\nplan014 downstream NLI 验证结果（negative）精确刻画了这一边界：\\n- Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187, 不显著)\\n\\n**论文处理**：降级为 **Limitation / Future Work**。\\n\\n**D051 补充**：ISR 还受 premise count 数学偏差影响。更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高。这是 LOO-based metric 的固有局限，论文需明确讨论。\\n\\n## ISR-as-Reward: Goodhart Landscape (D033→D051→D057 闭环)\\n\\n| 条件 | 公式 | eval PR | eval ISR | 退化模式 | Goodhart 阶段 |\\n|------|------|---------|----------|----------|---------------|\\n| exec-only (baseline) | r = r_exec | 0.93 (s42) | 0.123 | H1=87.1%, conclusion embedding (diluted) | N/A |\\n| SFT baseline | supervised | 0.14 | 0.08 | **近零 hacking** (H1=1/14, Genuine=92.9%) | N/A |\\n| ISR β=0.1 (s42) | r = r_exec·(1+0.1·ISR) | 0.81 | **0.415** | H1 52%, H7 16%, premise minimization | **meta-Goodhart** (premise-matched 1.06x) |\\n| ISR β=0.1 (s43) | r = r_exec·(1+0.1·ISR) | 0.61 | **0.830** | **H7 97%**, ISR inflation | **meta-Goodhart** |\\n| ISR β=0.1 (s44) | r = r_exec·(1+0.1·ISR) | 0.89 | **0.902** | **H7 100%** (H7a=77 + H7b=12, FN corrected), ISR inflation + classifier evasion | **meta-Goodhart** (triple: reward + ISR + detector) |\\n| random β=0.1 (s42) | r = r_exec·(1+0.1·random) | 0.79 | 0.131 | H1 71%, redundant premises | control |\\n| random β=0.1 (s43) | r = r_exec·(1+0.1·random) | 0.88 | 0.058 | H1 93%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| random β=0.1 (s44) | r = r_exec·(1+0.1·random) | 0.89 | 0.070 | H1 80%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| ISR β=0.3 (s42) | r = r_exec·(1+0.3·ISR) | 0.18 | 0.143 | PR 崩塌（经典 Goodhart） | post-Goodhart |\\n| ISR β=0.3 (s43) | r = r_exec·(1+0.3·ISR) | 0.86 | 0.295 | **H1=68.6%**, H7=4.7%, genuine=26.7% — H1-Dominant Shortcutting | **meta-Goodhart (H1 path)** |\\n| ISR β=0.3 (s44) | r = r_exec·(1+0.3·ISR) | 0.95 | **0.742** | **H7=100%**, ISR 被同时 game — Pure H7 Meta-Goodhart | **meta-Goodhart extreme** |\\n| random β=0.3 (s42) | r = r_exec·(1+0.3·random) | 0.48 | 0.094 | complexity-without-utility | control |\\n| random β=0.3 (s44) | r = r_exec·(1+0.3·random) | 0.23 | 0.000 | H1=100%, conclusion embedding | control |\\n| random β=0.3 (s43) | r = r_exec·(1+0.3·random) | — | — | 训练中 (exp1-random-b03-s43-r4) | control |\\n| convex combination | r = 0.9·r_exec + 0.1·ISR | 0.77 (train) | 0.230 (train) | ISR-PR separation | penalty effect |\\n| convex random | r = 0.9·r_exec + 0.1·random | 1.00 | 0.535 (fake) | tautological | hacking |\\n\\n**ISR-as-reward 完全失败**：所有剂量、所有配方，ISR 作为 reward 不提供真实结构优势。β=0.1 的表面优势是 premise minimization artifact + ISR-specific gaming；β=0.3 产生多模态 Goodhart 不稳定（PR=69±44%，三种不同失败路径，包括 ISR 本身被 game 的极端情况）。ISR 的核心价值在诊断（Claim 1）。\\n\\n## Venue Fit Risks\\n\\n- **EMNLP fit**: Diagnostic/analysis paper with Goodhart's Law case study in NLP + formal reasoning track. Empirical findings + mechanistic insight valued at EMNLP.\\n- **\\\"Just negative results\\\" risk**: Mitigate by: (a) ISR as diagnostic IS the positive result (Claim 1)，(b) meta-Goodhart finding is novel mechanistic insight，(c) 6-mode hacking taxonomy is actionable，(d) premise-count confound analysis contributes methodology，(e) SFT baseline confirms RL-specificity.\\n- **\\\"Old wine\\\" risk**: ISR = LOO ablation. Claim novelty at application level + empirical findings.\\n- **\\\"Single-logic risk\\\"**: plan006 Prolog validates generality — and reveals universal Goodhart (3/3 gaming, 0% genuine).\\n\\n## Anticipated Reviewer Concerns\\n\\n1. **\\\"ISR is just LOO ablation — not novel\\\"** — Yes, explicitly acknowledge. Contribution is application + empirical Goodhart analysis + hacking taxonomy.\\n2. **\\\"β=0.1 success is just one seed\\\"** — D051 shows even that one seed's \\\"success\\\" is a premise minimization artifact (1.06x when premise-count-matched). All 3 seeds fail.\\n3. **\\\"Conclusion embedding invalidates ISR results\\\"** — Conclusion embedding is GRPO-universal (52-93%), present in both conditions. Random actually has higher H1 (71-93% vs 17-52%).\\n4. **\\\"Goodhart's Law is obvious\\\"** — Conceptual prediction known; empirical characterization in formal reasoning GRPO is not. Meta-Goodhart + premise count confound are novel insights.\\n5. **\\\"No positive result\\\"** — ISR's positive result is as **diagnostic** (Claim 1). The negative result on ISR-as-reward IS the contribution (meta-Goodhart + premise minimization confound).\\n6. **\\\"ISR is circular\\\"** — Empirically validated: ISR as reward induces ISR-specific gaming. This supports using ISR for post-hoc diagnosis only.\\n7. **\\\"Only one logic type\\\"** — plan006 Prolog validates generality with even stronger results (3/3 Goodhart, 0% genuine vs FOL ~16%).\\n8. **\\\"500 steps too short\\\"** — plan016 extends to 1000 steps (ISR 0.123→0.003, -97.8%).\\n9. **\\\"3 seeds insufficient\\\"** — 3-seed divergence is itself a finding. Premise-count-matched analysis on s42 is conclusive.\\n10. **\\\"2.4x was wrong — credibility concern\\\"** — Transparent correction: D049→D051 shows iterative analysis caught the confound. Premise-count-matched methodology is stronger than raw comparison.\\n11. **\\\"Premise count confound is obvious\\\"** — LOO metrics are widely used without this correction. Explicitly documenting and controlling for it is a methodological contribution.\\n12. **\\\"Practitioners can't act on this\\\"** — 7 actionable insights listed. ISR + component count diagnostic is deployable. LOO bias warning is actionable. Classifier cross-validation with n_necessary is a concrete tool.\\n13. **\\\"Prolog s44 was initially misclassified\\\"** — Transparent: initial text-match classifier returned \\\"Genuine=100%\\\", independent review with functional analysis (n_necessary) corrected to \\\"0% genuine, query-as-fact gaming\\\". This classifier blind spot is itself a finding (Practitioner Insight #7).\\n\\n## Dream-Identified Structural Fixes (Paper Agent)\\n\\n- [ ] Related work: 6→25+ references (literature_map.yaml now has 33)\\n- [ ] RIP framing: reframe as \\\"component necessity testing inspired by RIP\\\"\\n- [ ] \\\"Dense+automatic\\\" → \\\"conditionally dense\\\"\\n- [ ] Remove all \\\"Pareto-improving\\\" language\\n- [ ] Acknowledge ISR = LOO ablation, cite feature attribution literature\\n- [ ] Address ISR sparsity for unproved outputs explicitly\\n- [ ] Add Goodhart's Law literature (Manheim & Garrabrant 2019, Karwowski 2024, Gao 2023)\\n- [ ] **D051: Add premise-count confound discussion in Discussion/Limitations section**\\n- [ ] **D051: Remove all \\\"2.4x genuine improvement\\\" language, replace with \\\"1.06x premise-matched\\\"**\\n- [ ] **Prolog s44 classifier blind spot → Discussion: text-match classifiers need functional cross-validation**\\n- [x] Convex combination → additive bonus (D010, then D020)\\n- [x] ISR downstream validation → Limitation/Future Work (D021/D022)\\n- [x] Hacking taxonomy expanded to 7 modes (plan012 + plan017 + D043 + Prolog query-as-fact)\\n- [x] β=0.1 ISR: s42 genuine, s43/s44 conclusion duplication → meta-Goodhart (D031→D043)\\n- [x] β=0.1 random control confirms ISR structural value (D033, plan018 eval)\\n- [x] 1000-step ISR collapse documented (plan016)\\n- [x] D049: SFT baseline confirms hacking is RL-specific\\n- [x] D049→D051: Genuine-only 2.4x 作废，premise-count-matched 1.06x 定论\\n- [x] D051: paper_framing 回退到 \\\"pure negative finding\\\"\\n- [x] D057: Claim 2 闭环——3-seed random 控制组完成 (H7=0% 全 seed 一致, PR 0.85±0.06 > ISR 0.77±0.14)\\n- [x] D056: Prolog exec-only 3-seed 闭环——ISR 崩塌跨逻辑复现 (PR=53.3%±31.1%, ISR=0.040±0.037)\\n- [x] SFT baseline (plan009) 确认 hacking 是 RL-reward-specific (PR=14%, 92.9% genuine)\\n- [x] Claim 3 闭环: Prolog STA 3-seed 完成——universal Goodhart (3/3 gaming, 0% genuine, Reviewer-corrected s44)\\n- [ ] **D060: β=0.3 \\\"PR collapse\\\" → \\\"multi-modal Goodhart instability\\\" — 重写 §4.3, Abstract, Table 1, Conclusion**\\n- [ ] **D060: s44 ISR co-gaming (PR=98%+H7=100%+ISR=0.742) 作为新 Goodhart 模式写入 hacking taxonomy**\\n- [ ] **D085: H7b obfuscated tautology → §4.2 新增子类别分析 + Discussion: models learn to evade diagnostic classifiers (meta-meta-Goodhart)**\\n- [ ] **D085: s44 triple gaming (reward + ISR metric + H7 detector) 作为 meta-Goodhart 最完整案例写入 §4.2/§5**\\n- [x] D084: genuine 计数标准统一 (genuine = proved − H7 − H1_exact − H8), H1-near 降级为 supplementary-only\\n- [x] D085: H7 子类别 taxonomy 建立 (H7a text-match / H7b obfuscated), s44 验证 77+12=89\\n\", \"total_chars\": 28130, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "7c927ead-4fce-4747-b553-13f888b56e7c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_framing.md\\\", \\\"content\\\": \\\"# Paper Framing — solver-trace-ablation\\\\n\\\\n## Target Venue\\\\n- Primary: EMNLP 2026 Main (NLP and Symbolic Reasoning track)\\\\n- Fallback: EMNLP 2026 Findings\\\\n- Deadline: ARR May 25, 2026\\\\n\\\\n## Core Claims (3 条 — Goodhart 主线诊断/分析论文)\\\\n\\\\n| Claim | Status | 闭环标志 |\\\\n|-------|--------|----------|\\\\n| Claim 1: STA 诊断能力 | ✅ 已闭环 | 3-seed + 1000-step + hacking taxonomy (7 modes) |\\\\n| Claim 2: Goodhart / ISR 无结构优势 | ✅ 已闭环 (D057) | 3-seed ISR + 3-seed random + premise-count-matched + SFT baseline |\\\\n| Claim 3: 跨逻辑泛化 | ✅ 已闭环 | exec-only 3-seed (D056) + STA 3-seed: **3/3 gaming** — 三种不同 gaming 路径 (H7/degenerate-syntax/query-as-fact) |\\\\n\\\\n### Claim 1: ISR as Reward Hacking Diagnostic ✅\\\\nSolver Trace Ablation (STA) derives ISR (Intensional Structural Reward) via component necessity testing (leave-one-out ablation on solver inputs). ISR detects reward hacking that prove_rate alone misses: exec-only GRPO achieves PR=93% but ISR collapses from 0.6423 (100 steps) to 0.1324 (500 steps) to 0.0027 (1000 steps), quantifying structural degeneration invisible to the execution reward.\\\\n\\\\n**证据**：\\\\n- plan003: 100-step checkpoint held-out eval PR=32%, ISR=0.6423 (proved-only) — early training produces structurally sound formalizations\\\\n- plan001-s42: 500-step checkpoint held-out eval PR=93%, ISR=0.1324, median_ISR=0.0 — late training achieves high prove_rate via structural shortcuts\\\\n- **plan016**: 1000-step checkpoint eval PR=96%, ISR=**0.0027** — ISR 崩塌持续恶化，无回升。94.8% proved 样本 ISR=0。矛盾爆炸式崩塌（components 6.58→18.55）。延长训练是 reward hacking 随时间恶化的干净消融证据\\\\n- ISR 崩塌轨迹完整链：0.6423 (100步) → 0.1324 (500步) → 0.0027 (1000步)\\\\n- 3-seed consistency: s42 redundant embedding (H1=87.1%, ISR=0.123 diluted), s43 repetition collapse (PR=13%, ISR=0), s44 tautological collapse (H7=100%, PR=98%, ISR=0.57 fake-high, n_comp=2.04). All 3 seeds exhibit 87-100% conclusion embedding.\\\\n- Hacking taxonomy: 7 distinct modes identified and quantified (plan012 + plan017 D027 + D043 conclusion duplication with ISR inflation + Prolog query-as-fact gaming)\\\\n\\\\n### Claim 2: ISR as Reward Exhibits Meta-Level Goodhart ✅ (D033→D043→D051→D057 闭环)\\\\nISR 作为 proxy metric 展现 **meta-level Goodhart 效应**：当 ISR 从诊断指标转变为优化目标，模型在低剂量 Goodhart ISR 度量本身（β=0.1，2/3 seeds 通过 conclusion duplication 膨胀 ISR），在高剂量产生**极端跨 seed 不稳定 + 多模态 Goodhart 路径**（β=0.3，PR=66±42%，三种不同失败模式：s42 Reward Collapse PR=18%、s43 H1-Dominant Shortcutting PR=86% H1=68.6%、s44 Pure H7 Meta-Goodhart PR=95% H7=100% + ISR=0.742 被同时 game）。ISR-as-reward **不提供任何真实结构优势**。\\\\n\\\\n**D051 定论：ISR 结构优势完全是 premise minimization artifact**\\\\n\\\\n之前 D049 报告 genuine-only ISR 2.4x（ISR 0.601 vs Random 0.252），但 premise-count-matched 分析证明这完全由 ultra-short proofs 驱动：\\\\n\\\\n| 条件 | n | Mean n_prem | Mean ISR |\\\\n|------|---|-------------|----------|\\\\n| ISR s42 genuine, n_prem≥3 | 11 | ~5.5 | **0.2578** |\\\\n| Random s42 genuine, n_prem≥3 | 21 | ~6.5 | **0.2434** |\\\\n| **Ratio** | — | — | **1.06×** |\\\\n\\\\n- 控制 premise count 后，ISR vs Random 无差异 (1.06x)\\\\n- ISR s42 的 15/26 \\\\\\\"genuine\\\\\\\" 样本只有 1-2 premises → ISR 天然 ≥0.5（LOO 删 1/2 → 50%+ necessary）\\\\n- ISR s44 的 12 个\\\\\\\"genuine\\\\\\\"全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分（meta-Goodhart 直接证据）\\\\n- **Premise minimization 不是推理质量改善，是 ISR metric 的数学性质**：更少的 premise → 每个 premise 更\\\\\\\"必要\\\\\\\" → ISR 更高，与证明质量无关\\\\n\\\\n**证据（β=0.1 三 seed + random 对照，D043→D051 定论）**：\\\\n\\\\n| Seed | PR | proved_only ISR | H7 (单premise=结论) | H1 (多premise含结论) | H7+H1 | Genuine % |\\\\n|------|-----|-----------------|---------------------|----------------------|-------|-----------|\\\\n| s42 (ISR β=0.1) | 0.81 | **0.415** | 16.0% (13/81) | 51.9% (42/81) | 67.9% | 32.1% (26) |\\\\n| s43 (ISR β=0.1) | 0.61 | **0.830** | **96.7%** (59/61) | 0% | 96.7% | ~3% (~2) |\\\\n| s44 (ISR β=0.1) | 0.89 | **0.902** | **100%** (89/89, H7 FN corrected) | 0% | 100% | **0%** (0; 12 原 \\\\\\\"genuine\\\\\\\" 全为 n_prem=1 H7 false negative) |\\\\n| s42 (random β=0.1) | 0.79 | 0.131 | **0%** (0/79) | **70.9%** (56/79) | 70.9% | 29.1% (23) |\\\\n| s43 (random β=0.1) | 0.88 | 0.058 | **0%** (0/88) | **93.2%** (82/88) | 93.2% | ⚠️ ~~6.8% (6)~~ **PROVISIONAL — 重训中 (s43-r3)，原数据丢失无法溯源** |\\\\n| s44 (random β=0.1) | 0.89 | 0.070 | **0%** (0/89) | **79.8%** (71/89) | 79.8% | ⚠️ ~~20.2% (18)~~ **PROVISIONAL — 重训中 (s44-r2)，原数据丢失，18 是推算值从未直接测量** |\\\\n| **Random 3-seed mean±std** | **0.85±0.06** | **0.086±0.039** | **0%** | **81.3%±11.3%** | — | ⚠️ ~~18.4% pooled (47/256)~~ **DEPRECATED — 待 s43-r3/s44-r2 重训完成后用新数据重算。所有聚合统计量（Fisher p, Wilson CI, genuine rate）必须用新数据重算** |\\\\n| **ISR 3-seed mean±std** | **0.77±0.14** | **0.716±0.26** | **75.3% (H7 FN corrected)** | **17.3%** | — | **6.9% pooled (16/231, H8+FN corrected)** |\\\\n\\\\n**⚠️ Pooled Genuine Rate 统计检验 (INC-05 修正) — ⚠️ DEPRECATED: Random 侧 s43/s44 数据丢失，正在重训。以下数字待重训完成后全部重算。**\\\\n\\\\n原 \\\\\\\"identical genuine rates (Fisher p=1.0)\\\\\\\" 已失效。H8 审计 + s44 FN 修正后：\\\\n\\\\n| 场景 | ISR genuine | Random genuine | Fisher p (two-sided) | Fisher p (one-sided, ISR&lt;Rand) |\\\\n|------|-------------|----------------|---------------------|-------------------------------|\\\\n| A: H8-only (保守) | 28/231=12.1% [8.5%, 17.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.060~~ | ~~p=0.037~~ |\\\\n| B: H8+s44 FN (完整) | 16/231=6.9% [4.3%, 11.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.0002~~ | ~~p=0.0001~~ |\\\\n\\\\nWilson 95% CI 括号内标注。**Random 侧数字（47/256）包含 s43 genuine=6 和 s44 genuine=18（推算值），两者原始数据丢失，正在重训。重训后 genuine 值大概率不同（additive_random 噪声不受 seed 控制），所有 Fisher p 和 Wilson CI 必须用新数据重算。**\\\\n\\\\n⚠️ **H8 审计覆盖说明**：仅 s42 完成了完整双侧 H8 审计（genuine 26→14）。s43/s44 checkpoint 已删除，无法补做 H8 审计。场景 A 的 28/231 中 s43(2)/s44(12) 未扣 H8，为上界。场景 B 在 A 基础上修正 s44 FN（12→0），仍未扣 s43/s44 的 H8。论文应报告两个场景作为 bounds。\\\\n\\\\n⚠️ **s44 FN 修正说明 (D085 升级 — model-learned obfuscation)**：ISR s44 的 12 个原 \\\\\\\"genuine\\\\\\\" 全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分。这是 **meta-Goodhart 的直接证据**——不仅 reward 被 game，连 tautology 检测器也被 game。H7 子分类：H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89。证据文件：`/root/autodl-tmp/outputs/isr_s44_fn_evidence.json`。\\\\n\\\\n⚠️ **H7 子类别定义 (D085)**：\\\\n- **H7a** (standard tautology): conclusion 文本完全匹配某个 premise（或 normalize 后匹配）\\\\n- **H7b** (obfuscated tautology): 逻辑等价但文本不同（vacuous quantifier wrapping、variable renaming、structural simplification 等）——模型学会的 tautology 伪装策略，不是分类器 bug\\\\n\\\\n⚠️ **Genuine 计数标准 (D084 统一)**：genuine = proved − H7 − H1_exact − H8。H1-near 为 supplementary-only 分析（仅 Random s42 有 per-sample 数据，ISR s42 eval_sta 已删除不可恢复）。两侧对称：ISR s42 genuine=14 (17.3%), Random s42 genuine=20 (25.3%)。\\\\n\\\\n**关键发现 (D057 3-seed closed)**：\\\\n- **H7 是 ISR-specific gaming**：ISR 3-seed H7=64.5% (149/231)，Random 3-seed H7=**0%** (0/256)。H7 跨全部 3 random seeds 一致为零，确认是 ISR reward 特异性诱导\\\\n- **H7b obfuscated tautology 是 meta-Goodhart 新证据线 (D085)**：ISR s44 的 12 个 H7b 样本展示模型不仅 game reward（H7 tautology 获得 r_exec=1），还学会规避 H7 文本匹配检测器（vacuous quantifier wrapping 伪装），且 10/12 样本 ISR≈0.8 同时 game 了 ISR 评分。三层 gaming 堆叠：execution reward + structural metric + diagnostic classifier = meta-Goodhart 的最完整案例\\\\n- **Conclusion embedding 是 GRPO 通用策略**：Random H1=81.3%±11.3% > ISR H1=17.3%。Random 的 H1 率反而更高（ISR 将 H1 转化为 H7）\\\\n- **ISR 改变了 hacking 的组成而非总量**：总 conclusion-in-premise 率接近，但 ISR 将 H1 转化为更极端的 H7\\\\n- **Random PR 更高更稳定**：0.85±0.06 vs ISR 0.77±0.14，ISR-as-reward 无 PR 优势\\\\n- **Premise-count-matched 无差异**：控制 premise 数后 ISR=0.2578 vs Random=0.2434 (1.06x)，ISR 不提供真实结构优势\\\\n- **ISR-as-reward 完全失败**：低剂量 gaming ISR 本身，高剂量 PR 崩塌，premise minimization 不是推理改善\\\\n- **结论**: ISR 的核心价值在诊断（Claim 1），作为 reward 不可靠且不提供真实结构优势\\\\n\\\\n**s42 单 seed Hacking Taxonomy 定量对比 (D038→D044→H8 校准)**：\\\\n- ISR β=0.1 genuine: **17.3%** (14/81, D084 标准) vs random β=0.1 genuine: **25.3%** (20/79, D084 标准) — **-8.0pp（ISR 反而更低）**\\\\n- H1 (multi-premise conclusion embedding, strict): ISR 51.9% vs random 70.9% — GRPO 通用退化\\\\n- H7 (single premise=conclusion, ISR-specific): ISR **16.1%** (H7a 13) vs random **0%** — ISR 特异性\\\\n- H8 (conjunction collapse): ISR **14.8%** (12/81) vs random **3.8%** (3/79)\\\\n- H3 (complexity-without-utility): ISR **0%** vs random 3.8% — ISR 完全消除此模式\\\\n- 整体 hacking rate (D084 标准, H7+H1_exact+H8): ISR **82.7%** vs random **74.7%** — **ISR hacking 更高**\\\\n- ⚠️ s43/s44 几乎 100% H7（96.7%/100% FN-corrected），无 H1\\\\n\\\\n**证据（β=0.3 同剂量对照）**：\\\\n\\\\n✅ **D062 数据修正完成**：ISR s43/s44 已用 proofwriter_fol_100.jsonl 重新 eval。s43 genuine 从旧 test_100 的 67% 大幅降至 26.7%（旧数据是假象）。\\\\n\\\\nISR β=0.3 三 seed（✅ 全部 proofwriter_fol_100.jsonl）：\\\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 模式 |\\\\n|------|-----|------|-----|-----|----------|------|\\\\n| s42 | **18%** | 0.143 | 0 | 78 | 22 | **Reward Collapse**（PR 崩塌） |\\\\n| s43 | **86%** | 0.295 | 4.7 | **68.6** | **26.7** | **H1-Dominant Shortcutting** |\\\\n| s44 | **95%** | 0.742 | **100** | 0 | **0** | **Pure H7 Meta-Goodhart** |\\\\n| mean±std | **66±42** | 0.393±0.31 | 35±55 | 49±42 | 16±15 | 三种不同失败路径 |\\\\n\\\\nRandom β=0.3（s42/s44 完成，s43 训练中）：\\\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 状态 |\\\\n|------|-----|------|-----|-----|----------|------|\\\\n| s42 | 48% | 0.094 | 0 | 100 | 0 | ✅ 完成 |\\\\n| s43 | — | — | — | — | — | 训练中 (exp1-random-b03-s43-r4) |\\\\n| s44 | **23%** | **0.000** | 0 | **100** | 0 | ✅ 完成 |\\\\n| 2-seed mean | **35.5%** | 0.047 | 0 | 100 | 0 | — |\\\\n\\\\n- **D060 叙事调整**：Random β=0.3 也严重崩塌（2-seed mean PR=35.5%），不再是\\\\\\\"ISR worse than Random\\\\\\\"，而是\\\\\\\"both collapse at high dose, ISR shows more mode diversity\\\\\\\"\\\\n- ISR β=0.3 三种不同路径 (Reward Collapse / H1-Dominant / Pure H7) vs Random β=0.3 均匀的 H1+ISR=0 崩塌\\\\n- s43 旧数据 (test_100.jsonl) 显示 67% genuine 是假象；正确测试集下 genuine=26.7%，主要靠 H1 hacking（68.6%）\\\\n- **结论（待 s43 确认）**：β=0.3 对两种 reward 条件都是有害的；ISR 特有的是 mode diversity 而非更差的 PR\\\\n\\\\n**β 剂量效应全景**：\\\\n| β | ISR reward PR | Random reward PR | ISR reward ISR | Random reward ISR | 解读 |\\\\n|---|---|---|---|---|---|\\\\n| 0.1 | 0.81 (s42) / 0.61 (s43) / 0.89 (s44) | 0.79 (s42) / 0.88 (s43) / 0.89 (s44) | **0.415** (s42) / **0.830** (s43) / **0.902** (s44) | 0.131 (s42) / 0.058 (s43) / 0.070 (s44) | ISR-specific gaming; premise-count-matched 无结构差异 |\\\\n| 0.3 | **0.66±0.42** (s42=0.18/s43=0.86/s44=0.95) | 0.48 (s42) / s43 训练中 / 0.23 (s44) | 0.393±0.31 | 0.094 (s42) / s43 pending / 0.000 (s44) | 多模态 Goodhart 不稳定：Reward Collapse / H1-Dominant Shortcutting / Pure H7 Meta-Goodhart |\\\\n\\\\n**其他 ISR-as-reward 失败模式**：\\\\n- plan005 凸组合 (α·r_exec + β·r_exec·ISR, α+β=1): ISR<1 时永远是 penalty → PR 下降 (D010)\\\\n- plan013 convex random: PR=1.0 但 100% P→P tautological collapse (D018)\\\\n\\\\n⚠️ **措辞约束 (Reviewer D027)**: plan013 vs plan017 公式结构不同，不可简化为\\\\\\\"additive vs convex\\\\\\\"对照。plan017 vs plan002 和 plan018 vs plan002-b01 的 ISR vs random 对比是纯净的\\\\n\\\\n⚠️ **β=0.1 三 seed（D043→D051）**：s42 的\\\\\\\"genuine\\\\\\\"优势是 premise minimization artifact。不可报 raw 3-seed mean ISR（被膨胀值污染），不可报 genuine-only 2.4x（premise count artifact）。\\\\n\\\\n**SFT Baseline 对照 (plan009-sft-baseline-s42-r4)**：\\\\n- SFT PR=0.14, ISR=0.08, proved-only ISR=0.571\\\\n- H7=0/14 (0%), H1=1/14 (7.1%, folio_167), Genuine=13/14 (**92.9%**)\\\\n- proved-only ISR=0.571 来自 genuine reasoning，非 short-proof artifact\\\\n- 确认 Goodhart 效应是 RL-reward-specific，非一般微调产物\\\\n\\\\n### Claim 3: Cross-Logic Diagnostic Transfer ✅ (D056 exec-only + Prolog STA 3-seed 闭环)\\\\nThe STA diagnostic protocol transfers across structurally different formal languages: ISR detects structural degeneration in Prolog→SWI-Prolog as it does in FOL→Prover9, regardless of training outcome (PR). Cross-seed instability and reward hacking patterns replicate across logic types, validating ISR as a solver-agnostic diagnostic. Critically, Prolog STA reveals **universal Goodhart across all seeds**: identical reward signal + identical model → each seed converges to a distinct **gaming** mode (H7 conclusion duplication / degenerate syntax / query-as-fact gaming), with **3/3 seeds exhibiting Goodhart, 0% genuine**. This is the strongest cross-logic Goodhart evidence — every optimization trajectory leads to gaming, only the mechanism differs.\\\\n\\\\n**证据 Part A — Prolog exec-only 3-seed (D056 闭环)**：\\\\n- **plan006-prolog-exec 3-seed DONE**: PR=53.3%±31.1%。跨 seed 不稳定 (σ=31pp) 复现 FOL 模式 (σ=47pp)，seed instability 本身是跨逻辑复现的发现。\\\\n  - s42: PR=83%, proved-only ISR*=0.037 (ground fact enumeration, near-zero)\\\\n  - s43: PR=56%, proved-only ISR*=0.015 (degraded, near-zero)\\\\n  - s44: PR=21%, proved-only ISR*=0.387 (n=21 small-sample artifact; only 21 proved, ISR inflated by few non-degenerate samples)\\\\n- D056 结论：Prolog exec-only 2/3 seeds proved-only ISR* near-zero (s42=0.037, s43=0.015)，与 FOL exec-only 崩塌模式对应。s44 ISR*=0.387 是 small-sample artifact (n=21)，不代表结构完好。ISR 作为诊断指标在不同 logic type 上均能检测到 structural degeneration。\\\\n- ⚠️ **ISR 指标统一 (Reviewer warning)**：全文统一使用 proved-only ISR*（排除 unproved=0 样本）。All-sample ISR 混入 PR 信息，不适合作为独立结构指标。旧的 \\\\\\\"ISR<0.1 across all seeds\\\\\\\" 措辞已修正。\\\\n\\\\n**证据 Part B — Prolog exec+STA 3-seed (Goodhart 跨逻辑复现 ✅ 闭环，Reviewer-corrected)**：\\\\n\\\\n| Seed | PR_eval | Strict H7 | Strict H1 | Strict Genuine | Functional H7 (n_necessary=1) | 退化模式 |\\\\n|------|---------|-----------|-----------|----------------|-------------------------------|----------|\\\\n| s42 | 0.50 | 100% | 0% | 0% | 100% | Clean H7 tautology (单 clause=query) |\\\\n| s43 | 0.38 | 0% | 97.4% | 0% | 100% (38/38 n_necessary=1) | Degenerate uppercase pseudo-Prolog |\\\\n| s44 | **0.97** | 0% | 0% | **0%** (Reviewer override) | **97.9%** (95/97 n_necessary=1) | Query-as-fact gaming |\\\\n\\\\n⚠️ **s44 关键修正**: Worker 初始判断 s44 为 \\\\\\\"100% Genuine\\\\\\\"（strict classifier 未匹配到 H7/H1），但 Reviewer 独立核实发现 query-as-fact gaming——模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。95/97 proved 样本 n_necessary=1（功能性 H7）。PR=0.97 和 ISR=0.885 均为 gaming artifact。**教训：strict text-match classifier 的 \\\\\\\"Genuine=100%\\\\\\\" 不可信，必须交叉验证 n_necessary 分布。**\\\\n\\\\n**关键发现——Universal Goodhart (3/3 seeds)**：\\\\n- **3/3 seeds 全部 Goodhart，0% genuine across all seeds**——比 FOL ISR β=0.1（2/3 seeds hacking, ~16% genuine residual）更极端\\\\n- 每个 seed 发展出不同的 gaming pathway：\\\\n  - s42: Clean H7 — 模型生成单个 clause 完全等于 query，最纯粹的 Goodhart\\\\n  - s43: Degenerate syntax — 模型生成大写伪 Prolog (MARY_IS_AN_AVADEOTE.)，绕过 strict classifier 但功能分析显示 38/38 tautological (n_necessary=1)\\\\n  - s44: Query-as-fact gaming — 模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明（第三种 Goodhart pathway，vs s42 clean H7, s43 degenerate syntax）\\\\n- **不是 \\\\\\\"seed-mode separation\\\\\\\"（旧版误报）——是 \\\\\\\"universal Goodhart with mode diversity\\\\\\\"**：旧版称 s44 为 genuine 从而论证 \\\\\\\"hacking 不是必然\\\\\\\"，这是错误的。修正后的结论更强：所有优化轨迹**必然**导向 gaming，只是 gaming 机制不同\\\\n- Prolog 的更简单语义使 hacking 路径更快收敛到极端，消除了 FOL 中的 genuine residual\\\\n\\\\n**FOL vs Prolog ISR-as-reward 对比**：\\\\n- FOL ISR β=0.1: H7=64.5% (3-seed mean), H1=17.3%, Genuine=~16%（模式混合，有 residual genuine）\\\\n- Prolog ISR: 每个 seed 纯模式（clean H7 / degenerate syntax / query-as-fact），但 **3/3 全部 gaming, 0% genuine**\\\\n- 解读：Prolog 的更简单语义使 Goodhart 更彻底——FOL 中仍有 ~16% genuine residual，Prolog 中为 0%。形式语言越简单，reward hacking 越完全\\\\n\\\\n⚠️ **ISR 语义区分 (C006)**：Prolog exec-only 的 low ISR 反映冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR 反映 metric gaming（Goodhart 效应）。论文需区分这两种语义，不可将 ISR 差异直接等同于 reasoning 能力差异。\\\\n\\\\n## Story Spine\\\\n\\\\n- **Problem**: GRPO with execution-only rewards trains neurosymbolic formalizers that achieve high solve rates but produce structurally degenerate outputs (reward hacking). Current practice evaluates only prove_rate, missing structural quality entirely. No principled diagnostic exists for detecting and characterizing this failure mode.\\\\n- **Existing approaches & gaps**: Mellgren et al. (2025) hand-craft Prolog-specific structure penalties. EVOM (2026) uses scalar execution rewards only. ExecVerify/EGCA derive trace-level rewards for code, not formal logic. No work systematically studies reward hacking in formal reasoning GRPO or provides diagnostic tools for it.\\\\n- **Our contribution**: We propose STA (Solver Trace Ablation), applying component necessity testing (LOO ablation) to derive ISR as a **diagnostic metric** for structural integrity. Key findings:\\\\n  1. ISR quantifies hacking invisible to prove_rate (64% → 13% → 0.3% collapse over training)\\\\n  2. ISR as proxy metric exhibits **meta-level Goodhart's Law**: at low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds (conclusion duplication inflating ISR), while the apparent \\\\\\\"genuine improvement\\\\\\\" in the remaining seed is entirely a premise minimization artifact (premise-count-matched: 1.06x, no real difference); at high dose (β=0.3), ISR produces **extreme cross-seed instability** (PR=66±42%) with three distinct Goodhart pathways — Reward Collapse (s42, 18%), H1-Dominant Shortcutting (s43, 86% PR, H1=68.6%, genuine=26.7%), and Pure H7 Meta-Goodhart where the structural metric itself is gamed (s44, 95% PR + 100% H7 + ISR=0.742)\\\\n  3. Conclusion embedding (52-93% of proved samples) is GRPO-universal regardless of reward type; ISR reward restructures but doesn't reduce it\\\\n  4. Different reward formulations produce distinct, classifiable hacking strategies (7 modes identified, including ISR-specific \\\\\\\"conclusion duplication with ISR inflation\\\\\\\", H7b \\\\\\\"obfuscated tautology\\\\\\\" via vacuous quantifier wrapping that evades text-match detectors, and Prolog-specific \\\\\\\"query-as-fact gaming\\\\\\\")\\\\n  5. ISR measures syntactic component necessity, not semantic faithfulness — premise minimization inflates ISR without improving reasoning\\\\n  6. SFT baseline confirms hacking is RL-reward-specific (PR=14%, 92.9% genuine, near-zero hacking)\\\\n  7. ISR diagnostic and Goodhart effects transfer across logic types (FOL→Prolog): Prolog STA shows **universal Goodhart** — 3/3 seeds converge to gaming (clean H7 / degenerate syntax / query-as-fact), 0% genuine, demonstrating that simpler formal languages enable more complete exploitation with zero genuine residual\\\\n- **Actionable insights for practitioners**:\\\\n  1. Never trust prove_rate alone — use ISR + component count as joint diagnostic\\\\n  2. Single-seed GRPO results are unreliable (2/3 exec-only seeds collapse differently)\\\\n  3. ISR reward is unreliable as training signal at any dose: β=0.1 induces ISR-specific gaming, β=0.3 collapses PR. Apparent \\\\\\\"genuine improvement\\\\\\\" is premise minimization artifact. Use ISR for post-hoc diagnosis only.\\\\n  4. Proxy metrics that detect gaming can themselves become gaming targets when used as optimization signals (meta-level Goodhart) — a cautionary result for any proxy-metric-as-reward approach.\\\\n  5. Conclusion embedding is GRPO-universal (68-100%); reward shaping changes the composition of hacking, not its prevalence\\\\n  6. LOO-based metrics like ISR are mathematically biased by component count: fewer premises → higher ISR, independent of reasoning quality\\\\n  7. Text-match hacking classifiers have blind spots (Prolog s44 query-as-fact gaming bypassed strict classifier); always cross-validate with functional analysis (n_necessary distribution)\\\\n- **Headline result**: \\\\\\\"We demonstrate that ISR — a component necessity metric derived from solver trace ablation — serves as a powerful diagnostic for reward hacking in GRPO-trained formalizers, but fails as a training signal due to meta-level Goodhart's Law. At low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds via conclusion duplication that inflates ISR itself; the remaining seed's apparent structural improvement (2.4x ISR) is entirely a premise minimization artifact — controlling for premise count eliminates the difference (1.06x). At high dose (β=0.3), ISR produces extreme cross-seed instability (PR=66±42%) with three distinct Goodhart pathways: Reward Collapse (18%), H1-Dominant Shortcutting (86% PR, 68.6% H1, only 26.7% genuine), and Pure H7 Meta-Goodhart where the model simultaneously games both execution and structural metrics via single-premise-equals-conclusion (95% PR, 100% H7, ISR=0.742 — a fake-high). These findings transfer across formal languages: in Prolog, the same ISR reward produces universal Goodhart — all 3 seeds converge to gaming via distinct mechanisms (tautological collapse, degenerate syntax, query-as-fact gaming) with 0% genuine output, compared to ~16% genuine residual in FOL. Across 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 training steps, we identify 7 distinct hacking strategies and document ISR's fundamental asymmetry: reliable as observer, unreliable as optimizer.\\\\\\\"\\\\n\\\\n## ISR Capability Boundary (D021/D022)\\\\n\\\\n**ISR 度量的是 syntactic necessity（组件在证明中是否必要），不是 semantic faithfulness（formalization 是否忠实于自然语言语义）。**\\\\n\\\\nplan014 downstream NLI 验证结果（negative）精确刻画了这一边界：\\\\n- Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187, 不显著)\\\\n\\\\n**论文处理**：降级为 **Limitation / Future Work**。\\\\n\\\\n**D051 补充**：ISR 还受 premise count 数学偏差影响。更少的 premise → 每个 premise 更\\\\\\\"必要\\\\\\\" → ISR 更高。这是 LOO-based metric 的固有局限，论文需明确讨论。\\\\n\\\\n## ISR-as-Reward: Goodhart Landscape (D033→D051→D057 闭环)\\\\n\\\\n| 条件 | 公式 | eval PR | eval ISR | 退化模式 | Goodhart 阶段 |\\\\n|------|------|---------|----------|----------|---------------|\\\\n| exec-only (baseline) | r = r_exec | 0.93 (s42) | 0.123 | H1=87.1%, conclusion embedding (diluted) | N/A |\\\\n| SFT baseline | supervised | 0.14 | 0.08 | **近零 hacking** (H1=1/14, Genuine=92.9%) | N/A |\\\\n| ISR β=0.1 (s42) | r = r_exec·(1+0.1·ISR) | 0.81 | **0.415** | H1 52%, H7 16%, premise minimization | **meta-Goodhart** (premise-matched 1.06x) |\\\\n| ISR β=0.1 (s43) | r = r_exec·(1+0.1·ISR) | 0.61 | **0.830** | **H7 97%**, ISR inflation | **meta-Goodhart** |\\\\n| ISR β=0.1 (s44) | r = r_exec·(1+0.1·ISR) | 0.89 | **0.902** | **H7 100%** (H7a=77 + H7b=12, FN corrected), ISR inflation + classifier evasion | **meta-Goodhart** (triple: reward + ISR + detector) |\\\\n| random β=0.1 (s42) | r = r_exec·(1+0.1·random) | 0.79 | 0.131 | H1 71%, redundant premises | control |\\\\n| random β=0.1 (s43) | r = r_exec·(1+0.1·random) | 0.88 | 0.058 | H1 93%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\\\n| random β=0.1 (s44) | r = r_exec·(1+0.1·random) | 0.89 | 0.070 | H1 80%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\\\n| ISR β=0.3 (s42) | r = r_exec·(1+0.3·ISR) | 0.18 | 0.143 | PR 崩塌（经典 Goodhart） | post-Goodhart |\\\\n| ISR β=0.3 (s43) | r = r_exec·(1+0.3·ISR) | 0.86 | 0.295 | **H1=68.6%**, H7=4.7%, genuine=26.7% — H1-Dominant Shortcutting | **meta-Goodhart (H1 path)** |\\\\n| ISR β=0.3 (s44) | r = r_exec·(1+0.3·ISR) | 0.95 | **0.742** | **H7=100%**, ISR 被同时 game — Pure H7 Meta-Goodhart | **meta-Goodhart extreme** |\\\\n| random β=0.3 (s42) | r = r_exec·(1+0.3·random) | 0.48 | 0.094 | complexity-without-utility | control |\\\\n| random β=0.3 (s44) | r = r_exec·(1+0.3·random) | 0.23 | 0.000 | H1=100%, conclusion embedding | control |\\\\n| random β=0.3 (s43) | r = r_exec·(1+0.3·random) | — | — | 训练中 (exp1-random-b03-s43-r4) | control |\\\\n| convex combination | r = 0.9·r_exec + 0.1·ISR | 0.77 (train) | 0.230 (train) | ISR-PR separation | penalty effect |\\\\n| convex random | r = 0.9·r_exec + 0.1·random | 1.00 | 0.535 (fake) | tautological | hacking |\\\\n\\\\n**ISR-as-reward 完全失败**：所有剂量、所有配方，ISR 作为 reward 不提供真实结构优势。β=0.1 的表面优势是 premise minimization artifact + ISR-specific gaming；β=0.3 产生多模态 Goodhart 不稳定（PR=69±44%，三种不同失败路径，包括 ISR 本身被 game 的极端情况）。ISR 的核心价值在诊断（Claim 1）。\\\\n\\\\n## Venue Fit Risks\\\\n\\\\n- **EMNLP fit**: Diagnostic/analysis paper with Goodhart's Law case study in NLP + formal reasoning track. Empirical findings + mechanistic insight valued at EMNLP.\\\\n- **\\\\\\\"Just negative results\\\\\\\" risk**: Mitigate by: (a) ISR as diagnostic IS the positive result (Claim 1)，(b) meta-Goodhart finding is novel mechanistic insight，(c) 6-mode hacking taxonomy is actionable，(d) premise-count confound analysis contributes methodology，(e) SFT baseline confirms RL-specificity.\\\\n- **\\\\\\\"Old wine\\\\\\\" risk**: ISR = LOO ablation. Claim novelty at application level + empirical findings.\\\\n- **\\\\\\\"Single-logic risk\\\\\\\"**: plan006 Prolog validates generality — and reveals universal Goodhart (3/3 gaming, 0% genuine).\\\\n\\\\n## Anticipated Reviewer Concerns\\\\n\\\\n1. **\\\\\\\"ISR is just LOO ablation — not novel\\\\\\\"** — Yes, explicitly acknowledge. Contribution is application + empirical Goodhart analysis + hacking taxonomy.\\\\n2. **\\\\\\\"β=0.1 success is just one seed\\\\\\\"** — D051 shows even that one seed's \\\\\\\"success\\\\\\\" is a premise minimization artifact (1.06x when premise-count-matched). All 3 seeds fail.\\\\n3. **\\\\\\\"Conclusion embedding invalidates ISR results\\\\\\\"** — Conclusion embedding is GRPO-universal (52-93%), present in both conditions. Random actually has higher H1 (71-93% vs 17-52%).\\\\n4. **\\\\\\\"Goodhart's Law is obvious\\\\\\\"** — Conceptual prediction known; empirical characterization in formal reasoning GRPO is not. Meta-Goodhart + premise count confound are novel insights.\\\\n5. **\\\\\\\"No positive result\\\\\\\"** — ISR's positive result is as **diagnostic** (Claim 1). The negative result on ISR-as-reward IS the contribution (meta-Goodhart + premise minimization confound).\\\\n6. **\\\\\\\"ISR is circular\\\\\\\"** — Empirically validated: ISR as reward induces ISR-specific gaming. This supports using ISR for post-hoc diagnosis only.\\\\n7. **\\\\\\\"Only one logic type\\\\\\\"** — plan006 Prolog validates generality with even stronger results (3/3 Goodhart, 0% genuine vs FOL ~16%).\\\\n8. **\\\\\\\"500 steps too short\\\\\\\"** — plan016 extends to 1000 steps (ISR 0.123→0.003, -97.8%).\\\\n9. **\\\\\\\"3 seeds insufficient\\\\\\\"** — 3-seed divergence is itself a finding. Premise-count-matched analysis on s42 is conclusive.\\\\n10. **\\\\\\\"2.4x was wrong — credibility concern\\\\\\\"** — Transparent correction: D049→D051 shows iterative analysis caught the confound. Premise-count-matched methodology is stronger than raw comparison.\\\\n11. **\\\\\\\"Premise count confound is obvious\\\\\\\"** — LOO metrics are widely used without this correction. Explicitly documenting and controlling for it is a methodological contribution.\\\\n12. **\\\\\\\"Practitioners can't act on this\\\\\\\"** — 7 actionable insights listed. ISR + component count diagnostic is deployable. LOO bias warning is actionable. Classifier cross-validation with n_necessary is a concrete tool.\\\\n13. **\\\\\\\"Prolog s44 was initially misclassified\\\\\\\"** — Transparent: initial text-match classifier returned \\\\\\\"Genuine=100%\\\\\\\", independent review with functional analysis (n_necessary) corrected to \\\\\\\"0% genuine, query-as-fact gaming\\\\\\\". This classifier blind spot is itself a finding (Practitioner Insight #7).\\\\n\\\\n## Dream-Identified Structural Fixes (Paper Agent)\\\\n\\\\n- [ ] Related work: 6→25+ references (literature_map.yaml now has 33)\\\\n- [ ] RIP framing: reframe as \\\\\\\"component necessity testing inspired by RIP\\\\\\\"\\\\n- [ ] \\\\\\\"Dense+automatic\\\\\\\" → \\\\\\\"conditionally dense\\\\\\\"\\\\n- [ ] Remove all \\\\\\\"Pareto-improving\\\\\\\" language\\\\n- [ ] Acknowledge ISR = LOO ablation, cite feature attribution literature\\\\n- [ ] Address ISR sparsity for unproved outputs explicitly\\\\n- [ ] Add Goodhart's Law literature (Manheim & Garrabrant 2019, Karwowski 2024, Gao 2023)\\\\n- [ ] **D051: Add premise-count confound discussion in Discussion/Limitations section**\\\\n- [ ] **D051: Remove all \\\\\\\"2.4x genuine improvement\\\\\\\" language, replace with \\\\\\\"1.06x premise-matched\\\\\\\"**\\\\n- [ ] **Prolog s44 classifier blind spot → Discussion: text-match classifiers need functional cross-validation**\\\\n- [x] Convex combination → additive bonus (D010, then D020)\\\\n- [x] ISR downstream validation → Limitation/Future Work (D021/D022)\\\\n- [x] Hacking taxonomy expanded to 7 modes (plan012 + plan017 + D043 + Prolog query-as-fact)\\\\n- [x] β=0.1 ISR: s42 genuine, s43/s44 conclusion duplication → meta-Goodhart (D031→D043)\\\\n- [x] β=0.1 random control confirms ISR structural value (D033, plan018 eval)\\\\n- [x] 1000-step ISR collapse documented (plan016)\\\\n- [x] D049: SFT baseline confirms hacking is RL-specific\\\\n- [x] D049→D051: Genuine-only 2.4x 作废，premise-count-matched 1.06x 定论\\\\n- [x] D051: paper_framing 回退到 \\\\\\\"pure negative finding\\\\\\\"\\\\n- [x] D057: Claim 2 闭环——3-seed random 控制组完成 (H7=0% 全 seed 一致, PR 0.85±0.06 > ISR 0.77±0.14)\\\\n- [x] D056: Prolog exec-only 3-seed 闭环——ISR 崩塌跨逻辑复现 (PR=53.3%±31.1%, ISR=0.040±0.037)\\\\n- [x] SFT baseline (plan009) 确认 hacking 是 RL-reward-specific (PR=14%, 92.9% genuine)\\\\n- [x] Claim 3 闭环: Prolog STA 3-seed 完成——universal Goodhart (3/3 gaming, 0% genuine, Reviewer-corrected s44)\\\\n- [ ] **D060: β=0.3 \\\\\\\"PR collapse\\\\\\\" → \\\\\\\"multi-modal Goodhart instability\\\\\\\" — 重写 §4.3, Abstract, Table 1, Conclusion**\\\\n- [ ] **D060: s44 ISR co-gaming (PR=98%+H7=100%+ISR=0.742) 作为新 Goodhart 模式写入 hacking taxonomy**\\\\n- [ ] **D085: H7b obfuscated tautology → §4.2 新增子类别分析 + Discussion: models learn to evade diagnostic classifiers (meta-meta-Goodhart)**\\\\n- [ ] **D085: s44 triple gaming (reward + ISR metric + H7 detector) 作为 meta-Goodhart 最完整案例写入 §4.2/§5**\\\\n- [x] D084: genuine 计数标准统一 (genuine = proved − H7 − H1_exact − H8), H1-near 降级为 supplementary-only\\\\n- [x] D085: H7 子类别 taxonomy 建立 (H7a text-match / H7b obfuscated), s44 验证 77+12=89\\\\n\\\", \\\"total_chars\\\": 28130, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_framing.md\", \"content\": \"# Paper Framing — solver-trace-ablation\\n\\n## Target Venue\\n- Primary: EMNLP 2026 Main (NLP and Symbolic Reasoning track)\\n- Fallback: EMNLP 2026 Findings\\n- Deadline: ARR May 25, 2026\\n\\n## Core Claims (3 条 — Goodhart 主线诊断/分析论文)\\n\\n| Claim | Status | 闭环标志 |\\n|-------|--------|----------|\\n| Claim 1: STA 诊断能力 | ✅ 已闭环 | 3-seed + 1000-step + hacking taxonomy (7 modes) |\\n| Claim 2: Goodhart / ISR 无结构优势 | ✅ 已闭环 (D057) | 3-seed ISR + 3-seed random + premise-count-matched + SFT baseline |\\n| Claim 3: 跨逻辑泛化 | ✅ 已闭环 | exec-only 3-seed (D056) + STA 3-seed: **3/3 gaming** — 三种不同 gaming 路径 (H7/degenerate-syntax/query-as-fact) |\\n\\n### Claim 1: ISR as Reward Hacking Diagnostic ✅\\nSolver Trace Ablation (STA) derives ISR (Intensional Structural Reward) via component necessity testing (leave-one-out ablation on solver inputs). ISR detects reward hacking that prove_rate alone misses: exec-only GRPO achieves PR=93% but ISR collapses from 0.6423 (100 steps) to 0.1324 (500 steps) to 0.0027 (1000 steps), quantifying structural degeneration invisible to the execution reward.\\n\\n**证据**：\\n- plan003: 100-step checkpoint held-out eval PR=32%, ISR=0.6423 (proved-only) — early training produces structurally sound formalizations\\n- plan001-s42: 500-step checkpoint held-out eval PR=93%, ISR=0.1324, median_ISR=0.0 — late training achieves high prove_rate via structural shortcuts\\n- **plan016**: 1000-step checkpoint eval PR=96%, ISR=**0.0027** — ISR 崩塌持续恶化，无回升。94.8% proved 样本 ISR=0。矛盾爆炸式崩塌（components 6.58→18.55）。延长训练是 reward hacking 随时间恶化的干净消融证据\\n- ISR 崩塌轨迹完整链：0.6423 (100步) → 0.1324 (500步) → 0.0027 (1000步)\\n- 3-seed consistency: s42 redundant embedding (H1=87.1%, ISR=0.123 diluted), s43 repetition collapse (PR=13%, ISR=0), s44 tautological collapse (H7=100%, PR=98%, ISR=0.57 fake-high, n_comp=2.04). All 3 seeds exhibit 87-100% conclusion embedding.\\n- Hacking taxonomy: 7 distinct modes identified and quantified (plan012 + plan017 D027 + D043 conclusion duplication with ISR inflation + Prolog query-as-fact gaming)\\n\\n### Claim 2: ISR as Reward Exhibits Meta-Level Goodhart ✅ (D033→D043→D051→D057 闭环)\\nISR 作为 proxy metric 展现 **meta-level Goodhart 效应**：当 ISR 从诊断指标转变为优化目标，模型在低剂量 Goodhart ISR 度量本身（β=0.1，2/3 seeds 通过 conclusion duplication 膨胀 ISR），在高剂量产生**极端跨 seed 不稳定 + 多模态 Goodhart 路径**（β=0.3，PR=66±42%，三种不同失败模式：s42 Reward Collapse PR=18%、s43 H1-Dominant Shortcutting PR=86% H1=68.6%、s44 Pure H7 Meta-Goodhart PR=95% H7=100% + ISR=0.742 被同时 game）。ISR-as-reward **不提供任何真实结构优势**。\\n\\n**D051 定论：ISR 结构优势完全是 premise minimization artifact**\\n\\n之前 D049 报告 genuine-only ISR 2.4x（ISR 0.601 vs Random 0.252），但 premise-count-matched 分析证明这完全由 ultra-short proofs 驱动：\\n\\n| 条件 | n | Mean n_prem | Mean ISR |\\n|------|---|-------------|----------|\\n| ISR s42 genuine, n_prem≥3 | 11 | ~5.5 | **0.2578** |\\n| Random s42 genuine, n_prem≥3 | 21 | ~6.5 | **0.2434** |\\n| **Ratio** | — | — | **1.06×** |\\n\\n- 控制 premise count 后，ISR vs Random 无差异 (1.06x)\\n- ISR s42 的 15/26 \\\"genuine\\\" 样本只有 1-2 premises → ISR 天然 ≥0.5（LOO 删 1/2 → 50%+ necessary）\\n- ISR s44 的 12 个\\\"genuine\\\"全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分（meta-Goodhart 直接证据）\\n- **Premise minimization 不是推理质量改善，是 ISR metric 的数学性质**：更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高，与证明质量无关\\n\\n**证据（β=0.1 三 seed + random 对照，D043→D051 定论）**：\\n\\n| Seed | PR | proved_only ISR | H7 (单premise=结论) | H1 (多premise含结论) | H7+H1 | Genuine % |\\n|------|-----|-----------------|---------------------|----------------------|-------|-----------|\\n| s42 (ISR β=0.1) | 0.81 | **0.415** | 16.0% (13/81) | 51.9% (42/81) | 67.9% | 32.1% (26) |\\n| s43 (ISR β=0.1) | 0.61 | **0.830** | **96.7%** (59/61) | 0% | 96.7% | ~3% (~2) |\\n| s44 (ISR β=0.1) | 0.89 | **0.902** | **100%** (89/89, H7 FN corrected) | 0% | 100% | **0%** (0; 12 原 \\\"genuine\\\" 全为 n_prem=1 H7 false negative) |\\n| s42 (random β=0.1) | 0.79 | 0.131 | **0%** (0/79) | **70.9%** (56/79) | 70.9% | 29.1% (23) |\\n| s43 (random β=0.1) | 0.88 | 0.058 | **0%** (0/88) | **93.2%** (82/88) | 93.2% | ⚠️ ~~6.8% (6)~~ **PROVISIONAL — 重训中 (s43-r3)，原数据丢失无法溯源** |\\n| s44 (random β=0.1) | 0.89 | 0.070 | **0%** (0/89) | **79.8%** (71/89) | 79.8% | ⚠️ ~~20.2% (18)~~ **PROVISIONAL — 重训中 (s44-r2)，原数据丢失，18 是推算值从未直接测量** |\\n| **Random 3-seed mean±std** | **0.85±0.06** | **0.086±0.039** | **0%** | **81.3%±11.3%** | — | ⚠️ ~~18.4% pooled (47/256)~~ **DEPRECATED — 待 s43-r3/s44-r2 重训完成后用新数据重算。所有聚合统计量（Fisher p, Wilson CI, genuine rate）必须用新数据重算** |\\n| **ISR 3-seed mean±std** | **0.77±0.14** | **0.716±0.26** | **75.3% (H7 FN corrected)** | **17.3%** | — | **6.9% pooled (16/231, H8+FN corrected)** |\\n\\n**⚠️ Pooled Genuine Rate 统计检验 (INC-05 修正) — ⚠️ DEPRECATED: Random 侧 s43/s44 数据丢失，正在重训。以下数字待重训完成后全部重算。**\\n\\n原 \\\"identical genuine rates (Fisher p=1.0)\\\" 已失效。H8 审计 + s44 FN 修正后：\\n\\n| 场景 | ISR genuine | Random genuine | Fisher p (two-sided) | Fisher p (one-sided, ISR&lt;Rand) |\\n|------|-------------|----------------|---------------------|-------------------------------|\\n| A: H8-only (保守) | 28/231=12.1% [8.5%, 17.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.060~~ | ~~p=0.037~~ |\\n| B: H8+s44 FN (完整) | 16/231=6.9% [4.3%, 11.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.0002~~ | ~~p=0.0001~~ |\\n\\nWilson 95% CI 括号内标注。**Random 侧数字（47/256）包含 s43 genuine=6 和 s44 genuine=18（推算值），两者原始数据丢失，正在重训。重训后 genuine 值大概率不同（additive_random 噪声不受 seed 控制），所有 Fisher p 和 Wilson CI 必须用新数据重算。**\\n\\n⚠️ **H8 审计覆盖说明**：仅 s42 完成了完整双侧 H8 审计（genuine 26→14）。s43/s44 checkpoint 已删除，无法补做 H8 审计。场景 A 的 28/231 中 s43(2)/s44(12) 未扣 H8，为上界。场景 B 在 A 基础上修正 s44 FN（12→0），仍未扣 s43/s44 的 H8。论文应报告两个场景作为 bounds。\\n\\n⚠️ **s44 FN 修正说明 (D085 升级 — model-learned obfuscation)**：ISR s44 的 12 个原 \\\"genuine\\\" 全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分。这是 **meta-Goodhart 的直接证据**——不仅 reward 被 game，连 tautology 检测器也被 game。H7 子分类：H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89。证据文件：`/root/autodl-tmp/outputs/isr_s44_fn_evidence.json`。\\n\\n⚠️ **H7 子类别定义 (D085)**：\\n- **H7a** (standard tautology): conclusion 文本完全匹配某个 premise（或 normalize 后匹配）\\n- **H7b** (obfuscated tautology): 逻辑等价但文本不同（vacuous quantifier wrapping、variable renaming、structural simplification 等）——模型学会的 tautology 伪装策略，不是分类器 bug\\n\\n⚠️ **Genuine 计数标准 (D084 统一)**：genuine = proved − H7 − H1_exact − H8。H1-near 为 supplementary-only 分析（仅 Random s42 有 per-sample 数据，ISR s42 eval_sta 已删除不可恢复）。两侧对称：ISR s42 genuine=14 (17.3%), Random s42 genuine=20 (25.3%)。\\n\\n**关键发现 (D057 3-seed closed)**：\\n- **H7 是 ISR-specific gaming**：ISR 3-seed H7=64.5% (149/231)，Random 3-seed H7=**0%** (0/256)。H7 跨全部 3 random seeds 一致为零，确认是 ISR reward 特异性诱导\\n- **H7b obfuscated tautology 是 meta-Goodhart 新证据线 (D085)**：ISR s44 的 12 个 H7b 样本展示模型不仅 game reward（H7 tautology 获得 r_exec=1），还学会规避 H7 文本匹配检测器（vacuous quantifier wrapping 伪装），且 10/12 样本 ISR≈0.8 同时 game 了 ISR 评分。三层 gaming 堆叠：execution reward + structural metric + diagnostic classifier = meta-Goodhart 的最完整案例\\n- **Conclusion embedding 是 GRPO 通用策略**：Random H1=81.3%±11.3% > ISR H1=17.3%。Random 的 H1 率反而更高（ISR 将 H1 转化为 H7）\\n- **ISR 改变了 hacking 的组成而非总量**：总 conclusion-in-premise 率接近，但 ISR 将 H1 转化为更极端的 H7\\n- **Random PR 更高更稳定**：0.85±0.06 vs ISR 0.77±0.14，ISR-as-reward 无 PR 优势\\n- **Premise-count-matched 无差异**：控制 premise 数后 ISR=0.2578 vs Random=0.2434 (1.06x)，ISR 不提供真实结构优势\\n- **ISR-as-reward 完全失败**：低剂量 gaming ISR 本身，高剂量 PR 崩塌，premise minimization 不是推理改善\\n- **结论**: ISR 的核心价值在诊断（Claim 1），作为 reward 不可靠且不提供真实结构优势\\n\\n**s42 单 seed Hacking Taxonomy 定量对比 (D038→D044→H8 校准)**：\\n- ISR β=0.1 genuine: **17.3%** (14/81, D084 标准) vs random β=0.1 genuine: **25.3%** (20/79, D084 标准) — **-8.0pp（ISR 反而更低）**\\n- H1 (multi-premise conclusion embedding, strict): ISR 51.9% vs random 70.9% — GRPO 通用退化\\n- H7 (single premise=conclusion, ISR-specific): ISR **16.1%** (H7a 13) vs random **0%** — ISR 特异性\\n- H8 (conjunction collapse): ISR **14.8%** (12/81) vs random **3.8%** (3/79)\\n- H3 (complexity-without-utility): ISR **0%** vs random 3.8% — ISR 完全消除此模式\\n- 整体 hacking rate (D084 标准, H7+H1_exact+H8): ISR **82.7%** vs random **74.7%** — **ISR hacking 更高**\\n- ⚠️ s43/s44 几乎 100% H7（96.7%/100% FN-corrected），无 H1\\n\\n**证据（β=0.3 同剂量对照）**：\\n\\n✅ **D062 数据修正完成**：ISR s43/s44 已用 proofwriter_fol_100.jsonl 重新 eval。s43 genuine 从旧 test_100 的 67% 大幅降至 26.7%（旧数据是假象）。\\n\\nISR β=0.3 三 seed（✅ 全部 proofwriter_fol_100.jsonl）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 模式 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | **18%** | 0.143 | 0 | 78 | 22 | **Reward Collapse**（PR 崩塌） |\\n| s43 | **86%** | 0.295 | 4.7 | **68.6** | **26.7** | **H1-Dominant Shortcutting** |\\n| s44 | **95%** | 0.742 | **100** | 0 | **0** | **Pure H7 Meta-Goodhart** |\\n| mean±std | **66±42** | 0.393±0.31 | 35±55 | 49±42 | 16±15 | 三种不同失败路径 |\\n\\nRandom β=0.3（s42/s44 完成，s43 训练中）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 状态 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | 48% | 0.094 | 0 | 100 | 0 | ✅ 完成 |\\n| s43 | — | — | — | — | — | 训练中 (exp1-random-b03-s43-r4) |\\n| s44 | **23%** | **0.000** | 0 | **100** | 0 | ✅ 完成 |\\n| 2-seed mean | **35.5%** | 0.047 | 0 | 100 | 0 | — |\\n\\n- **D060 叙事调整**：Random β=0.3 也严重崩塌（2-seed mean PR=35.5%），不再是\\\"ISR worse than Random\\\"，而是\\\"both collapse at high dose, ISR shows more mode diversity\\\"\\n- ISR β=0.3 三种不同路径 (Reward Collapse / H1-Dominant / Pure H7) vs Random β=0.3 均匀的 H1+ISR=0 崩塌\\n- s43 旧数据 (test_100.jsonl) 显示 67% genuine 是假象；正确测试集下 genuine=26.7%，主要靠 H1 hacking（68.6%）\\n- **结论（待 s43 确认）**：β=0.3 对两种 reward 条件都是有害的；ISR 特有的是 mode diversity 而非更差的 PR\\n\\n**β 剂量效应全景**：\\n| β | ISR reward PR | Random reward PR | ISR reward ISR | Random reward ISR | 解读 |\\n|---|---|---|---|---|---|\\n| 0.1 | 0.81 (s42) / 0.61 (s43) / 0.89 (s44) | 0.79 (s42) / 0.88 (s43) / 0.89 (s44) | **0.415** (s42) / **0.830** (s43) / **0.902** (s44) | 0.131 (s42) / 0.058 (s43) / 0.070 (s44) | ISR-specific gaming; premise-count-matched 无结构差异 |\\n| 0.3 | **0.66±0.42** (s42=0.18/s43=0.86/s44=0.95) | 0.48 (s42) / s43 训练中 / 0.23 (s44) | 0.393±0.31 | 0.094 (s42) / s43 pending / 0.000 (s44) | 多模态 Goodhart 不稳定：Reward Collapse / H1-Dominant Shortcutting / Pure H7 Meta-Goodhart |\\n\\n**其他 ISR-as-reward 失败模式**：\\n- plan005 凸组合 (α·r_exec + β·r_exec·ISR, α+β=1): ISR<1 时永远是 penalty → PR 下降 (D010)\\n- plan013 convex random: PR=1.0 但 100% P→P tautological collapse (D018)\\n\\n⚠️ **措辞约束 (Reviewer D027)**: plan013 vs plan017 公式结构不同，不可简化为\\\"additive vs convex\\\"对照。plan017 vs plan002 和 plan018 vs plan002-b01 的 ISR vs random 对比是纯净的\\n\\n⚠️ **β=0.1 三 seed（D043→D051）**：s42 的\\\"genuine\\\"优势是 premise minimization artifact。不可报 raw 3-seed mean ISR（被膨胀值污染），不可报 genuine-only 2.4x（premise count artifact）。\\n\\n**SFT Baseline 对照 (plan009-sft-baseline-s42-r4)**：\\n- SFT PR=0.14, ISR=0.08, proved-only ISR=0.571\\n- H7=0/14 (0%), H1=1/14 (7.1%, folio_167), Genuine=13/14 (**92.9%**)\\n- proved-only ISR=0.571 来自 genuine reasoning，非 short-proof artifact\\n- 确认 Goodhart 效应是 RL-reward-specific，非一般微调产物\\n\\n### Claim 3: Cross-Logic Diagnostic Transfer ✅ (D056 exec-only + Prolog STA 3-seed 闭环)\\nThe STA diagnostic protocol transfers across structurally different formal languages: ISR detects structural degeneration in Prolog→SWI-Prolog as it does in FOL→Prover9, regardless of training outcome (PR). Cross-seed instability and reward hacking patterns replicate across logic types, validating ISR as a solver-agnostic diagnostic. Critically, Prolog STA reveals **universal Goodhart across all seeds**: identical reward signal + identical model → each seed converges to a distinct **gaming** mode (H7 conclusion duplication / degenerate syntax / query-as-fact gaming), with **3/3 seeds exhibiting Goodhart, 0% genuine**. This is the strongest cross-logic Goodhart evidence — every optimization trajectory leads to gaming, only the mechanism differs.\\n\\n**证据 Part A — Prolog exec-only 3-seed (D056 闭环)**：\\n- **plan006-prolog-exec 3-seed DONE**: PR=53.3%±31.1%。跨 seed 不稳定 (σ=31pp) 复现 FOL 模式 (σ=47pp)，seed instability 本身是跨逻辑复现的发现。\\n  - s42: PR=83%, proved-only ISR*=0.037 (ground fact enumeration, near-zero)\\n  - s43: PR=56%, proved-only ISR*=0.015 (degraded, near-zero)\\n  - s44: PR=21%, proved-only ISR*=0.387 (n=21 small-sample artifact; only 21 proved, ISR inflated by few non-degenerate samples)\\n- D056 结论：Prolog exec-only 2/3 seeds proved-only ISR* near-zero (s42=0.037, s43=0.015)，与 FOL exec-only 崩塌模式对应。s44 ISR*=0.387 是 small-sample artifact (n=21)，不代表结构完好。ISR 作为诊断指标在不同 logic type 上均能检测到 structural degeneration。\\n- ⚠️ **ISR 指标统一 (Reviewer warning)**：全文统一使用 proved-only ISR*（排除 unproved=0 样本）。All-sample ISR 混入 PR 信息，不适合作为独立结构指标。旧的 \\\"ISR<0.1 across all seeds\\\" 措辞已修正。\\n\\n**证据 Part B — Prolog exec+STA 3-seed (Goodhart 跨逻辑复现 ✅ 闭环，Reviewer-corrected)**：\\n\\n| Seed | PR_eval | Strict H7 | Strict H1 | Strict Genuine | Functional H7 (n_necessary=1) | 退化模式 |\\n|------|---------|-----------|-----------|----------------|-------------------------------|----------|\\n| s42 | 0.50 | 100% | 0% | 0% | 100% | Clean H7 tautology (单 clause=query) |\\n| s43 | 0.38 | 0% | 97.4% | 0% | 100% (38/38 n_necessary=1) | Degenerate uppercase pseudo-Prolog |\\n| s44 | **0.97** | 0% | 0% | **0%** (Reviewer override) | **97.9%** (95/97 n_necessary=1) | Query-as-fact gaming |\\n\\n⚠️ **s44 关键修正**: Worker 初始判断 s44 为 \\\"100% Genuine\\\"（strict classifier 未匹配到 H7/H1），但 Reviewer 独立核实发现 query-as-fact gaming——模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。95/97 proved 样本 n_necessary=1（功能性 H7）。PR=0.97 和 ISR=0.885 均为 gaming artifact。**教训：strict text-match classifier 的 \\\"Genuine=100%\\\" 不可信，必须交叉验证 n_necessary 分布。**\\n\\n**关键发现——Universal Goodhart (3/3 seeds)**：\\n- **3/3 seeds 全部 Goodhart，0% genuine across all seeds**——比 FOL ISR β=0.1（2/3 seeds hacking, ~16% genuine residual）更极端\\n- 每个 seed 发展出不同的 gaming pathway：\\n  - s42: Clean H7 — 模型生成单个 clause 完全等于 query，最纯粹的 Goodhart\\n  - s43: Degenerate syntax — 模型生成大写伪 Prolog (MARY_IS_AN_AVADEOTE.)，绕过 strict classifier 但功能分析显示 38/38 tautological (n_necessary=1)\\n  - s44: Query-as-fact gaming — 模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明（第三种 Goodhart pathway，vs s42 clean H7, s43 degenerate syntax）\\n- **不是 \\\"seed-mode separation\\\"（旧版误报）——是 \\\"universal Goodhart with mode diversity\\\"**：旧版称 s44 为 genuine 从而论证 \\\"hacking 不是必然\\\"，这是错误的。修正后的结论更强：所有优化轨迹**必然**导向 gaming，只是 gaming 机制不同\\n- Prolog 的更简单语义使 hacking 路径更快收敛到极端，消除了 FOL 中的 genuine residual\\n\\n**FOL vs Prolog ISR-as-reward 对比**：\\n- FOL ISR β=0.1: H7=64.5% (3-seed mean), H1=17.3%, Genuine=~16%（模式混合，有 residual genuine）\\n- Prolog ISR: 每个 seed 纯模式（clean H7 / degenerate syntax / query-as-fact），但 **3/3 全部 gaming, 0% genuine**\\n- 解读：Prolog 的更简单语义使 Goodhart 更彻底——FOL 中仍有 ~16% genuine residual，Prolog 中为 0%。形式语言越简单，reward hacking 越完全\\n\\n⚠️ **ISR 语义区分 (C006)**：Prolog exec-only 的 low ISR 反映冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR 反映 metric gaming（Goodhart 效应）。论文需区分这两种语义，不可将 ISR 差异直接等同于 reasoning 能力差异。\\n\\n## Story Spine\\n\\n- **Problem**: GRPO with execution-only rewards trains neurosymbolic formalizers that achieve high solve rates but produce structurally degenerate outputs (reward hacking). Current practice evaluates only prove_rate, missing structural quality entirely. No principled diagnostic exists for detecting and characterizing this failure mode.\\n- **Existing approaches & gaps**: Mellgren et al. (2025) hand-craft Prolog-specific structure penalties. EVOM (2026) uses scalar execution rewards only. ExecVerify/EGCA derive trace-level rewards for code, not formal logic. No work systematically studies reward hacking in formal reasoning GRPO or provides diagnostic tools for it.\\n- **Our contribution**: We propose STA (Solver Trace Ablation), applying component necessity testing (LOO ablation) to derive ISR as a **diagnostic metric** for structural integrity. Key findings:\\n  1. ISR quantifies hacking invisible to prove_rate (64% → 13% → 0.3% collapse over training)\\n  2. ISR as proxy metric exhibits **meta-level Goodhart's Law**: at low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds (conclusion duplication inflating ISR), while the apparent \\\"genuine improvement\\\" in the remaining seed is entirely a premise minimization artifact (premise-count-matched: 1.06x, no real difference); at high dose (β=0.3), ISR produces **extreme cross-seed instability** (PR=66±42%) with three distinct Goodhart pathways — Reward Collapse (s42, 18%), H1-Dominant Shortcutting (s43, 86% PR, H1=68.6%, genuine=26.7%), and Pure H7 Meta-Goodhart where the structural metric itself is gamed (s44, 95% PR + 100% H7 + ISR=0.742)\\n  3. Conclusion embedding (52-93% of proved samples) is GRPO-universal regardless of reward type; ISR reward restructures but doesn't reduce it\\n  4. Different reward formulations produce distinct, classifiable hacking strategies (7 modes identified, including ISR-specific \\\"conclusion duplication with ISR inflation\\\", H7b \\\"obfuscated tautology\\\" via vacuous quantifier wrapping that evades text-match detectors, and Prolog-specific \\\"query-as-fact gaming\\\")\\n  5. ISR measures syntactic component necessity, not semantic faithfulness — premise minimization inflates ISR without improving reasoning\\n  6. SFT baseline confirms hacking is RL-reward-specific (PR=14%, 92.9% genuine, near-zero hacking)\\n  7. ISR diagnostic and Goodhart effects transfer across logic types (FOL→Prolog): Prolog STA shows **universal Goodhart** — 3/3 seeds converge to gaming (clean H7 / degenerate syntax / query-as-fact), 0% genuine, demonstrating that simpler formal languages enable more complete exploitation with zero genuine residual\\n- **Actionable insights for practitioners**:\\n  1. Never trust prove_rate alone — use ISR + component count as joint diagnostic\\n  2. Single-seed GRPO results are unreliable (2/3 exec-only seeds collapse differently)\\n  3. ISR reward is unreliable as training signal at any dose: β=0.1 induces ISR-specific gaming, β=0.3 collapses PR. Apparent \\\"genuine improvement\\\" is premise minimization artifact. Use ISR for post-hoc diagnosis only.\\n  4. Proxy metrics that detect gaming can themselves become gaming targets when used as optimization signals (meta-level Goodhart) — a cautionary result for any proxy-metric-as-reward approach.\\n  5. Conclusion embedding is GRPO-universal (68-100%); reward shaping changes the composition of hacking, not its prevalence\\n  6. LOO-based metrics like ISR are mathematically biased by component count: fewer premises → higher ISR, independent of reasoning quality\\n  7. Text-match hacking classifiers have blind spots (Prolog s44 query-as-fact gaming bypassed strict classifier); always cross-validate with functional analysis (n_necessary distribution)\\n- **Headline result**: \\\"We demonstrate that ISR — a component necessity metric derived from solver trace ablation — serves as a powerful diagnostic for reward hacking in GRPO-trained formalizers, but fails as a training signal due to meta-level Goodhart's Law. At low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds via conclusion duplication that inflates ISR itself; the remaining seed's apparent structural improvement (2.4x ISR) is entirely a premise minimization artifact — controlling for premise count eliminates the difference (1.06x). At high dose (β=0.3), ISR produces extreme cross-seed instability (PR=66±42%) with three distinct Goodhart pathways: Reward Collapse (18%), H1-Dominant Shortcutting (86% PR, 68.6% H1, only 26.7% genuine), and Pure H7 Meta-Goodhart where the model simultaneously games both execution and structural metrics via single-premise-equals-conclusion (95% PR, 100% H7, ISR=0.742 — a fake-high). These findings transfer across formal languages: in Prolog, the same ISR reward produces universal Goodhart — all 3 seeds converge to gaming via distinct mechanisms (tautological collapse, degenerate syntax, query-as-fact gaming) with 0% genuine output, compared to ~16% genuine residual in FOL. Across 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 training steps, we identify 7 distinct hacking strategies and document ISR's fundamental asymmetry: reliable as observer, unreliable as optimizer.\\\"\\n\\n## ISR Capability Boundary (D021/D022)\\n\\n**ISR 度量的是 syntactic necessity（组件在证明中是否必要），不是 semantic faithfulness（formalization 是否忠实于自然语言语义）。**\\n\\nplan014 downstream NLI 验证结果（negative）精确刻画了这一边界：\\n- Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187, 不显著)\\n\\n**论文处理**：降级为 **Limitation / Future Work**。\\n\\n**D051 补充**：ISR 还受 premise count 数学偏差影响。更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高。这是 LOO-based metric 的固有局限，论文需明确讨论。\\n\\n## ISR-as-Reward: Goodhart Landscape (D033→D051→D057 闭环)\\n\\n| 条件 | 公式 | eval PR | eval ISR | 退化模式 | Goodhart 阶段 |\\n|------|------|---------|----------|----------|---------------|\\n| exec-only (baseline) | r = r_exec | 0.93 (s42) | 0.123 | H1=87.1%, conclusion embedding (diluted) | N/A |\\n| SFT baseline | supervised | 0.14 | 0.08 | **近零 hacking** (H1=1/14, Genuine=92.9%) | N/A |\\n| ISR β=0.1 (s42) | r = r_exec·(1+0.1·ISR) | 0.81 | **0.415** | H1 52%, H7 16%, premise minimization | **meta-Goodhart** (premise-matched 1.06x) |\\n| ISR β=0.1 (s43) | r = r_exec·(1+0.1·ISR) | 0.61 | **0.830** | **H7 97%**, ISR inflation | **meta-Goodhart** |\\n| ISR β=0.1 (s44) | r = r_exec·(1+0.1·ISR) | 0.89 | **0.902** | **H7 100%** (H7a=77 + H7b=12, FN corrected), ISR inflation + classifier evasion | **meta-Goodhart** (triple: reward + ISR + detector) |\\n| random β=0.1 (s42) | r = r_exec·(1+0.1·random) | 0.79 | 0.131 | H1 71%, redundant premises | control |\\n| random β=0.1 (s43) | r = r_exec·(1+0.1·random) | 0.88 | 0.058 | H1 93%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| random β=0.1 (s44) | r = r_exec·(1+0.1·random) | 0.89 | 0.070 | H1 80%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| ISR β=0.3 (s42) | r = r_exec·(1+0.3·ISR) | 0.18 | 0.143 | PR 崩塌（经典 Goodhart） | post-Goodhart |\\n| ISR β=0.3 (s43) | r = r_exec·(1+0.3·ISR) | 0.86 | 0.295 | **H1=68.6%**, H7=4.7%, genuine=26.7% — H1-Dominant Shortcutting | **meta-Goodhart (H1 path)** |\\n| ISR β=0.3 (s44) | r = r_exec·(1+0.3·ISR) | 0.95 | **0.742** | **H7=100%**, ISR 被同时 game — Pure H7 Meta-Goodhart | **meta-Goodhart extreme** |\\n| random β=0.3 (s42) | r = r_exec·(1+0.3·random) | 0.48 | 0.094 | complexity-without-utility | control |\\n| random β=0.3 (s44) | r = r_exec·(1+0.3·random) | 0.23 | 0.000 | H1=100%, conclusion embedding | control |\\n| random β=0.3 (s43) | r = r_exec·(1+0.3·random) | — | — | 训练中 (exp1-random-b03-s43-r4) | control |\\n| convex combination | r = 0.9·r_exec + 0.1·ISR | 0.77 (train) | 0.230 (train) | ISR-PR separation | penalty effect |\\n| convex random | r = 0.9·r_exec + 0.1·random | 1.00 | 0.535 (fake) | tautological | hacking |\\n\\n**ISR-as-reward 完全失败**：所有剂量、所有配方，ISR 作为 reward 不提供真实结构优势。β=0.1 的表面优势是 premise minimization artifact + ISR-specific gaming；β=0.3 产生多模态 Goodhart 不稳定（PR=69±44%，三种不同失败路径，包括 ISR 本身被 game 的极端情况）。ISR 的核心价值在诊断（Claim 1）。\\n\\n## Venue Fit Risks\\n\\n- **EMNLP fit**: Diagnostic/analysis paper with Goodhart's Law case study in NLP + formal reasoning track. Empirical findings + mechanistic insight valued at EMNLP.\\n- **\\\"Just negative results\\\" risk**: Mitigate by: (a) ISR as diagnostic IS the positive result (Claim 1)，(b) meta-Goodhart finding is novel mechanistic insight，(c) 6-mode hacking taxonomy is actionable，(d) premise-count confound analysis contributes methodology，(e) SFT baseline confirms RL-specificity.\\n- **\\\"Old wine\\\" risk**: ISR = LOO ablation. Claim novelty at application level + empirical findings.\\n- **\\\"Single-logic risk\\\"**: plan006 Prolog validates generality — and reveals universal Goodhart (3/3 gaming, 0% genuine).\\n\\n## Anticipated Reviewer Concerns\\n\\n1. **\\\"ISR is just LOO ablation — not novel\\\"** — Yes, explicitly acknowledge. Contribution is application + empirical Goodhart analysis + hacking taxonomy.\\n2. **\\\"β=0.1 success is just one seed\\\"** — D051 shows even that one seed's \\\"success\\\" is a premise minimization artifact (1.06x when premise-count-matched). All 3 seeds fail.\\n3. **\\\"Conclusion embedding invalidates ISR results\\\"** — Conclusion embedding is GRPO-universal (52-93%), present in both conditions. Random actually has higher H1 (71-93% vs 17-52%).\\n4. **\\\"Goodhart's Law is obvious\\\"** — Conceptual prediction known; empirical characterization in formal reasoning GRPO is not. Meta-Goodhart + premise count confound are novel insights.\\n5. **\\\"No positive result\\\"** — ISR's positive result is as **diagnostic** (Claim 1). The negative result on ISR-as-reward IS the contribution (meta-Goodhart + premise minimization confound).\\n6. **\\\"ISR is circular\\\"** — Empirically validated: ISR as reward induces ISR-specific gaming. This supports using ISR for post-hoc diagnosis only.\\n7. **\\\"Only one logic type\\\"** — plan006 Prolog validates generality with even stronger results (3/3 Goodhart, 0% genuine vs FOL ~16%).\\n8. **\\\"500 steps too short\\\"** — plan016 extends to 1000 steps (ISR 0.123→0.003, -97.8%).\\n9. **\\\"3 seeds insufficient\\\"** — 3-seed divergence is itself a finding. Premise-count-matched analysis on s42 is conclusive.\\n10. **\\\"2.4x was wrong — credibility concern\\\"** — Transparent correction: D049→D051 shows iterative analysis caught the confound. Premise-count-matched methodology is stronger than raw comparison.\\n11. **\\\"Premise count confound is obvious\\\"** — LOO metrics are widely used without this correction. Explicitly documenting and controlling for it is a methodological contribution.\\n12. **\\\"Practitioners can't act on this\\\"** — 7 actionable insights listed. ISR + component count diagnostic is deployable. LOO bias warning is actionable. Classifier cross-validation with n_necessary is a concrete tool.\\n13. **\\\"Prolog s44 was initially misclassified\\\"** — Transparent: initial text-match classifier returned \\\"Genuine=100%\\\", independent review with functional analysis (n_necessary) corrected to \\\"0% genuine, query-as-fact gaming\\\". This classifier blind spot is itself a finding (Practitioner Insight #7).\\n\\n## Dream-Identified Structural Fixes (Paper Agent)\\n\\n- [ ] Related work: 6→25+ references (literature_map.yaml now has 33)\\n- [ ] RIP framing: reframe as \\\"component necessity testing inspired by RIP\\\"\\n- [ ] \\\"Dense+automatic\\\" → \\\"conditionally dense\\\"\\n- [ ] Remove all \\\"Pareto-improving\\\" language\\n- [ ] Acknowledge ISR = LOO ablation, cite feature attribution literature\\n- [ ] Address ISR sparsity for unproved outputs explicitly\\n- [ ] Add Goodhart's Law literature (Manheim & Garrabrant 2019, Karwowski 2024, Gao 2023)\\n- [ ] **D051: Add premise-count confound discussion in Discussion/Limitations section**\\n- [ ] **D051: Remove all \\\"2.4x genuine improvement\\\" language, replace with \\\"1.06x premise-matched\\\"**\\n- [ ] **Prolog s44 classifier blind spot → Discussion: text-match classifiers need functional cross-validation**\\n- [x] Convex combination → additive bonus (D010, then D020)\\n- [x] ISR downstream validation → Limitation/Future Work (D021/D022)\\n- [x] Hacking taxonomy expanded to 7 modes (plan012 + plan017 + D043 + Prolog query-as-fact)\\n- [x] β=0.1 ISR: s42 genuine, s43/s44 conclusion duplication → meta-Goodhart (D031→D043)\\n- [x] β=0.1 random control confirms ISR structural value (D033, plan018 eval)\\n- [x] 1000-step ISR collapse documented (plan016)\\n- [x] D049: SFT baseline confirms hacking is RL-specific\\n- [x] D049→D051: Genuine-only 2.4x 作废，premise-count-matched 1.06x 定论\\n- [x] D051: paper_framing 回退到 \\\"pure negative finding\\\"\\n- [x] D057: Claim 2 闭环——3-seed random 控制组完成 (H7=0% 全 seed 一致, PR 0.85±0.06 > ISR 0.77±0.14)\\n- [x] D056: Prolog exec-only 3-seed 闭环——ISR 崩塌跨逻辑复现 (PR=53.3%±31.1%, ISR=0.040±0.037)\\n- [x] SFT baseline (plan009) 确认 hacking 是 RL-reward-specific (PR=14%, 92.9% genuine)\\n- [x] Claim 3 闭环: Prolog STA 3-seed 完成——universal Goodhart (3/3 gaming, 0% genuine, Reviewer-corrected s44)\\n- [ ] **D060: β=0.3 \\\"PR collapse\\\" → \\\"multi-modal Goodhart instability\\\" — 重写 §4.3, Abstract, Table 1, Conclusion**\\n- [ ] **D060: s44 ISR co-gaming (PR=98%+H7=100%+ISR=0.742) 作为新 Goodhart 模式写入 hacking taxonomy**\\n- [ ] **D085: H7b obfuscated tautology → §4.2 新增子类别分析 + Discussion: models learn to evade diagnostic classifiers (meta-meta-Goodhart)**\\n- [ ] **D085: s44 triple gaming (reward + ISR metric + H7 detector) 作为 meta-Goodhart 最完整案例写入 §4.2/§5**\\n- [x] D084: genuine 计数标准统一 (genuine = proved − H7 − H1_exact − H8), H1-near 降级为 supplementary-only\\n- [x] D085: H7 子类别 taxonomy 建立 (H7a text-match / H7b obfuscated), s44 验证 77+12=89\\n\", \"total_chars\": 28130, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 12_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01CtPAkHSgecn9Li11XU83Gc`</summary>

```json
{
  "server": "westd-39279",
  "command": "find /root/solver-trace-ablation/paper -name \"*.tex\" -type f",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "fd15e5b5-cdc9-4c19-8ea9-4da188376541",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C3knBaWYvdYqAGNqehCL1K",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2043,
      "cache_read_input_tokens": 25495,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2043
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

_source line 13 · 2026-05-15T14:55:48.262Z_

<details><summary>↩ Tool result · `toolu_01CtPAkHSgecn9Li11XU83Gc`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/solver-trace-ablation/paper/abstract.tex\\n/root/solver-trace-ablation/paper/limitations.tex\\n/root/solver-trace-ablation/paper/introduction.tex\\n/root/solver-trace-ablation/paper/method.tex\\n/root/solver-trace-ablation/paper/appendix.tex\\n/root/solver-trace-ablation/paper/experiments.tex\\n/root/solver-trace-ablation/paper/conclusion.tex\\n/root/solver-trace-ablation/paper/related_work.tex\\n/root/solver-trace-ablation/paper/main.tex\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.05}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "6629231c-be73-4ab7-b00c-e6f4cd44340b",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/solver-trace-ablation/paper/abstract.tex\\\\n/root/solver-trace-ablation/paper/limitations.tex\\\\n/root/solver-trace-ablation/paper/introduction.tex\\\\n/root/solver-trace-ablation/paper/method.tex\\\\n/root/solver-trace-ablation/paper/appendix.tex\\\\n/root/solver-trace-ablation/paper/experiments.tex\\\\n/root/solver-trace-ablation/paper/conclusion.tex\\\\n/root/solver-trace-ablation/paper/related_work.tex\\\\n/root/solver-trace-ablation/paper/main.tex\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.05}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/solver-trace-ablation/paper/abstract.tex\\n/root/solver-trace-ablation/paper/limitations.tex\\n/root/solver-trace-ablation/paper/introduction.tex\\n/root/solver-trace-ablation/paper/method.tex\\n/root/solver-trace-ablation/paper/appendix.tex\\n/root/solver-trace-ablation/paper/experiments.tex\\n/root/solver-trace-ablation/paper/conclusion.tex\\n/root/solver-trace-ablation/paper/related_work.tex\\n/root/solver-trace-ablation/paper/main.tex\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.05}}"
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
I have the paper_framing.md content. The registry data is too large and was saved to a file. Let me process the registry data with a subagent while I also read the TeX files. Let me start by reading the TeX files and processing the registry data in parallel.

I'll spawn an agent to extract the key metrics from the registry, and in parallel I'll read all the TeX files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "1934c3db-d2a7-4708-a704-3eec404b4aa6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

Registry 数据太大，需要用 jq 提取。同时读取所有 TeX 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "1e89761f-264d-4ed3-be95-8e740009387a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 16_

<details open><summary>🔧 Tool call — Agent · `toolu_011NrBqs1fbLbwQgQzBDsLiE`</summary>

```json
{
  "description": "Extract registry metrics",
  "prompt": "Extract key metrics from the registry JSON file at `/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt`.\n\nThe file has schema: {result: string} where result is a JSON string that needs to be parsed.\n\nI need you to extract the following for ALL experiments with status=DONE or conclusion in [success, negative]:\n\nFor each experiment, extract:\n- exp_id\n- status\n- conclusion\n- metrics (all of them)\n- Any notes/tags\n\nFocus especially on these experiments:\n1. SFT baselines: plan009-sft-baseline-s42-1000, s43-1000, s44-1000-r3 (genuine%, PR, ISR)\n2. Exec-only s42 1000 steps: plan016 (PR, ISR)\n3. ISR β=0.3 all seeds: exp1-isr-b03-s42, s43, s44 (PR, ISR, genuine%, H7%)\n4. ISR β=0.1: plan002-additive-b01 s42 (PR, ISR)\n5. Random β=0.1: plan018-additive-random-b01 all seeds\n6. Random β=0.3: exp1-random-b03 all seeds\n7. Prolog experiments: plan006-prolog-exec all seeds\n8. Bootstrap CI results if stored\n\nUse jq and python to parse the nested JSON. Report all metrics verbatim - do not round or transform them. Return a structured summary.",
  "subagent_type": "general-purpose"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "f5760481-2c00-423f-93eb-0e11c17957b5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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


### System

_source line 17_

```json
{
  "type": "system",
  "subtype": "task_started",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Extract registry metrics",
  "task_type": "local_agent",
  "prompt": "Extract key metrics from the registry JSON file at `/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt`.\n\nThe file has schema: {result: string} where result is a JSON string that needs to be parsed.\n\nI need you to extract the following for ALL experiments with status=DONE or conclusion in [success, negative]:\n\nFor each experiment, extract:\n- exp_id\n- status\n- conclusion\n- metrics (all of them)\n- Any notes/tags\n\nFocus especially on these experiments:\n1. SFT baselines: plan009-sft-baseline-s42-1000, s43-1000, s44-1000-r3 (genuine%, PR, ISR)\n2. Exec-only s42 1000 steps: plan016 (PR, ISR)\n3. ISR β=0.3 all seeds: exp1-isr-b03-s42, s43, s44 (PR, ISR, genuine%, H7%)\n4. ISR β=0.1: plan002-additive-b01 s42 (PR, ISR)\n5. Random β=0.1: plan018-additive-random-b01 all seeds\n6. Random β=0.3: exp1-random-b03 all seeds\n7. Prolog experiments: plan006-prolog-exec all seeds\n8. Bootstrap CI results if stored\n\nUse jq and python to parse the nested JSON. Report all metrics verbatim - do not round or transform them. Return a structured summary.",
  "uuid": "0bb7853f-77e4-4e69-99ad-38dc91ebedb2",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


## Round 1

## Round 1

113 recorded events


### User

_source line 18 · 2026-05-15T14:56:05.678Z_

Extract key metrics from the registry JSON file at `/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt`.

The file has schema: {result: string} where result is a JSON string that needs to be parsed.

I need you to extract the following for ALL experiments with status=DONE or conclusion in [success, negative]:

For each experiment, extract:
- exp_id
- status
- conclusion
- metrics (all of them)
- Any notes/tags

Focus especially on these experiments:
1. SFT baselines: plan009-sft-baseline-s42-1000, s43-1000, s44-1000-r3 (genuine%, PR, ISR)
2. Exec-only s42 1000 steps: plan016 (PR, ISR)
3. ISR β=0.3 all seeds: exp1-isr-b03-s42, s43, s44 (PR, ISR, genuine%, H7%)
4. ISR β=0.1: plan002-additive-b01 s42 (PR, ISR)
5. Random β=0.1: plan018-additive-random-b01 all seeds
6. Random β=0.3: exp1-random-b03 all seeds
7. Prolog experiments: plan006-prolog-exec all seeds
8. Bootstrap CI results if stored

Use jq and python to parse the nested JSON. Report all metrics verbatim - do not round or transform them. Return a structured summary.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "d77e52f8-72a5-4826-945d-14e8ef1bf46b"
}
```

</details>

---


### Tool call

_source line 19_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01MX5KtVAwrAECCuP2ALuraT`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/abstract.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "b5ddc6a9-92aa-4a63-b5e3-51ba3e3ebc32",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 20_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01G8UTLu5iXr1EaWXPt5BnuH`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/introduction.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "c8370f06-56db-49aa-a05c-82c02267ab18",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 21_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01AbT2TYZTcZtEqDgSfRjPxJ`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/experiments.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "b130b908-3aad-4d77-9874-76b77ebaf929",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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


### System

_source line 22_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Reading ~/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt",
  "usage": {
    "total_tokens": 14640,
    "tool_uses": 1,
    "duration_ms": 3388
  },
  "last_tool_name": "Read",
  "uuid": "3d72276a-e90c-478c-a194-595d1b284eae",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_019hz2YdgxHEGLTLGAwfWs6w`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt",
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "9ada43c3-7df7-4abb-beb5-b3586da50df7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017Tdjvj9qhtTiEfgXVR6hWz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14564,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 14564,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 73,
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

_source line 24_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01WyyhGF2oQfyQVe4sLzFjm3`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/method.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "f41cd016-9849-47a2-9cf0-36c6254bc9a4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 25 · 2026-05-15T14:56:09.347Z_

<details><summary>↩ Tool result · reported error · `toolu_019hz2YdgxHEGLTLGAwfWs6w`</summary>

```text
File content (80511 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "56cb5c24-561f-4b97-b068-16eda379efb9",
  "tool_use_result": "Error: File content (80511 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---


### Tool call

_source line 26_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01L9xQknyho6LpzxcYFAbsHG`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/conclusion.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "6ebfa4dd-8ada-4ec9-a2cf-5418e8bf3a51",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 27_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01NbgFozFf5sLpNrhNzvfKqw`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/limitations.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "ba7d65be-b83f-496b-a9a1-71af31bb869a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 28_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_012ySpG2qZzCGuTRy1UyJDwA`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/related_work.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "7567b0f3-edc9-4bc4-a4ab-e10a92c6544d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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

_source line 29_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01M81UkiJjQW9CZCHcbzuDQw`</summary>

```json
{
  "server": "westd-39279",
  "command": "cat /root/solver-trace-ablation/paper/appendix.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "231b3575-1f32-411c-a72c-132ac7c98b15",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Koq1Ea37ev6eskLqeVypyD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14255,
      "cache_read_input_tokens": 27538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14255
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


### System

_source line 30_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Reading ~/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt",
  "usage": {
    "total_tokens": 15702,
    "tool_uses": 2,
    "duration_ms": 7137
  },
  "last_tool_name": "Read",
  "uuid": "fd3ecd5a-05d0-40c6-b3d1-845a67c7c393",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Read · `toolu_0188hWwFSFCXZwMB8EoiHcjx`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt",
  "limit": 50
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "bd3d4b54-2448-43f1-9399-bec2900fb282",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013wdSk2drv4SmKaC53TBaXG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1062,
      "cache_read_input_tokens": 14564,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1062,
        "ephemeral_1h_input_tokens": 0
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

_source line 32 · 2026-05-15T14:56:13.088Z_

<details><summary>↩ Tool result · reported error · `toolu_0188hWwFSFCXZwMB8EoiHcjx`</summary>

```text
File content (80511 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "d30bf390-403f-4d13-9a72-f0dd678c90aa",
  "tool_use_result": "Error: File content (80511 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---


### System

_source line 33_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Check line count of registry file",
  "usage": {
    "total_tokens": 16007,
    "tool_uses": 3,
    "duration_ms": 10573
  },
  "last_tool_name": "Bash",
  "uuid": "937daec3-f235-44ee-b747-2f5f94de8e72",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 34_

<details open><summary>🔧 Tool call — Bash · `toolu_019wvvoEdxhKou5quMRpeMPk`</summary>

```json
{
  "command": "wc -l /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt",
  "description": "Check line count of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "5013b978-3059-4e57-b97f-1c87753dcd5a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HMdiF3FYMxABkpkYkNtPYe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 235,
      "cache_read_input_tokens": 15626,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 235,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 70,
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

_source line 35 · 2026-05-15T14:56:16.521Z_

<details><summary>↩ Tool result · `toolu_019wvvoEdxhKou5quMRpeMPk`</summary>

```text
0 /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "9dbd74b7-cac9-4522-8e73-8cb457872b79"
}
```

</details>

---


### System

_source line 36_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Parse registry JSON structure",
  "usage": {
    "total_tokens": 16282,
    "tool_uses": 4,
    "duration_ms": 17392
  },
  "last_tool_name": "Bash",
  "uuid": "434bef80-428c-44a2-b6eb-afc5981001d4",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Bash · `toolu_01C5RyHTpagTykrvaQP6QNhC`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\n# The outer schema is {result: string} where result is a JSON string\ninner = json.loads(raw['result'])\n\n# Show top-level keys\nprint(\"Top-level keys:\", list(inner.keys()))\nprint(\"Type of inner:\", type(inner))\nif isinstance(inner, dict):\n    for k, v in inner.items():\n        if isinstance(v, list):\n            print(f\"  {k}: list of {len(v)} items\")\n        elif isinstance(v, dict):\n            print(f\"  {k}: dict with keys {list(v.keys())[:10]}\")\n        else:\n            print(f\"  {k}: {type(v).__name__} = {str(v)[:200]}\")\nPYEOF",
  "description": "Parse registry JSON structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "17dd6da8-c96e-4732-9442-2c11388278a7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01P5xXbYfgkQ7BN7qqG1dXc8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 273,
      "cache_read_input_tokens": 15861,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 273,
        "ephemeral_1h_input_tokens": 0
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

_source line 38 · 2026-05-15T14:56:23.182Z_

<details><summary>↩ Tool result · `toolu_01C5RyHTpagTykrvaQP6QNhC`</summary>

```text
Top-level keys: ['success', 'data', 'error', 'metadata']
Type of inner: &lt;class 'dict'>
  success: bool = True
  data: dict with keys ['experiments', 'count', 'total', 'baseline']
  error: NoneType = None
  metadata: dict with keys ['elapsed_seconds']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "b9d38e13-c5af-4682-8139-81cea1b48fe9"
}
```

</details>

---


### System

_source line 39_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running List all experiments with status and conclusion",
  "usage": {
    "total_tokens": 16846,
    "tool_uses": 5,
    "duration_ms": 23534
  },
  "last_tool_name": "Bash",
  "uuid": "afdeb8ee-73dd-4eda-a3f1-b30c7586ccec",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Bash · `toolu_01Rxcfx7RkWdDL6YvDZ9fM86`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\ndata = inner['data']\nexperiments = data['experiments']\n\nprint(f\"Total experiments: {data['total']}, Returned: {data['count']}\")\nprint(f\"Baseline: {json.dumps(data.get('baseline'), indent=2)[:500]}\")\nprint()\n\n# List all experiments with their status and conclusion\nfor exp in experiments:\n    exp_id = exp.get('exp_id', 'N/A')\n    status = exp.get('status', 'N/A')\n    conclusion = exp.get('conclusion', 'N/A')\n    print(f\"  {exp_id:50s} status={status:10s} conclusion={conclusion}\")\nPYEOF",
  "description": "List all experiments with status and conclusion"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "051daf7d-0a3e-433e-a6f0-10f26daef0e9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017K7sWAN6mVuVRuXKJ8nx5n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 491,
      "cache_read_input_tokens": 16134,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 491,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 73,
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

_source line 41 · 2026-05-15T14:56:29.456Z_

<details><summary>↩ Tool result · reported error · `toolu_01Rxcfx7RkWdDL6YvDZ9fM86`</summary>

```text
Exit code 1
Total experiments: 86, Returned: 86
Baseline: null

Traceback (most recent call last):
  File "&lt;stdin>", line 18, in &lt;module>
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "ddcb5657-1c1b-486a-92b7-6baee73b9ac5",
  "tool_use_result": "Error: Exit code 1\nTotal experiments: 86, Returned: 86\nBaseline: null\n\nTraceback (most recent call last):\n  File \"&lt;stdin>\", line 18, in &lt;module>\nAttributeError: 'str' object has no attribute 'get'"
}
```

</details>

---


### System

_source line 42_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Inspect experiments data structure",
  "usage": {
    "total_tokens": 17384,
    "tool_uses": 6,
    "duration_ms": 30735
  },
  "last_tool_name": "Bash",
  "uuid": "1ee861ae-0508-4a77-9304-6faca2021059",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 43_

<details open><summary>🔧 Tool call — Bash · `toolu_01MPuWvEzcUf2vXvmwiatNUS`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\ndata = inner['data']\nexperiments = data['experiments']\n\n# Check the type and structure of experiments\nprint(f\"Type of experiments: {type(experiments)}\")\nif isinstance(experiments, list):\n    print(f\"Length: {len(experiments)}\")\n    print(f\"Type of first element: {type(experiments[0])}\")\n    # If elements are strings, they might need another parse\n    if isinstance(experiments[0], str):\n        print(f\"First element (first 500 chars): {experiments[0][:500]}\")\n        try:\n            parsed = json.loads(experiments[0])\n            print(f\"Parsed first element keys: {list(parsed.keys())}\")\n        except:\n            print(\"Not JSON parseable\")\n    elif isinstance(experiments[0], dict):\n        print(f\"First element keys: {list(experiments[0].keys())}\")\n        print(json.dumps(experiments[0], indent=2)[:1000])\nelif isinstance(experiments, dict):\n    print(f\"Keys: {list(experiments.keys())[:20]}\")\nPYEOF",
  "description": "Inspect experiments data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "2b5e1dd5-59da-4890-a0d9-d048f2a11f81",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195MCE8MLvucamkrTUtKoNB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 466,
      "cache_read_input_tokens": 16625,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 466,
        "ephemeral_1h_input_tokens": 0
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

_source line 44 · 2026-05-15T14:56:36.526Z_

<details><summary>↩ Tool result · `toolu_01MPuWvEzcUf2vXvmwiatNUS`</summary>

```text
Type of experiments: &lt;class 'dict'>
Keys: ['plan002-additive-b01-s44', 'plan002-additive-b01-s42', 'plan002-additive-b01-s42-1000', 'plan002-additive-b01-s43', 'plan002-additive-b01-s43-r2', 'plan018-additive-random-b01-s42', 'plan018-additive-random-b01-s44-r2', 'plan018-additive-random-b01-s43-r3', 'exp1-isr-b03-s43', 'plan009-sft-baseline-s44-1000-r3', 'plan009-sft-baseline-s44-1000', 'plan009-sft-baseline-s43-1000', 'plan009-sft-baseline-s44', 'plan009-sft-baseline-s43', 'plan001-exec-only-s44-1000-r2', 'plan001-exec-only-s43-1000-r2', 'plan001-exec-only-s44-1000', 'plan001-exec-only-s43-1000', 'plan018-additive-random-b01-s42-1000-r3', 'plan009-sft-baseline-s44-1000-r2']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "c7f1b167-005f-4815-9d20-4f60af52efd8"
}
```

</details>

---


### System

_source line 45_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Inspect individual experiment entry structure",
  "usage": {
    "total_tokens": 18282,
    "tool_uses": 7,
    "duration_ms": 36517
  },
  "last_tool_name": "Bash",
  "uuid": "01a126b3-d435-439a-a98b-7a89fa34322a",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 46_

<details open><summary>🔧 Tool call — Bash · `toolu_013tFJJcKAG4mcfpKJjd49zy`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# Each value might be a string that needs parsing\nfirst_key = list(experiments.keys())[0]\nfirst_val = experiments[first_key]\nprint(f\"Type of value: {type(first_val)}\")\nif isinstance(first_val, str):\n    print(f\"First 1000 chars: {first_val[:1000]}\")\n    try:\n        parsed = json.loads(first_val)\n        print(f\"Parsed keys: {list(parsed.keys())}\")\n    except:\n        print(\"Not parseable as JSON\")\nelif isinstance(first_val, dict):\n    print(json.dumps(first_val, indent=2)[:2000])\nPYEOF",
  "description": "Inspect individual experiment entry structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "62497632-a39e-410c-a11b-7cdc70bf1ac2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ENRXTustbiRj2nFQc1VsyF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 826,
      "cache_read_input_tokens": 17091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 826,
        "ephemeral_1h_input_tokens": 0
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

_source line 47 · 2026-05-15T14:56:42.307Z_

<details><summary>↩ Tool result · `toolu_013tFJJcKAG4mcfpKJjd49zy`</summary>

```text
Type of value: &lt;class 'dict'>
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-14T08:36:17.298Z",
  "updated_at": "2026-05-15T14:39:36.660Z",
  "hypothesis": "ISR \u03b2=0.1 seed=44 \u591a seed \u9a8c\u8bc1\uff1aexec-only s44 \u662f tautological collapse (PR=98%, ISR=0.57 fake)\uff0cISR \u03b2=0.1 \u80fd\u5426\u9632\u6b62 tautological collapse\uff1f3-seed mean\u00b1std \u7528\u4e8e\u8bba\u6587 Claim 2\u3002",
  "parent": "plan002-additive-b01-s42",
  "server": "westd-39279",
  "gpu": "cuda:1",
  "account": "root",
  "reproduce": {
    "server": "westd-39279",
    "gpu": "cuda:1",
    "started_at": "2026-05-14T08:45:11.826Z",
    "command": "bash -c \"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s44\"",
    "finished_at": "2026-05-14T09:28:10.836Z",
    "training_hours": 0.72
  },
  "spec": {
    "command": "python3 scripts/train_grpo.py --mode additive_bonus --isr_beta 0.1 --seed 44",
    "server": "westd-39279",
    "gpu": [
      "cuda:1"
    ],
    "pid": "466540",
    "log_path": "~/runs/solver-trace-ablation/plan002-additive-b01-s44.log",
    "submitted_at": "2026-05-14T08:46:23.037Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "data/train_500_seed42.jsonl",
    "data_count": 500,
    "model_name": "Qwen3-4B",
    "seed": 44,
    "wall_clock_seconds": 2950.3,
    "gpu_hours": 0.82
  },
  "pid": "466540",
  "log_path": "~/runs/solver-trace-ablation/plan002-additive-b01-s44.log",
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-14T09:28:12.416418+00:00"
      }
    ]
  },
  "metrics": {
    "eval_prove_rate": 0.8
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "8815db88-5160-42c2-8ec0-36d7021b2af4"
}
```

</details>

---


### System

_source line 48_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running List all experiments overview",
  "usage": {
    "total_tokens": 19605,
    "tool_uses": 8,
    "duration_ms": 42503
  },
  "last_tool_name": "Bash",
  "uuid": "c1f9b211-c5e4-4914-bfd7-bf7191577df9",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 49_

<details open><summary>🔧 Tool call — Bash · `toolu_01U9eMpjqx5tLtTbFmezP8xv`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# First, list ALL experiments with status and conclusion\nprint(\"=\" * 120)\nprint(\"ALL EXPERIMENTS OVERVIEW\")\nprint(\"=\" * 120)\nfor exp_id, exp in sorted(experiments.items()):\n    status = exp.get('status', 'N/A')\n    conclusion = exp.get('conclusion', 'N/A')\n    has_metrics = 'metrics' in exp and exp['metrics']\n    print(f\"  {exp_id:55s} status={status:12s} conclusion={str(conclusion):12s} has_metrics={has_metrics}\")\n\nprint(f\"\\nTotal: {len(experiments)} experiments\")\nPYEOF",
  "description": "List all experiments overview"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "02a02a6f-93dd-465a-80c4-3116407dde37",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PfGabGF2WJt4c8xGkWacAW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1307,
      "cache_read_input_tokens": 17917,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1307,
        "ephemeral_1h_input_tokens": 0
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

_source line 50 · 2026-05-15T14:56:48.284Z_

<details><summary>↩ Tool result · `toolu_01U9eMpjqx5tLtTbFmezP8xv`</summary>

```text
&lt;persisted-output>
Output too large (37.6KB). Full output saved to: /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/bypykm503.txt

Preview (first 2KB):
========================================================================================================================
ALL EXPERIMENTS OVERVIEW
========================================================================================================================
  exp1-isr-b03-s42-1000                                   status=DONE         conclusion=failed       has_metrics=False
  exp1-isr-b03-s42-1000-r2                                status=DONE         conclusion=negative     has_metrics={'eval_prove_rate': 0.95, 'eval_mean_isr': 0.734, 'eval_isr_std': 0.2575, 'eval_median_isr': 0.6, 'eval_proved_only_isr': 0.7726, 'eval_n_proved': 95, 'eval_n_problems': 100, 'eval_data': 'proofwriter_fol_100.jsonl', 'eval_by_answer_type': {'false': {'count': 25, 'proved': 25, 'prove_rate': 1, 'mean_isr': 0.824}, 'unknown': {'count': 41, 'proved': 38, 'prove_rate': 0.927, 'mean_isr': 0.673}, 'true': {'count': 34, 'proved': 32, 'prove_rate': 0.941, 'mean_isr': 0.741}}, 'h7_count': 0, 'h7_rate': 0, 'h1_count': 54, 'h1_rate': 0.568, 'genuine_count': 0, 'genuine_rate': 0, 'tautological_collapse': True, 'isr_1_count': 41, 'isr_1_rate': 0.432, 'single_premise_count': 0, 'train_final_prove_rate': 0.829, 'train_final_mean_isr': 0.727, 'train_loss': 0.0041, 'train_runtime_seconds': 6280, 'train_final_entropy': 9e-06, 'completions_mean_length': 47, 'h8_conjunction_collapse_count': 41, 'h8_conjunction_collapse_rate': 0.432, 'content_independent_predicates': True}
  exp1-isr-b03-s43                                        status=DONE         conclusion=success      has_metrics={'parse_rate': 1, 'prove_rate': 0.91, 'mean_isr': 0.2575, 'isr_std': 0.2363, 'median_isr': 0.3333, 'proved_only_mean_isr': 0.283, 'hacking_rate_strict_h7': 0.022, 'hacking_rate_functional': 0.3297, 'genuine_rate': 0.6703, 'genuine_count': 61, 'n_proved': 91, 'n_problems': 100, 'h1_conclusion_in_premise': 0.747, 'eval_data': 'test_100.jsonl', 'eval_output': '/root/autodl-tmp/outputs/eval_sta_exp1_isr_b03_s43.json'}
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "beecd2d5-4d25-4d24-9192-41b0789c9f65"
}
```

</details>

---


### System

_source line 51_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Extract detailed metrics for all target experiments",
  "usage": {
    "total_tokens": 20991,
    "tool_uses": 9,
    "duration_ms": 56800
  },
  "last_tool_name": "Bash",
  "uuid": "fdaa1516-7efb-415a-9734-9ef67963ef96",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 52_

<details open><summary>🔧 Tool call — Bash · `toolu_015aeQFn9sMAxhXazWyRKNoe`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# Target experiment IDs grouped\ntargets = {\n    \"SFT Baselines\": [\n        \"plan009-sft-baseline-s42-1000\",\n        \"plan009-sft-baseline-s43-1000\",\n        \"plan009-sft-baseline-s44-1000-r3\",\n    ],\n    \"Exec-only s42 1000 steps (plan016)\": [\n        \"plan016-exec-only-s42-1000\",\n    ],\n    \"ISR beta=0.3 all seeds\": [\n        \"exp1-isr-b03-s42\",\n        \"exp1-isr-b03-s43\",\n        \"exp1-isr-b03-s44\",\n    ],\n    \"ISR beta=0.1 s42\": [\n        \"plan002-additive-b01-s42\",\n    ],\n    \"Random beta=0.1 all seeds\": [\n        \"plan018-additive-random-b01-s42\",\n        \"plan018-additive-random-b01-s43-r3\",\n        \"plan018-additive-random-b01-s44-r2\",\n    ],\n    \"Random beta=0.3 all seeds\": [\n        \"exp1-random-b03-s42\",\n        \"exp1-random-b03-s43\",\n        \"exp1-random-b03-s44\",\n    ],\n    \"Prolog exec all seeds\": [\n        \"plan006-prolog-exec-s42\",\n        \"plan006-prolog-exec-s43\",\n        \"plan006-prolog-exec-s44\",\n    ],\n}\n\n# Also grab any bootstrap CI experiments\nbootstrap_keys = [k for k in experiments.keys() if 'bootstrap' in k.lower() or 'ci' in k.lower()]\nif bootstrap_keys:\n    targets[\"Bootstrap CI\"] = bootstrap_keys\n\n# Print detailed info for each target\nfor group_name, exp_ids in targets.items():\n    print(\"\\n\" + \"=\" * 120)\n    print(f\"GROUP: {group_name}\")\n    print(\"=\" * 120)\n    for exp_id in exp_ids:\n        if exp_id in experiments:\n            exp = experiments[exp_id]\n            print(f\"\\n--- {exp_id} ---\")\n            print(f\"  status:     {exp.get('status', 'N/A')}\")\n            print(f\"  conclusion: {exp.get('conclusion', 'N/A')}\")\n            print(f\"  tags:       {exp.get('tags', 'N/A')}\")\n            print(f\"  notes:      {exp.get('notes', 'N/A')}\")\n            metrics = exp.get('metrics', {})\n            if metrics:\n                print(f\"  metrics:\")\n                for mk, mv in sorted(metrics.items()):\n                    print(f\"    {mk}: {json.dumps(mv)}\")\n            else:\n                print(f\"  metrics: (none)\")\n        else:\n            print(f\"\\n--- {exp_id} --- NOT FOUND in registry\")\n            # Try fuzzy match\n            close = [k for k in experiments.keys() if exp_id.rstrip('-r2-r3').split('-1000')[0] in k]\n            if close:\n                print(f\"    Similar keys: {close}\")\n\nPYEOF",
  "description": "Extract detailed metrics for all target experiments",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "138c1672-708d-478d-8d40-14152fba0f0f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U1ZZb1hnYLEnKPo7LdBTGk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1314,
      "cache_read_input_tokens": 19224,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1314,
        "ephemeral_1h_input_tokens": 0
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

_source line 53 · 2026-05-15T14:57:02.583Z_

<details><summary>↩ Tool result · `toolu_015aeQFn9sMAxhXazWyRKNoe`</summary>

```text
========================================================================================================================
GROUP: SFT Baselines
========================================================================================================================

--- plan009-sft-baseline-s42-1000 ---
  status:     DONE
  conclusion: success
  tags:       N/A
  notes:      SFT 1000步 (15.88 epochs): train loss 降至 0.0168（严重过拟合），但 eval genuine_rate=92.31% 与 500步的 92.9% 基本持平。prove_rate 从 0.14 微降至 0.13，h7=0，h1=1。结论：SFT 即使过拟合也不产生 Goodhart collapse（h7/h8=0），验证了 Goodhart 是 RL(GRPO) reward optimization 特有现象。Unknown 类全部 0/41 未 prove（与 500步一致），SFT 不具备泛化到 unknown 类的能力。
  metrics:
    conclusion_in_premise_count: 1
    conclusion_in_premise_rate: 0.0769
    content_independent_count: 0
    eval_by_answer_type: {"true": {"count": 34, "proved": 12, "prove_rate": 0.353, "mean_isr": 0.209}, "false": {"count": 25, "proved": 1, "prove_rate": 0.04, "mean_isr": 0.011}, "unknown": {"count": 41, "proved": 0, "prove_rate": 0, "mean_isr": 0}}
    eval_data: "proofwriter_fol_100.jsonl"
    eval_isr_std: 0.2077
    eval_mean_isr: 0.0738
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_n_problems: 100
    eval_n_proved: 13
    eval_output_path: "/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/eval_sta_results.json"
    eval_prove_rate: 0.13
    eval_proved_only_isr: 0.5677
    genuine_count: 12
    genuine_rate: 0.9231
    h1_strict_count: 1
    h1_strict_rate: 0.0769
    h7_strict_count: 0
    h7_strict_rate: 0
    h8_conjunction_collapse_count: 0
    h8_conjunction_collapse_rate: 0
    isr_1_count: 0
    train_epochs: 15.88
    train_final_loss: 0.0168
    train_last_step_loss: 0.0168
    train_runtime_sec: 1415
    train_steps: 1000
    train_token_accuracy: 0.9955

--- plan009-sft-baseline-s43-1000 ---
  status:     DONE
  conclusion: success
  tags:       N/A
  notes:      SFT s43 1000步结果与 s42 高度一致：prove_rate 11% vs 13%（-2pp），mean_isr 0.0699 vs 0.0738，final_loss 0.0167 vs 0.0168。差异在 seed 方差范围内。SFT baseline 稳定。注意：eval_sta.py 当前版本不输出 h7/h1/h8/genuine 分类指标。
  metrics:
    by_answer_type: {"true": {"count": 34, "proved": 11, "prove_rate": 0.3235}, "false": {"count": 25, "proved": 0, "prove_rate": 0}, "unknown": {"count": 41, "proved": 0, "prove_rate": 0}}
    conclusion_in_premise_count: 1
    conclusion_in_premise_rate: 0.0909
    content_independent_count: 0
    content_independent_rate: 0
    eval_elapsed_s: 326.1
    genuine_count: 10
    genuine_rate: 0.9091
    h1_strict_count: 1
    h1_strict_rate: 0.0909
    h7_strict_count: 0
    h7_strict_rate: 0
    h8_conjunction_collapse_count: 0
    h8_conjunction_collapse_rate: 0
    isr_1_count: 1
    isr_1_rate: 0.0909
    isr_std: 0.2155
    mean_isr: 0.0699
    median_isr: 0
    n_problems: 100
    n_proved: 11
    prove_rate: 0.11
    proved_only_mean_isr: 0.6352
    train_avg_loss: 0.1551
    train_final_loss: 0.0167
    train_runtime_s: 1584.79
    train_token_accuracy: 0.9954

--- plan009-sft-baseline-s44-1000-r3 ---
  status:     DONE
  conclusion: success
  tags:       N/A
  notes:      N/A
  metrics:
    eval_by_answer_type: {"true": {"count": 34, "proved": 15, "prove_rate": 0.441, "mean_isr": 0.26}, "false": {"count": 25, "proved": 0, "prove_rate": 0, "mean_isr": 0}, "unknown": {"count": 41, "proved": 0, "prove_rate": 0, "mean_isr": 0}}
    eval_data: "proofwriter_fol_100.jsonl"
    eval_isr_std: 0.2268
    eval_mean_isr: 0.0884
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_n_problems: 100
    eval_n_proved: 15
    eval_prove_rate: 0.15
    eval_proved_only_isr: 0.5892
    genuine_count: 14
    genuine_rate: 0.9333
    h1_count: 1
    h1_rate: 0.0667
    h7_count: 0
    h7_rate: 0
    h8_conjunction_collapse_count: 0
    h8_conjunction_collapse_rate: 0

========================================================================================================================
GROUP: Exec-only s42 1000 steps (plan016)
========================================================================================================================

--- plan016-exec-only-s42-1000 --- NOT FOUND in registry

========================================================================================================================
GROUP: ISR beta=0.3 all seeds
========================================================================================================================

--- exp1-isr-b03-s42 --- NOT FOUND in registry
    Similar keys: ['exp1-isr-b03-s43', 'exp1-isr-b03-s42-1000-r2', 'exp1-isr-b03-s42-1000', 'exp1-isr-b03-s43-r3', 'exp1-isr-b03-s43-r4', 'exp1-isr-b03-s44-r2', 'exp1-isr-b03-s44', 'exp1-isr-b03-s43-r2']

--- exp1-isr-b03-s43 ---
  status:     DONE
  conclusion: success
  tags:       N/A
  notes:      D062/D063 INVALIDATED: eval used test_100.jsonl (wrong test set). Checkpoint deleted, cannot re-eval. Retrain as exp1-isr-b03-s43-r4.
  metrics:
    eval_data: "test_100.jsonl"
    eval_output: "/root/autodl-tmp/outputs/eval_sta_exp1_isr_b03_s43.json"
    genuine_count: 61
    genuine_rate: 0.6703
    h1_conclusion_in_premise: 0.747
    hacking_rate_functional: 0.3297
    hacking_rate_strict_h7: 0.022
    isr_std: 0.2363
    mean_isr: 0.2575
    median_isr: 0.3333
    n_problems: 100
    n_proved: 91
    parse_rate: 1
    prove_rate: 0.91
    proved_only_mean_isr: 0.283

--- exp1-isr-b03-s44 ---
  status:     DONE
  conclusion: failed
  tags:       N/A
  notes:      OOM on first submission: GPU 0 was occupied by orphan PID 5480 (exp1-isr-b03-s43-r2 training process survived tmux kill). Pending resubmission after GPU 0 cleared.
  metrics: (none)

========================================================================================================================
GROUP: ISR beta=0.1 s42
========================================================================================================================

--- plan002-additive-b01-s42 ---
  status:     DONE
  conclusion: negative
  tags:       N/A
  notes:      H8 re-audit (2026-05-15): 81 proved samples. H7 (single premise=conclusion): 13/81=16.1%, H1 (multi-prem conclusion embedding): 42/81=51.9%, H8 (conjunction collapse): 12/81=14.8%, content-independent: 19/81=23.5%. Genuine (proved - H7 - H1 - H8): 14/81=17.3%. Pre-H8 genuine was 26/81=32.1% — H8 removed 12 samples. Combined conclusion duplication+conjunction = 82.7%. Eval source: proofwriter_fol_100.jsonl (backup at /root/autodl-tmp/eval_results_backup/). H8 JSON: /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json. ⚠️ RECLASSIFIED negative (Reviewer WARNING): 500步快照 genuine 30.9%（H8 未扣除，为上界），1000步崩塌至 2.2%，表明 Goodhart collapse 已在 500 步启动但未完成。
  metrics:
    eval_component_count_mean: 5.58
    eval_data: "proofwriter_fol_100.jsonl"
    eval_isr_std: 0.3227
    eval_mean_isr: 0.3365
    eval_median_isr: 0.2
    eval_method: "eval_sta.py full STA"
    eval_n_problems: 100
    eval_n_proved: 81
    eval_prove_rate: 0.81
    eval_proved_only_isr: 0.4154
    genuine_count: 14
    genuine_rate: 0.173
    h1_count: 42
    h1_rate: 0.519
    h7_count: 13
    h7_rate: 0.16
    h8_audit_note: "2026-05-15: H8 conjunction collapse audit completed. 12/81 proved samples are H8. Genuine 26\u219214 (32.1%\u219217.3%). H8 JSON at /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json"
    h8_conjunction_collapse_count: 12
    h8_conjunction_collapse_rate: 0.148
    tautological_collapse: false

========================================================================================================================
GROUP: Random beta=0.1 all seeds
========================================================================================================================

--- plan018-additive-random-b01-s42 ---
  status:     DONE
  conclusion: negative
  tags:       N/A
  notes:      Random control β=0.1 vs ISR β=0.1 (plan002-b01) 对照。conclusion=negative: random control的ISR远低于ISR-guided。

对比 plan002-b01 (ISR β=0.1):
- PR: 0.79 vs 0.81 (≈持平, Δ=0.02)
- Mean ISR: 0.104 vs 0.337 (ISR 3.2x higher)
- Proved-only ISR: 0.131 vs 0.415 (ISR 3.2x higher)
- Median ISR: 0.036 vs plan002未记录
- Component count: 8.46 vs 5.58 (random组更多冗余)
- ISR=0占比(proved): 36.7% (random组大量proof无结构)
- Tautological collapse: 无 (component_2_ratio=0)

关键发现: PR几乎相同说明β=0.1 random噪声不影响证明能力。但ISR差3.2倍，证明ISR reward提供genuine structural guidance而非仅variance regularization。这强力支持Claim 2: ISR信号在低剂量下有结构价值。

Eval output: /root/autodl-tmp/outputs/plan018_additive_random_b01_s42/eval_results.json
  metrics:
    eval_isr_std: 0.1369
    eval_mean_isr: 0.1038
    eval_median_isr: 0.0357
    eval_n_problems: 100
    eval_n_proved: 79
    eval_prove_rate: 0.79
    eval_proved_only_isr: 0.1314
    genuine_count_exact_h1: 23
    genuine_count_strict: 12
    genuine_rate_exact_h1: 0.2911
    genuine_rate_strict: 0.1519
    h1_count: 56
    h1_near_count: 8
    h1_near_rate: 0.1013
    h1_rate: 0.7089
    h7_count: 0
    h7_rate: 0
    h8_conjunction_collapse_count: 3
    h8_conjunction_collapse_rate: 0.038
    tautological_collapse: false
    taxonomy_verification: "2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12)."

--- plan018-additive-random-b01-s43-r3 ---
  status:     PREPARING
  conclusion: N/A
  tags:       N/A
  notes:      N/A
  metrics: (none)

--- plan018-additive-random-b01-s44-r2 ---
  status:     PREPARING
  conclusion: N/A
  tags:       N/A
  notes:      N/A
  metrics: (none)

========================================================================================================================
GROUP: Random beta=0.3 all seeds
========================================================================================================================

--- exp1-random-b03-s42 --- NOT FOUND in registry
    Similar keys: ['exp1-random-b03-s43-r4', 'exp1-random-b03-s44-r2', 'exp1-random-b03-s43-r3', 'exp1-random-b03-s43-r2', 'exp1-random-b03-s43', 'exp1-random-b03-s44']

--- exp1-random-b03-s43 ---
  status:     DONE
  conclusion: success
  tags:       N/A
  notes:      D062/D063 INVALIDATED: eval used test_100.jsonl (wrong test set). Checkpoint deleted, cannot re-eval. Retrain as exp1-random-b03-s43-r2.
  metrics:
    eval_data: "test_100.jsonl"
    eval_output: "/root/autodl-tmp/outputs/eval_sta_exp1_random_b03_s43.json"
    genuine_count: 71
    genuine_rate: 0.8987
    h1_conclusion_in_premise: 0.759
    hacking_rate_functional: 0.1013
    hacking_rate_strict_h7: 0
    isr_std: 0.1628
    mean_isr: 0.1745
    median_isr: 0.1667
    n_problems: 100
    n_proved: 79
    parse_rate: 1
    prove_rate: 0.79
    proved_only_mean_isr: 0.2209

--- exp1-random-b03-s44 ---
  status:     DONE
  conclusion: failed
  tags:       N/A
  notes:      N/A
  metrics: (none)

========================================================================================================================
GROUP: Prolog exec all seeds
========================================================================================================================

--- plan006-prolog-exec-s42 ---
  status:     DONE
  conclusion: negative
  tags:       N/A
  notes:      Eval (eval_sta.py) 完成。PR=83%, mean_ISR=0.031, proved_only_ISR=0.037, H7=0%, H1=0%。与 sta-s42 (PR=50%, ISR=1.0, H7=100%) 形成鲜明对比。exec-only 产生完全不同的 hacking 模式：ground fact enumeration（倾泻大量无关 ground facts，query 作为其中一个 fact 平凡成功），而非 sta-s42 的 tautological collapse。两种 reward signal 驱动两种不同的 hacking 策略。对论文是 positive finding：强化 Claim 1 且揭示 reward-specific hacking 机制。
  metrics:
    by_answer_type: {"true": {"proved": 37, "count": 40, "pr": 0.925, "isr": 0.037}, "false": {"proved": 21, "count": 29, "pr": 0.724, "isr": 0.038}, "unknown": {"proved": 25, "count": 31, "pr": 0.806, "isr": 0.016}}
    eval_isr_std: 0.0534
    eval_max_isr: 0.2
    eval_mean_isr: 0.031
    eval_median_isr: 0
    eval_prove_rate: 0.83
    eval_proved_only_isr: 0.037
    h1_rate: 0
    h7_rate: 0
    isr_1_rate: 0
    single_premise_rate: 0

--- plan006-prolog-exec-s43 ---
  status:     DONE
  conclusion: killed
  tags:       N/A
  notes:      KILLED at step 36/500: warmup_ratio=0.1 与 s42 (0.0) 不一致，3-seed 对比无效。重启为 plan006-prolog-exec-s43-r2 (warmup_ratio=0.0)。
  metrics: (none)

--- plan006-prolog-exec-s44 ---
  status:     DONE
  conclusion: negative
  tags:       N/A
  notes:      Eval 完成。PR=21% (3-seed 最低), ISR=0.081, proved_only_ISR=0.387 (max_ISR=1.0)。与 s42/s43 不同模式：PR 极低但 proved_only_ISR 较高，可能有少量样本 ISR=1 (H7-like)。Prolog exec-only 3-seed 汇总：s42 PR=83%/ISR=0.031, s43 PR=56%/ISR=0.008, s44 PR=21%/ISR=0.081。Mean PR=53.3%±31.1%, Mean ISR=0.040±0.037。跨 seed 极不稳定（PR std=31pp），与 FOL exec-only 一致。ISR 始终极低（<0.1），确认 Prolog exec-only 不产生 genuine reasoning traces。
  metrics:
    eval_by_type_false_isr: 0.04
    eval_by_type_false_pr: 0.04
    eval_by_type_true_isr: 0.09
    eval_by_type_true_pr: 0.206
    eval_by_type_unknown_isr: 0.099
    eval_by_type_unknown_pr: 0.317
    eval_data: "proofwriter_fol_100.jsonl"
    eval_elapsed_seconds: 683.9
    eval_isr_std: 0.2343
    eval_max_isr: 1
    eval_mean_isr: 0.0812
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_min_isr: 0
    eval_n_problems: 100
    eval_n_proved: 21
    eval_prove_rate: 0.21
    eval_proved_only_isr: 0.3866
    logic_type: "prolog"
    solver: "PrologSolver"
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "0f73a085-4032-4f0a-ba87-313f1f46bab2"
}
```

</details>

---


### System

_source line 54_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Extract additional/alternative experiments",
  "usage": {
    "total_tokens": 27547,
    "tool_uses": 10,
    "duration_ms": 76676
  },
  "last_tool_name": "Bash",
  "uuid": "529a8f02-3c1c-4f96-8c1d-086c05d176d4",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 55_

<details open><summary>🔧 Tool call — Bash · `toolu_01DbbvvhHvJS7gSeGzZnLNEY`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# Get missing/alternative experiments\nextra_targets = [\n    # plan016 variants\n    \"plan016-exec-only-s42-1000\",\n    \"plan016-exec-only-s42\",\n    # exp1-isr-b03-s42 variants\n    \"exp1-isr-b03-s42\",\n    \"exp1-isr-b03-s42-1000\",\n    \"exp1-isr-b03-s42-1000-r2\",\n    # exp1-isr-b03-s44 retries\n    \"exp1-isr-b03-s44-r2\",\n    # exp1-isr-b03-s43 retries (since original invalidated)\n    \"exp1-isr-b03-s43-r3\",\n    \"exp1-isr-b03-s43-r4\",\n    # exp1-random-b03-s42 variants\n    \"exp1-random-b03-s42\",\n    # exp1-random-b03-s43 retries\n    \"exp1-random-b03-s43-r2\",\n    \"exp1-random-b03-s43-r3\",\n    \"exp1-random-b03-s43-r4\",\n    # exp1-random-b03-s44 retries\n    \"exp1-random-b03-s44-r2\",\n    # plan002-additive-b01 other seeds\n    \"plan002-additive-b01-s43\",\n    \"plan002-additive-b01-s43-r2\",\n    \"plan002-additive-b01-s44\",\n    \"plan002-additive-b01-s42-1000\",\n    # plan006 prolog retries\n    \"plan006-prolog-exec-s43-r2\",\n    # plan001 exec-only\n    \"plan001-exec-only-s42-1000\",\n    \"plan001-exec-only-s43-1000\",\n    \"plan001-exec-only-s43-1000-r2\",\n    \"plan001-exec-only-s44-1000\",\n    \"plan001-exec-only-s44-1000-r2\",\n    # Bootstrap\n    \"bootstrap-ci\",\n]\n\n# Also search for any key containing plan016 or bootstrap\nplan016_keys = [k for k in experiments.keys() if 'plan016' in k]\nbootstrap_keys = [k for k in experiments.keys() if 'bootstrap' in k.lower() or 'ci-' in k.lower()]\nexec_only_keys = [k for k in experiments.keys() if 'exec-only' in k or 'exec_only' in k]\n\nprint(\"Keys matching 'plan016':\", plan016_keys)\nprint(\"Keys matching 'bootstrap/ci':\", bootstrap_keys)\nprint(\"Keys matching 'exec-only':\", exec_only_keys)\nprint()\n\n# Now dump all the extra targets that exist\nfor exp_id in extra_targets:\n    if exp_id in experiments:\n        exp = experiments[exp_id]\n        status = exp.get('status', 'N/A')\n        conclusion = exp.get('conclusion', 'N/A')\n        metrics = exp.get('metrics', {})\n        notes = exp.get('notes', 'N/A')\n        \n        if status == 'DONE' or conclusion in ['success', 'negative', 'failed', 'killed']:\n            print(f\"\\n--- {exp_id} ---\")\n            print(f\"  status:     {status}\")\n            print(f\"  conclusion: {conclusion}\")\n            print(f\"  notes:      {str(notes)[:300]}\")\n            if metrics:\n                print(f\"  metrics:\")\n                for mk, mv in sorted(metrics.items()):\n                    print(f\"    {mk}: {json.dumps(mv)}\")\n            else:\n                print(f\"  metrics: (none)\")\n\nPYEOF",
  "description": "Extract additional/alternative experiments",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "c3afe191-f9e9-41df-ad30-8163632af90b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J2p41oDwAh2ery3pGsNJKj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6554,
      "cache_read_input_tokens": 20538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6554,
        "ephemeral_1h_input_tokens": 0
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

_source line 56 · 2026-05-15T14:57:22.453Z_

<details><summary>↩ Tool result · `toolu_01DbbvvhHvJS7gSeGzZnLNEY`</summary>

```text
Keys matching 'plan016': ['plan016-extended-1000-s42']
Keys matching 'bootstrap/ci': []
Keys matching 'exec-only': ['plan001-exec-only-s44-1000-r2', 'plan001-exec-only-s43-1000-r2', 'plan001-exec-only-s44-1000', 'plan001-exec-only-s43-1000', 'plan001-exec-only-s42-r2', 'plan001-exec-only-s44', 'plan001-exec-only-s43-r4', 'plan001-exec-only-s43-r3', 'plan001-exec-only-s43-r2', 'plan001-exec-only-s43', 'plan001-exec-only-s42', 'plan003-eval-exec-only-r5', 'plan001-exec-only-s42-r3', 'sta-phase1-exec-only-r5', 'sta-phase1-exec-only-r4', 'sta-phase1-exec-only-r3', 'sta-phase1-exec-only-r2', 'sta-phase1-exec-only']


--- exp1-isr-b03-s42-1000 ---
  status:     DONE
  conclusion: failed
  notes:      N/A
  metrics: (none)

--- exp1-isr-b03-s42-1000-r2 ---
  status:     DONE
  conclusion: negative
  notes:      N/A
  metrics:
    completions_mean_length: 47
    content_independent_predicates: true
    eval_by_answer_type: {"false": {"count": 25, "proved": 25, "prove_rate": 1, "mean_isr": 0.824}, "unknown": {"count": 41, "proved": 38, "prove_rate": 0.927, "mean_isr": 0.673}, "true": {"count": 34, "proved": 32, "prove_rate": 0.941, "mean_isr": 0.741}}
    eval_data: "proofwriter_fol_100.jsonl"
    eval_isr_std: 0.2575
    eval_mean_isr: 0.734
    eval_median_isr: 0.6
    eval_n_problems: 100
    eval_n_proved: 95
    eval_prove_rate: 0.95
    eval_proved_only_isr: 0.7726
    genuine_count: 0
    genuine_rate: 0
    h1_count: 54
    h1_rate: 0.568
    h7_count: 0
    h7_rate: 0
    h8_conjunction_collapse_count: 41
    h8_conjunction_collapse_rate: 0.432
    isr_1_count: 41
    isr_1_rate: 0.432
    single_premise_count: 0
    tautological_collapse: true
    train_final_entropy: 9e-06
    train_final_mean_isr: 0.727
    train_final_prove_rate: 0.829
    train_loss: 0.0041
    train_runtime_seconds: 6280

--- exp1-isr-b03-s44-r2 ---
  status:     DONE
  conclusion: success
  notes:      D062/D063: eval_metrics used test_100.jsonl (invalidated). metrics field contains re-eval with proofwriter_fol_100.jsonl (valid). eval_invalidated applies only to eval_metrics.
  metrics:
    eval_data: "proofwriter_fol_100.jsonl"
    eval_note: "Re-eval with correct test set (D062). Previous test_100.jsonl results invalidated."
    genuine_count: 0
    genuine_rate: 0
    h1_count: 0
    h1_rate: 0
    h7_count: 95
    h7_rate: 1
    isr_std: 0.172
    mean_isr: 0.705
    n_problems: 100
    n_proved: 95
    prove_rate: 0.95
    proved_only_isr: 0.7421
    single_premise_rate: 1

--- exp1-isr-b03-s43-r3 ---
  status:     DONE
  conclusion: success
  notes:      Training completed 500/500 steps in 69min. Final stats: prove_rate=0.56125, mean_isr=0.1515, parse_rate=1.0. Checkpoint saved at checkpoint-500. EVAL: PR=0.86 (greedy), mean_ISR=0.2535, H7_strict=4/86(4.7%), H1_strict=59/86(68.6%), total_hacking=63/86(73.3%), genuine=23/86(26.7%). Hacking pattern: p
  metrics:
    epoch: 2
    eval_by_answer_type: {"false": {"count": 25, "proved": 23, "prove_rate": 0.92, "mean_isr": 0.334}, "unknown": {"count": 41, "proved": 35, "prove_rate": 0.854, "mean_isr": 0.199}, "true": {"count": 34, "proved": 28, "prove_rate": 0.824, "mean_isr": 0.26}}
    eval_conclusion_in_premise_count: 63
    eval_conclusion_in_premise_rate: 0.733
    eval_data: "proofwriter_fol_100.jsonl"
    eval_genuine_count: 23
    eval_genuine_rate: 0.267
    eval_h1_strict_count: 59
    eval_h1_strict_rate: 0.686
    eval_h7_strict_count: 4
    eval_h7_strict_rate: 0.047
    eval_isr_1_count: 0
    eval_isr_std: 0.2406
    eval_max_isr: 0.75
    eval_mean_isr: 0.2535
    eval_median_isr: 0.3333
    eval_min_isr: 0
    eval_n_problems: 100
    eval_n_proved: 86
    eval_prove_rate: 0.86
    eval_proved_only_mean_isr: 0.2948
    eval_single_premise_count: 5
    eval_single_premise_rate: 0.058
    final_step: 500
    mean_isr: 0.1515
    parse_rate: 1
    prove_rate: 0.56125
    train_loss: 0.0176
    train_runtime_sec: 4153.6

--- exp1-isr-b03-s43-r4 ---
  status:     DONE
  conclusion: killed
  notes:      Duplicate of exp1-isr-b03-s43-r3 (already RUNNING on cuda:0). Created during D068 chaos, confirmed redundant at Loop #10.
  metrics: (none)

--- exp1-random-b03-s43-r2 ---
  status:     DONE
  conclusion: killed
  notes:      N/A
  metrics: (none)

--- exp1-random-b03-s43-r3 ---
  status:     DONE
  conclusion: failed
  notes:      N/A
  metrics: (none)

--- exp1-random-b03-s43-r4 ---
  status:     DONE
  conclusion: success
  notes:      Training 500/500 steps, 1h42m. Final train: prove_rate=0.5505, mean_isr=0.1358, loss=0.01365. EVAL (proofwriter_fol_100.jsonl): PR=0.92, ISR=0.1659, H7=7/92(7.6%), H1=90/92(97.8%), genuine=2/92(2.2%). ANOMALY: massive seed variance vs s44-r2 (PR=0.23, ISR=0, H1=100%, genuine=0%). s43 learned high-PR
  metrics:
    epoch: 2
    eval_by_answer_type: {"false": {"count": 25, "proved": 23, "prove_rate": 0.92, "mean_isr": 0.156}, "unknown": {"count": 41, "proved": 37, "prove_rate": 0.902, "mean_isr": 0.184}, "true": {"count": 34, "proved": 32, "prove_rate": 0.941, "mean_isr": 0.151}}
    eval_data: "proofwriter_fol_100.jsonl"
    eval_genuine_count: 2
    eval_genuine_rate: 0.022
    eval_h1_strict_count: 90
    eval_h1_strict_rate: 0.978
    eval_h7_strict_count: 7
    eval_h7_strict_rate: 0.076
    eval_isr0_count: 6
    eval_isr_std: 0.1147
    eval_max_isr: 0.5
    eval_mean_isr: 0.1659
    eval_median_isr: 0.1429
    eval_min_isr: 0
    eval_n_problems: 100
    eval_n_proved: 92
    eval_prove_rate: 0.92
    eval_proved_only_mean_isr: 0.1803
    final_step: 500
    mean_isr: 0.1358
    parse_rate: 1
    prove_rate: 0.5505
    train_loss: 0.01365
    train_runtime_sec: 6161.1

--- exp1-random-b03-s44-r2 ---
  status:     DONE
  conclusion: success
  notes:      N/A
  metrics:
    eval_data: "proofwriter_fol_100.jsonl"
    eval_genuine_count: 0
    eval_genuine_rate: 0
    eval_h1_strict_count: 23
    eval_h1_strict_rate: 1
    eval_h7_strict_count: 0
    eval_h7_strict_rate: 0
    eval_isr_std: 0
    eval_mean_isr: 0
    eval_median_isr: 0
    eval_n_problems: 100
    eval_n_proved: 23
    eval_prove_rate: 0.23
    eval_proved_only_mean_isr: 0

--- plan002-additive-b01-s43 ---
  status:     DONE
  conclusion: negative
  notes:      NEGATIVE: conclusion duplication hacking 确认。100% proved 样本仅 1 premise，97% premise=conclusion（重言式 P→P）。ISR=0.506 是 artifact（唯一 premise 必然 necessary）。与 s44 相同失败模式。3-seed 中 s42 唯一可能 genuine（待验证），s43/s44 均 collapse。β=0.1 additive bonus 多 seed 可靠性不足。
  metrics:
    eval_n_problems: 100
    eval_n_proved: 61
    eval_prove_rate: 0.61
    eval_proved_only_isr: 0.83
    genuine_count: 2
    genuine_rate: 0.0328
    h1_count: 0
    h1_near_count: 0
    h1_near_rate: 0
    h1_rate: 0
    h7_count: 59
    h7_rate: 0.9672
    h8_conjunction_collapse_count: 0
    h8_conjunction_collapse_rate: 0
    proved_single_premise_ratio: 1
    taxonomy_note: "structurally determined: proved_single_premise_ratio=1.0, all taxonomy categories except H7 are zero by construction. eval file lost but classification derivable from structure."

--- plan002-additive-b01-s44 ---
  status:     DONE
  conclusion: negative
  notes:      H7 FN correction: 12 samples with n_prem=1 misclassified as genuine. Mismatch types: 11 vacuous_quantifier_wrapping (∃x(P(x)) vs ∃x(∃y(P(y)))), 1 structural_simplification. Not simple whitespace/case but logically equivalent structural variants. Evidence file: /root/autodl-tmp/outputs/isr_s44_fn_evi
  metrics:
    comp_2_ratio: 0.022
    component_mean: 4.33
    eval_isr_std: null
    eval_mean_isr: 0.803
    eval_n_problems: 100
    eval_n_proved: 89
    eval_prove_rate: 0.89
    eval_proved_only_isr: 0.902
    genuine_count: 0
    genuine_rate: 0
    h1_count: 0
    h1_rate: 0
    h7_count: 89
    h7_fn_correction: "12 former genuine reclassified as H7: all n_prem=1 false negatives (normalization mismatch prevented conclusion matching)"
    h7_rate: 1
    h8_conjunction_collapse_count: 0
    h8_conjunction_collapse_rate: 0

--- plan002-additive-b01-s42-1000 ---
  status:     DONE
  conclusion: negative
  notes:      D084 taxonomy re-audit (2026-05-15): 90 proved → H7=87 (96.7%), H1_exact=0, H1_near=1, H8=2 (2.2%), genuine=1 (1.1%). Changes vs prior: H7 +4 (paren normalization), H1 -4→0 (reclassified H7), H8 +1 (folio_1255 shared-antecedent conjunction missed), genuine -1. Tautological collapse confirmed. Taxono
  metrics:
    eval_component_count_mean: 2.889
    eval_isr_std: 0.3424
    eval_mean_isr: 0.7892
    eval_median_isr: 1
    eval_n_problems: 100
    eval_n_proved: 90
    eval_prove_rate: 0.9
    eval_proved_only_isr: 0.8769
    genuine_count: 1
    genuine_rate: 0.0111
    h1_count: 0
    h1_near_count: 1
    h1_near_rate: 0.0111
    h1_rate: 0
    h7_count: 87
    h7_rate: 0.9667
    h8_conjunction_collapse_count: 2
    h8_conjunction_collapse_rate: 0.0222
    tautological_collapse: true
    taxonomy_note: "2026-05-15 D084 re-audit: H7 83\u219287 (deeper paren normalization), H1_exact 4\u21920 (reclassified as H7), H8 1\u21922 (+folio_1255 shared-antecedent conjunction), genuine 2\u21921. H1_near=1 (folio_990, retained as genuine per C013). Taxonomy JSON: /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000_taxonomy_unified.json"
    taxonomy_standard: "D084: genuine = proved - H7 - H1_exact - H8"
    train_final_mean_isr: 0.532
    train_final_prove_rate: 0.855

--- plan006-prolog-exec-s43-r2 ---
  status:     DONE
  conclusion: failed
  notes:      OOM 诊断：非 batch size 问题。根因是 kill_job 只杀了 tmux 包装进程 (PID 587155)，训练子进程 587159/587160 残留在 cuda:1 上占 78.09 GiB 显存。s43-r2 启动时 cuda:1 仅剩 40 MiB free，首次前向传播即 OOM (尝试分配 48 MiB)。教训：kill_job 后必须 SSH 确认子进程也已终止（ps aux grep + nvidia-smi），不能只看 PID 返回成功。
  metrics: (none)

--- plan001-exec-only-s43-1000 ---
  status:     DONE
  conclusion: failed
  notes:      N/A
  metrics: (none)

--- plan001-exec-only-s44-1000 ---
  status:     DONE
  conclusion: failed
  notes:      N/A
  metrics: (none)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "3a251f43-b142-495b-b7fd-609466d0bd12"
}
```

</details>

---


### System

_source line 57_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Extract remaining experiments including plan016 and exec-only variants",
  "usage": {
    "total_tokens": 33157,
    "tool_uses": 11,
    "duration_ms": 90903
  },
  "last_tool_name": "Bash",
  "uuid": "fa29263b-7ad5-4dcd-8a2a-cc1f73d7740f",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 58_

<details open><summary>🔧 Tool call — Bash · `toolu_01BQWAbhoVZsazTUEzc7ePoN`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# Get plan016 and any remaining plan001 exec-only with metrics\nremaining = [\n    \"plan016-extended-1000-s42\",\n    \"plan001-exec-only-s42\",\n    \"plan001-exec-only-s42-r2\",\n    \"plan001-exec-only-s42-r3\",\n    \"plan001-exec-only-s43-1000-r2\",\n    \"plan001-exec-only-s44-1000-r2\",\n    \"plan003-eval-exec-only-r5\",\n    \"sta-phase1-exec-only\",\n    \"sta-phase1-exec-only-r5\",\n    # SFT extras\n    \"plan009-sft-baseline-s42\",\n    \"plan009-sft-baseline-s43\",\n    \"plan009-sft-baseline-s44\",\n    \"plan009-sft-baseline-s44-1000-r2\",\n    # random b01 1000 step\n    \"plan018-additive-random-b01-s42-1000-r3\",\n]\n\nfor exp_id in remaining:\n    if exp_id in experiments:\n        exp = experiments[exp_id]\n        status = exp.get('status', 'N/A')\n        conclusion = exp.get('conclusion', 'N/A')\n        metrics = exp.get('metrics', {})\n        notes = exp.get('notes', 'N/A')\n        \n        if status == 'DONE' and metrics:\n            print(f\"\\n--- {exp_id} ---\")\n            print(f\"  status:     {status}\")\n            print(f\"  conclusion: {conclusion}\")\n            print(f\"  notes:      {str(notes)[:300]}\")\n            print(f\"  metrics:\")\n            for mk, mv in sorted(metrics.items()):\n                print(f\"    {mk}: {json.dumps(mv)}\")\n        elif status == 'DONE':\n            print(f\"\\n--- {exp_id} --- (DONE, no metrics, conclusion={conclusion})\")\n\nPYEOF",
  "description": "Extract remaining experiments including plan016 and exec-only variants",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "bf9d258c-7ba6-42bb-a982-3c31e184ae53",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xtab4dEL8k3e6A6bA58nKX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5566,
      "cache_read_input_tokens": 27092,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5566,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 44,
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

_source line 59 · 2026-05-15T14:57:36.670Z_

<details><summary>↩ Tool result · `toolu_01BQWAbhoVZsazTUEzc7ePoN`</summary>

```text
--- plan016-extended-1000-s42 ---
  status:     DONE
  conclusion: success
  notes:      Extended training to 1000 steps CONFIRMS ISR collapse worsens monotonically.\n\n## 500 vs 1000 step comparison (eval_sta.py):\n| Metric | plan001-s42 (500步) | plan016 (1000步) | Change |\n|--------|-------------------|-----------------|--------|\n| eval PR | 0.93 | 0.96 | +3.2% |\n| eval ISR | 0.123 
  metrics:
    components: 18.55
    genuine_count: 0
    genuine_rate: 0
    h1_count: 96
    h1_rate: 1
    h7_count: 0
    h7_rate: 0
    isr: 0.003
    n_proved: 96
    prove_rate: 0.96

--- plan001-exec-only-s42 --- (DONE, no metrics, conclusion=failed)

--- plan001-exec-only-s42-r2 ---
  status:     DONE
  conclusion: success
  notes:      Cron 误判 DONE/failed（因 --help|grep 前缀命令的 PID 84896 退出，实际训练子进程 PID 84901 仍在运行）。已手动恢复 RUNNING。严禁在 cuda:0 启动新进程直到 r2 自然完成。⚠️ Reviewer 中期审查标注: 训练日志中 ISR=0.8612 为 binary approximation (_fast_fn)，非真实 ISR。最终可比 ISR 需通过 eval_sta.py (full STA) 重新评估。
  metrics:
    conclusion_embedding_total: 0.871
    content_independent_predicates_count: 1
    eval_data: "proofwriter_fol_100.jsonl"
    eval_isr_std: 0.1887
    eval_mean_isr: 0.1232
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_n_problems: 100
    eval_n_proved: 93
    eval_prove_rate: 0.93
    eval_proved_only_isr: 0.1324
    genuine_count: 7
    genuine_mean_isr: 0.3141
    genuine_rate: 0.0753
    h1_count: 81
    h1_mean_isr: 0.1055
    h1_rate: 0.871
    h7_count: 0
    h7_rate: 0
    h8_audit_note: "2026-05-15: H8 conjunction collapse added. genuine 12\u21927."
    h8_conjunction_collapse_count: 6
    h8_conjunction_collapse_rate: 0.0645

--- plan001-exec-only-s42-r3 --- (DONE, no metrics, conclusion=failed)

--- plan003-eval-exec-only-r5 ---
  status:     DONE
  conclusion: success
  notes:      N/A
  metrics:
    isr_by_type: {"true": 0.3598, "false": 0.1723, "unknown": 0.0979}
    isr_std: 0.3194
    mean_isr: 0.2055
    prove_rate: 0.32
    proved_count: 32
    proved_only_isr: 0.6423
    runtime_s: 251.7
    total_samples: 100

--- sta-phase1-exec-only --- (DONE, no metrics, conclusion=failed)

--- sta-phase1-exec-only-r5 ---
  status:     DONE
  conclusion: success
  notes:      N/A
  metrics:
    K: 8
    first20_isr_mean: 0.11875
    first20_prove_rate: 0.11875
    isr_pr_ratio_last20: 1
    last20_isr_mean: 0.2
    last20_prove_rate: 0.2
    last20_reward_mean: 0.2
    mean_isr: 0.1475
    overall_reward_mean: 0.15125
    parse_rate: 1
    prove_rate: 0.15125
    step_time_s: 9.44
    training_minutes: 15.7
    training_steps: 100

--- plan009-sft-baseline-s42 --- (DONE, no metrics, conclusion=killed)

--- plan009-sft-baseline-s43 ---
  status:     DONE
  conclusion: success
  notes:      N/A
  metrics:
    by_answer_type: {"true": {"count": 34, "proved": 13, "prove_rate": 0.382, "mean_isr": 0.234}, "false": {"count": 25, "proved": 1, "prove_rate": 0.04, "mean_isr": 0.027}, "unknown": {"count": 41, "proved": 1, "prove_rate": 0.024, "mean_isr": 0.008}}
    eval_data_path: "data/proofwriter_fol_100.jsonl"
    eval_isr_std: 0.2338
    eval_mean_isr: 0.0895
    eval_median_isr: 0
    eval_output_path: "/root/autodl-tmp/outputs/eval_sta_plan009_sft_s43.json"
    eval_prove_rate: 0.15
    eval_proved_only_isr: 0.5967
    genuine_count: 14
    genuine_rate: 0.933
    h1_count: 1
    h1_rate: 0.067
    h7_count: 0
    h7_rate: 0
    train_epochs: 7.94
    train_loss: 0.2391
    train_runtime_sec: 677.14
    train_steps: 500
    train_token_accuracy: 0.9938

--- plan009-sft-baseline-s44 ---
  status:     DONE
  conclusion: success
  notes:      N/A
  metrics:
    eval_by_answer_type: {"true": {"count": 34, "proved": 15, "prove_rate": 0.441, "mean_isr": 0.257}, "false": {"count": 25, "proved": 1, "prove_rate": 0.04, "mean_isr": 0.027}, "unknown": {"count": 41, "proved": 1, "prove_rate": 0.024, "mean_isr": 0.008}}
    eval_correction_note: "Corrected 2026-05-15: previous eval used test_100.jsonl (50/44/6 distribution), re-evaled with proofwriter_fol_100.jsonl (34/25/41)"
    eval_data: "proofwriter_fol_100.jsonl"
    eval_genuine_count: 15
    eval_genuine_rate: 0.882
    eval_h1_count: 2
    eval_h1_rate: 0.118
    eval_h7_count: 0
    eval_h7_rate: 0
    eval_isr_std: 0.2409
    eval_mean_isr: 0.0974
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_n_problems: 100
    eval_n_proved: 17
    eval_output_path: "/root/autodl-tmp/outputs/eval_sta_plan009_sft_s44.json"
    eval_prove_rate: 0.17
    eval_proved_only_isr: 0.5729
    eval_tautological_collapse: false
    train_epochs: 7.94
    train_final_loss: 0.2397
    train_last_step_loss: 0.0328
    train_runtime_sec: 729.05
    train_steps: 500
    train_token_accuracy: 0.9928

--- plan009-sft-baseline-s44-1000-r2 --- (DONE, no metrics, conclusion=failed)

--- plan018-additive-random-b01-s42-1000-r3 ---
  status:     DONE
  conclusion: negative
  notes:      N/A
  metrics:
    eval_by_answer_type: {"false": {"count": 25, "proved": 25, "prove_rate": 1, "mean_isr": 0.7533}, "unknown": {"count": 41, "proved": 39, "prove_rate": 0.951, "mean_isr": 0.6565}, "true": {"count": 34, "proved": 33, "prove_rate": 0.971, "mean_isr": 0.6814}}
    eval_isr_std: 0.2037
    eval_mean_isr: 0.6892
    eval_median_isr: 0.75
    eval_n_problems: 100
    eval_n_proved: 97
    eval_prove_rate: 0.97
    eval_proved_only_isr: 0.7105
    genuine_count: 0
    genuine_rate: 0
    h1_count: 97
    h1_rate: 0.97
    h7_count: 0
    h7_rate: 0
    n_premise_distribution: {"1": 97}
    pattern_description: "All 97 proved: 1 premise identical to conclusion (P therefore P). ISR varies by structural decomposition, not reasoning quality."
    tautological_collapse: true
    train_final_entropy: 0.003
    train_final_mean_isr: 0.5213
    train_final_prove_rate: 0.827
    train_loss: 0.00671
    train_runtime_seconds: 5783
    train_steps: 1000
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "c0cf3e9a-2a0c-4258-a910-f817d3e99c67"
}
```

</details>

---


### System

_source line 60_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Extract all Prolog experiment data",
  "usage": {
    "total_tokens": 36563,
    "tool_uses": 12,
    "duration_ms": 100039
  },
  "last_tool_name": "Bash",
  "uuid": "1ed05573-ee17-44c5-bbd9-62c0299c16ef",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 61_

<details open><summary>🔧 Tool call — Bash · `toolu_01NrtxToudNqSHFM4RzAboey`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# Get Prolog s43-r2 follow-ups and any remaining prolog experiments\nprolog_keys = [k for k in experiments.keys() if 'prolog' in k.lower()]\nprint(\"All Prolog keys:\", prolog_keys)\n\nfor exp_id in prolog_keys:\n    exp = experiments[exp_id]\n    status = exp.get('status', 'N/A')\n    conclusion = exp.get('conclusion', 'N/A')\n    metrics = exp.get('metrics', {})\n    notes = exp.get('notes', 'N/A')\n    if status == 'DONE' and metrics:\n        print(f\"\\n--- {exp_id} ---\")\n        print(f\"  status:     {status}\")\n        print(f\"  conclusion: {conclusion}\")\n        print(f\"  notes:      {str(notes)[:200]}\")\n        print(f\"  metrics:\")\n        for mk, mv in sorted(metrics.items()):\n            print(f\"    {mk}: {json.dumps(mv)}\")\n    elif status == 'DONE':\n        print(f\"\\n--- {exp_id} --- (DONE, no metrics, conclusion={conclusion})\")\n\n# Also check for plan006-prolog-exec-s43-r3, etc\nfor suffix in ['-r3', '-r4', '-r5']:\n    key = f\"plan006-prolog-exec-s43{suffix}\"\n    if key in experiments:\n        exp = experiments[key]\n        print(f\"\\n--- {key} ---\")\n        print(f\"  status: {exp.get('status')}, conclusion: {exp.get('conclusion')}\")\n        if exp.get('metrics'):\n            for mk, mv in sorted(exp['metrics'].items()):\n                print(f\"    {mk}: {json.dumps(mv)}\")\n\nPYEOF",
  "description": "Extract all Prolog experiment data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "294854d1-2d58-4747-aca2-00bc8f7f73a5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SArxQCqLwZy1e2qcvnVDpX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3334,
      "cache_read_input_tokens": 32658,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3334,
        "ephemeral_1h_input_tokens": 0
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

_source line 62 · 2026-05-15T14:57:45.888Z_

<details><summary>↩ Tool result · `toolu_01NrtxToudNqSHFM4RzAboey`</summary>

```text
All Prolog keys: ['plan006-prolog-sta-s44', 'plan006-prolog-sta-s43', 'plan006-prolog-sta-s42', 'plan006-prolog-exec-s44', 'plan006-prolog-exec-s43-r3', 'plan006-prolog-exec-s43-r2', 'plan006-prolog-exec-s42', 'plan006-prolog-exec-s43']

--- plan006-prolog-sta-s44 ---
  status:     DONE
  conclusion: negative
  notes:      Reviewer 独立核实: query-as-fact gaming, 0% genuine. 97/97 proved 样本中 95/97 n_necessary=1（功能性 H7）。模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。PR=0.97, ISR=0.885 是 gaming artifact（高 I
  metrics:
    failure_mode: "query-as-fact gaming (total H7 collapse)"
    genuine_rate: 0
    h7_functional_rate: 0.979
    isr_mean: 0.885
    isr_n_cl_ge3: "N/A (0 samples)"
    n_clauses_dist: "78/100 single-clause, 22/100 two-clause"
    pass_rate: 0.97
    premise_count_analysis: "100% artifact - zero samples with n_clauses>=3, model exclusively generates 1-2 clause programs"

--- plan006-prolog-sta-s43 ---
  status:     DONE
  conclusion: negative
  notes:      Eval: PR=0.38, ISR=0.185 proved-only. Strict classifier: H7=0%, H1=0%, Genuine=100%. 但功能分析显示所有 38 proved 样本 n_necessary=1（功能性 H7）。模型生成大写伪 Prolog（如 MARY_IS_AN_AVADEOTE.）—— 非标准语法，strict classifier 无法匹配 
  metrics:
    eval: {"n_problems": 100, "n_proved": 38, "prove_rate": 0.38, "mean_isr": 0.0704, "isr_std": 0.1263, "median_isr": 0, "proved_only_mean_isr": 0.1853, "min_isr": 0, "max_isr": 1, "by_answer_type": {"false": {"count": 25, "proved": 11, "prove_rate": 0.44, "mean_isr": 0.1003}, "unknown": {"count": 41, "proved": 11, "prove_rate": 0.268, "mean_isr": 0.0394}, "true": {"count": 34, "proved": 16, "prove_rate": 0.471, "mean_isr": 0.0859}}}
    h7_classification: {"h7_strict": 0, "h7_rate": 0, "h1_strict": 37, "h1_rate": 0.974, "conclusion_in_premise_total": 37, "conclusion_in_premise_rate": 0.974, "genuine_count": 0, "genuine_rate": 0, "isr_1_count": 1, "note": "1 pseudo-genuine sample (folio_1415) has query embedded in single mega-clause; all 38/38 proved samples are tautological"}
    train: {"final_prove_rate": 0.769, "final_mean_isr": 0.129, "final_loss": 0.0155, "final_entropy": 0.09, "final_reward": 0.573, "completion_length_mean": 143, "train_runtime_seconds": 5095, "train_runtime_minutes": 84.9}

--- plan006-prolog-sta-s42 ---
  status:     DONE
  conclusion: negative
  notes:      Eval metrics provenance: eval 在训练完成后立即在 westd-39279 服务器上运行 eval_sta.py，checkpoint 路径 /root/autodl-tmp/outputs/plan006_prolog_sta_s42/。Eval 结果由 Worker 从服务器 SSH 读取 eval_results.json 并手动录入 registry。Check
  metrics:
    cumulative_mean_isr: 0.787
    cumulative_prove_rate: 0.848
    eval_h7_count: 50
    eval_h7_rate: 1
    eval_isr_distribution: "binary: 50x0 + 50x1"
    eval_mean_isr: 0.5
    eval_n_clauses_mean: 1
    eval_prove_rate: 0.5
    eval_proved_count: 50
    eval_proved_only_isr: 1
    eval_total_count: 100
    final_completion_length: 27
    final_entropy: 0.01
    final_isr: 1
    final_prove_rate: 1
    final_reward: 1
    initial_completion_length: 120
    saturation_onset_step: 100
    steps_at_perfect_reward: 400
    train_loss: 0.00716
    train_runtime_sec: 2791
    training_hours: 0.78

--- plan006-prolog-exec-s44 ---
  status:     DONE
  conclusion: negative
  notes:      Eval 完成。PR=21% (3-seed 最低), ISR=0.081, proved_only_ISR=0.387 (max_ISR=1.0)。与 s42/s43 不同模式：PR 极低但 proved_only_ISR 较高，可能有少量样本 ISR=1 (H7-like)。Prolog exec-only 3-seed 汇总：s42 PR=83%/ISR=0.031, s43 PR=56%/
  metrics:
    eval_by_type_false_isr: 0.04
    eval_by_type_false_pr: 0.04
    eval_by_type_true_isr: 0.09
    eval_by_type_true_pr: 0.206
    eval_by_type_unknown_isr: 0.099
    eval_by_type_unknown_pr: 0.317
    eval_data: "proofwriter_fol_100.jsonl"
    eval_elapsed_seconds: 683.9
    eval_isr_std: 0.2343
    eval_max_isr: 1
    eval_mean_isr: 0.0812
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_min_isr: 0
    eval_n_problems: 100
    eval_n_proved: 21
    eval_prove_rate: 0.21
    eval_proved_only_isr: 0.3866
    logic_type: "prolog"
    solver: "PrologSolver"

--- plan006-prolog-exec-s43-r3 ---
  status:     DONE
  conclusion: negative
  notes:      Eval 完成。PR=56% (远低于 s42 的 83%), ISR=0.0084 (与 s42 的 0.031 同量级，均极低)。proved_only_ISR=0.015。Prolog exec-only 跨 seed 表现：s42 PR=83%/ISR=0.031, s43 PR=56%/ISR=0.008。s43 prove_rate 显著下降但 ISR 模式一致（极低，ground f
  metrics:
    eval_by_type_false_isr: 0.0043
    eval_by_type_false_pr: 0.48
    eval_by_type_true_isr: 0.0078
    eval_by_type_true_pr: 0.5
    eval_by_type_unknown_isr: 0.0114
    eval_by_type_unknown_pr: 0.6585
    eval_data: "proofwriter_fol_100.jsonl"
    eval_elapsed_seconds: 868.2
    eval_isr_std: 0.0221
    eval_max_isr: 0.1
    eval_mean_isr: 0.0084
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_min_isr: 0
    eval_n_problems: 100
    eval_n_proved: 56
    eval_prove_rate: 0.56
    eval_proved_only_isr: 0.015
    logic_type: "prolog"
    solver: "PrologSolver"

--- plan006-prolog-exec-s43-r2 --- (DONE, no metrics, conclusion=failed)

--- plan006-prolog-exec-s42 ---
  status:     DONE
  conclusion: negative
  notes:      Eval (eval_sta.py) 完成。PR=83%, mean_ISR=0.031, proved_only_ISR=0.037, H7=0%, H1=0%。与 sta-s42 (PR=50%, ISR=1.0, H7=100%) 形成鲜明对比。exec-only 产生完全不同的 hacking 模式：ground fact enumeration（倾泻大量无关 ground facts，q
  metrics:
    by_answer_type: {"true": {"proved": 37, "count": 40, "pr": 0.925, "isr": 0.037}, "false": {"proved": 21, "count": 29, "pr": 0.724, "isr": 0.038}, "unknown": {"proved": 25, "count": 31, "pr": 0.806, "isr": 0.016}}
    eval_isr_std: 0.0534
    eval_max_isr: 0.2
    eval_mean_isr: 0.031
    eval_median_isr: 0
    eval_prove_rate: 0.83
    eval_proved_only_isr: 0.037
    h1_rate: 0
    h7_rate: 0
    isr_1_rate: 0
    single_premise_rate: 0

--- plan006-prolog-exec-s43 --- (DONE, no metrics, conclusion=killed)

--- plan006-prolog-exec-s43-r3 ---
  status: DONE, conclusion: negative
    eval_by_type_false_isr: 0.0043
    eval_by_type_false_pr: 0.48
    eval_by_type_true_isr: 0.0078
    eval_by_type_true_pr: 0.5
    eval_by_type_unknown_isr: 0.0114
    eval_by_type_unknown_pr: 0.6585
    eval_data: "proofwriter_fol_100.jsonl"
    eval_elapsed_seconds: 868.2
    eval_isr_std: 0.0221
    eval_max_isr: 0.1
    eval_mean_isr: 0.0084
    eval_median_isr: 0
    eval_method: "eval_sta.py full STA"
    eval_min_isr: 0
    eval_n_problems: 100
    eval_n_proved: 56
    eval_prove_rate: 0.56
    eval_proved_only_isr: 0.015
    logic_type: "prolog"
    solver: "PrologSolver"
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "1c8a7978-dafe-4418-8a87-de8c9ee01e55"
}
```

</details>

---


### System

_source line 63_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "description": "Running Find ISR b03 s42 500-step and sta- experiments",
  "usage": {
    "total_tokens": 40269,
    "tool_uses": 13,
    "duration_ms": 111756
  },
  "last_tool_name": "Bash",
  "uuid": "c98b829e-b49a-4069-ab93-aa4dcfaeff2d",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool call

_source line 64_

<details open><summary>🔧 Tool call — Bash · `toolu_01Pgn8p9GCYajMtEwecVX5Eg`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfpath = \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt\"\n\nwith open(fpath, 'r') as f:\n    raw = json.load(f)\n\ninner = json.loads(raw['result'])\nexperiments = inner['data']['experiments']\n\n# Find the ISR b03 s42 500-step variant (not 1000)\nisr_b03_keys = [k for k in experiments.keys() if 'isr' in k.lower() and 'b03' in k.lower()]\nprint(\"All ISR b03 keys:\", isr_b03_keys)\n\n# Find random b03 s42 variant\nrandom_b03_keys = [k for k in experiments.keys() if 'random' in k.lower() and 'b03' in k.lower()]\nprint(\"All random b03 keys:\", random_b03_keys)\n\n# Find any \"sta\" keys that might be the original exec-only s42\nsta_keys = [k for k in experiments.keys() if k.startswith('sta-')]\nprint(\"All sta- keys:\", sta_keys)\n\n# Check for any key containing \"s42\" and \"isr\" or \"b03\" at 500 steps\nfor k in isr_b03_keys:\n    exp = experiments[k]\n    status = exp.get('status', 'N/A')\n    conclusion = exp.get('conclusion', 'N/A')\n    metrics = exp.get('metrics', {})\n    if 's42' in k and '1000' not in k:\n        print(f\"\\n--- {k} --- (possible ISR b03 s42 500-step)\")\n        print(f\"  status: {status}, conclusion: {conclusion}\")\n        if metrics:\n            for mk, mv in sorted(metrics.items()):\n                print(f\"    {mk}: {json.dumps(mv)}\")\n        else:\n            print(\"  (no metrics)\")\n\n# Also check sta-s42 etc\nfor k in sta_keys:\n    exp = experiments[k]\n    if exp.get('metrics'):\n        print(f\"\\n--- {k} ---\")\n        print(f\"  status: {exp.get('status')}, conclusion: {exp.get('conclusion')}\")\n        for mk, mv in sorted(exp['metrics'].items()):\n            print(f\"    {mk}: {json.dumps(mv)}\")\n\nPYEOF",
  "description": "Find ISR b03 s42 500-step and sta- experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "4c33ee43-01ac-4e94-8dc0-8762ab60c7bc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XKg26oj2uNQYXZx76pi4j9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3704,
      "cache_read_input_tokens": 35992,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3704,
        "ephemeral_1h_input_tokens": 0
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

_source line 65 · 2026-05-15T14:57:57.535Z_

<details><summary>↩ Tool result · `toolu_01Pgn8p9GCYajMtEwecVX5Eg`</summary>

```text
All ISR b03 keys: ['exp1-isr-b03-s43', 'exp1-isr-b03-s42-1000-r2', 'exp1-isr-b03-s42-1000', 'exp1-isr-b03-s43-r3', 'exp1-isr-b03-s43-r4', 'exp1-isr-b03-s44-r2', 'exp1-isr-b03-s44', 'exp1-isr-b03-s43-r2']
All random b03 keys: ['exp1-random-b03-s43-r4', 'exp1-random-b03-s44-r2', 'exp1-random-b03-s43-r3', 'exp1-random-b03-s43-r2', 'exp1-random-b03-s43', 'exp1-random-b03-s44']
All sta- keys: ['sta-phase1-exec-sta-r5', 'sta-phase1-exec-only-r5', 'sta-phase1-exec-sta-r4', 'sta-phase1-exec-only-r4', 'sta-phase1-exec-only-r3', 'sta-phase1-exec-sta-r3', 'sta-phase1-exec-sta-r2', 'sta-phase1-exec-only-r2', 'sta-phase1-exec-sta', 'sta-phase1-exec-only', 'sta-gt-isr-baseline', 'sta-phase0-baseline']

--- sta-phase1-exec-sta-r5 ---
  status: DONE, conclusion: negative
    K: 8
    first20_isr_mean: 0.05182
    first20_prove_rate: 0.08125
    isr_pr_ratio_last20: 0.33
    isr_pr_ratio_overall: 0.43
    last20_isr_mean: 0.04956
    last20_prove_rate: 0.15
    last20_reward_mean: 0.09978
    mean_isr: 0.04347
    overall_reward_mean: 0.07174
    parse_rate: 1
    prove_rate: 0.1
    step_time_s: 10.13
    training_minutes: 16.9
    training_steps: 100

--- sta-phase1-exec-only-r5 ---
  status: DONE, conclusion: success
    K: 8
    first20_isr_mean: 0.11875
    first20_prove_rate: 0.11875
    isr_pr_ratio_last20: 1
    last20_isr_mean: 0.2
    last20_prove_rate: 0.2
    last20_reward_mean: 0.2
    mean_isr: 0.1475
    overall_reward_mean: 0.15125
    parse_rate: 1
    prove_rate: 0.15125
    step_time_s: 9.44
    training_minutes: 15.7
    training_steps: 100

--- sta-phase1-exec-sta-r4 ---
  status: DONE, conclusion: negative
    first20_reward_mean: 0.119
    last20_isr_mean: 0.2125
    last20_prove_rate: 0.2125
    mean_isr: 0.1525
    parse_rate: 1
    prove_rate: 0.1575
    training_minutes: 15
    training_steps: 100

--- sta-phase1-exec-only-r4 ---
  status: DONE, conclusion: negative
    first20_reward_mean: 0.119
    last20_isr_mean: 0.2
    last20_prove_rate: 0.2
    mean_isr: 0.1475
    parse_rate: 1
    prove_rate: 0.15125
    training_minutes: 15
    training_steps: 100

--- sta-gt-isr-baseline ---
  status: DONE, conclusion: success
    gt_isr_median: 0.6125
    gt_isr_std: 0.2582
    gt_mean_isr: 0.5588
    gt_prove_rate: 0.18
    solver_execution_rate: 1
    true_mean_isr: 0.5833
    true_prove_rate: 0.5

--- sta-phase0-baseline ---
  status: DONE, conclusion: success
    avg_time_per_sample_s: 3.4
    effective_prove_rate_no_xor: 0.182
    isr_by_answer: {"true": {"n": 34, "proved": 9, "prove_rate": 0.265, "mean_isr": 0.1345}, "false": {"n": 25, "proved": 1, "prove_rate": 0.04, "mean_isr": 0.024}, "unknown": {"n": 41, "proved": 2, "prove_rate": 0.049, "mean_isr": 0.0302}}
    isr_range: [0, 0.889]
    isr_std: 0.1983
    mean_isr: 0.0641
    median_isr: 0
    prove_rate: 0.12
    proved_count: 12
    total_runtime_s: 336
    total_samples: 100
    xor_affected_samples: 34
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "59d3980c-0300-4228-bb6b-fa851295f5f1"
}
```

</details>

---


### System

_source line 66_

```json
{
  "type": "system",
  "subtype": "task_notification",
  "task_id": "a3e1e5f1b82696fa8",
  "tool_use_id": "toolu_011NrBqs1fbLbwQgQzBDsLiE",
  "status": "completed",
  "output_file": "",
  "summary": "Extract registry metrics",
  "usage": {
    "total_tokens": 42449,
    "tool_uses": 13,
    "duration_ms": 173878
  },
  "uuid": "846628f5-fbd2-439a-95ee-0987bd4ae2c4",
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc"
}
```

---


### Tool result

_source line 67 · 2026-05-15T14:58:59.568Z_

<details><summary>↩ Tool result · `toolu_011NrBqs1fbLbwQgQzBDsLiE`</summary>

```text
Now I have all the data. Here is the structured summary:

---

## Complete Metrics Extraction from Registry

### 1. SFT Baselines (500 and 1000 steps)

**plan009-sft-baseline-s42-1000** — status=DONE, conclusion=success
- eval_prove_rate: 0.13
- eval_mean_isr: 0.0738, eval_isr_std: 0.2077, eval_median_isr: 0
- eval_proved_only_isr: 0.5677
- genuine_count: 12, genuine_rate: 0.9231
- h7_strict_count: 0, h7_strict_rate: 0
- h1_strict_count: 1, h1_strict_rate: 0.0769
- h8_conjunction_collapse_count: 0, h8_conjunction_collapse_rate: 0
- train_steps: 1000, train_final_loss: 0.0168, train_token_accuracy: 0.9955
- by_answer_type: true PR=0.353, false PR=0.04, unknown PR=0

**plan009-sft-baseline-s43-1000** — status=DONE, conclusion=success
- prove_rate: 0.11
- mean_isr: 0.0699, isr_std: 0.2155, median_isr: 0
- proved_only_mean_isr: 0.6352
- genuine_count: 10, genuine_rate: 0.9091
- h7_strict_count: 0, h1_strict_count: 1, h8_conjunction_collapse_count: 0
- train_final_loss: 0.0167, train_token_accuracy: 0.9954

**plan009-sft-baseline-s44-1000-r3** — status=DONE, conclusion=success
- eval_prove_rate: 0.15
- eval_mean_isr: 0.0884, eval_isr_std: 0.2268, eval_median_isr: 0
- eval_proved_only_isr: 0.5892
- genuine_count: 14, genuine_rate: 0.9333
- h1_count: 1, h1_rate: 0.0667
- h7_count: 0, h8_conjunction_collapse_count: 0

**SFT 500-step variants** (for reference):
- plan009-sft-baseline-s43 (500 steps): PR=0.15, ISR=0.0895, genuine_rate=0.933
- plan009-sft-baseline-s44 (500 steps): PR=0.17, ISR=0.0974, genuine_rate=0.882

---

### 2. Exec-only s42

No `plan016-exec-only-s42-1000` exists. The closest equivalent is:

**plan016-extended-1000-s42** — status=DONE, conclusion=success
- prove_rate: 0.96
- isr: 0.003
- n_proved: 96, components: 18.55
- genuine_count: 0, genuine_rate: 0
- h1_count: 96, h1_rate: 1
- h7_count: 0

**plan001-exec-only-s42-r2** (500 steps, full STA eval) — status=DONE, conclusion=success
- eval_prove_rate: 0.93
- eval_mean_isr: 0.1232, eval_isr_std: 0.1887, eval_median_isr: 0
- eval_proved_only_isr: 0.1324
- genuine_count: 7, genuine_rate: 0.0753
- h1_count: 81, h1_rate: 0.871
- h7_count: 0
- h8_conjunction_collapse_count: 6, h8_conjunction_collapse_rate: 0.0645

---

### 3. ISR beta=0.3 All Seeds

**No `exp1-isr-b03-s42` at 500 steps exists.** Only 1000-step variants:

**exp1-isr-b03-s42-1000-r2** — status=DONE, conclusion=negative
- eval_prove_rate: 0.95
- eval_mean_isr: 0.734, eval_isr_std: 0.2575, eval_median_isr: 0.6
- eval_proved_only_isr: 0.7726
- genuine_count: 0, genuine_rate: 0
- h1_count: 54, h1_rate: 0.568
- h7_count: 0, h8_conjunction_collapse_count: 41, h8_conjunction_collapse_rate: 0.432
- isr_1_count: 41, isr_1_rate: 0.432
- tautological_collapse: true
- train_loss: 0.0041, train_final_entropy: 9e-06

**exp1-isr-b03-s43** — status=DONE, conclusion=success (**INVALIDATED** — eval used wrong test set test_100.jsonl)
- prove_rate: 0.91
- mean_isr: 0.2575, isr_std: 0.2363, median_isr: 0.3333
- proved_only_mean_isr: 0.283
- genuine_count: 61, genuine_rate: 0.6703
- hacking_rate_strict_h7: 0.022, hacking_rate_functional: 0.3297

**exp1-isr-b03-s43-r3** (retrained, valid eval) — status=DONE, conclusion=success
- eval_prove_rate: 0.86
- eval_mean_isr: 0.2535, eval_isr_std: 0.2406, eval_median_isr: 0.3333
- eval_proved_only_mean_isr: 0.2948
- eval_genuine_count: 23, eval_genuine_rate: 0.267
- eval_h7_strict_count: 4, eval_h7_strict_rate: 0.047
- eval_h1_strict_count: 59, eval_h1_strict_rate: 0.686
- eval_single_premise_count: 5, eval_single_premise_rate: 0.058
- train_loss: 0.0176, train_runtime_sec: 4153.6

**exp1-isr-b03-s44-r2** — status=DONE, conclusion=success
- prove_rate: 0.95
- mean_isr: 0.705, isr_std: 0.172
- proved_only_isr: 0.7421
- genuine_count: 0, genuine_rate: 0
- h7_count: 95, h7_rate: 1
- h1_count: 0
- single_premise_rate: 1

---

### 4. ISR beta=0.1 (plan002)

**plan002-additive-b01-s42** — status=DONE, conclusion=negative
- eval_prove_rate: 0.81
- eval_mean_isr: 0.3365, eval_isr_std: 0.3227, eval_median_isr: 0.2
- eval_proved_only_isr: 0.4154
- genuine_count: 14, genuine_rate: 0.173
- h1_count: 42, h1_rate: 0.519
- h7_count: 13, h7_rate: 0.16
- h8_conjunction_collapse_count: 12, h8_conjunction_collapse_rate: 0.148
- tautological_collapse: false

**plan002-additive-b01-s43** — status=DONE, conclusion=negative
- eval_prove_rate: 0.61
- eval_proved_only_isr: 0.83
- genuine_count: 2, genuine_rate: 0.0328
- h7_count: 59, h7_rate: 0.9672
- proved_single_premise_ratio: 1 (total H7 collapse)

**plan002-additive-b01-s44** — status=DONE, conclusion=negative
- eval_prove_rate: 0.89
- eval_mean_isr: 0.803
- genuine_count: 0, genuine_rate: 0
- h7_count: 89, h7_rate: 1 (complete tautological collapse)

**plan002-additive-b01-s42-1000** (extended to 1000 steps) — status=DONE, conclusion=negative
- eval_prove_rate: 0.9
- eval_mean_isr: 0.7892, eval_median_isr: 1
- eval_proved_only_isr: 0.8769
- genuine_count: 1, genuine_rate: 0.0111
- h7_count: 87, h7_rate: 0.9667
- h8_conjunction_collapse_count: 2, h8_conjunction_collapse_rate: 0.0222
- tautological_collapse: true

---

### 5. Random beta=0.1 (plan018)

**plan018-additive-random-b01-s42** — status=DONE, conclusion=negative
- eval_prove_rate: 0.79
- eval_mean_isr: 0.1038, eval_isr_std: 0.1369, eval_median_isr: 0.0357
- eval_proved_only_isr: 0.1314
- genuine_count_strict: 12, genuine_rate_strict: 0.1519
- genuine_count_exact_h1: 23, genuine_rate_exact_h1: 0.2911
- h1_count: 56, h1_rate: 0.7089
- h7_count: 0
- h8_conjunction_collapse_count: 3, h8_conjunction_collapse_rate: 0.038
- tautological_collapse: false

**plan018-additive-random-b01-s43-r3** — status=PREPARING (no metrics)

**plan018-additive-random-b01-s44-r2** — status=PREPARING (no metrics)

**plan018-additive-random-b01-s42-1000-r3** (1000 steps) — status=DONE, conclusion=negative
- eval_prove_rate: 0.97
- eval_mean_isr: 0.6892, eval_isr_std: 0.2037, eval_median_isr: 0.75
- eval_proved_only_isr: 0.7105
- genuine_count: 0, genuine_rate: 0
- h1_count: 97, h1_rate: 0.97
- tautological_collapse: true
- n_premise_distribution: {"1": 97} (all single-premise P->P)

---

### 6. Random beta=0.3 (exp1-random-b03)

**No `exp1-random-b03-s42` exists in the registry.**

**exp1-random-b03-s43** — status=DONE, conclusion=success (**INVALIDATED** — eval used test_100.jsonl)
- prove_rate: 0.79
- mean_isr: 0.1745, isr_std: 0.1628, median_isr: 0.1667
- proved_only_mean_isr: 0.2209
- genuine_count: 71, genuine_rate: 0.8987
- hacking_rate_strict_h7: 0, hacking_rate_functional: 0.1013

**exp1-random-b03-s43-r4** (retrained, valid eval) — status=DONE, conclusion=success
- eval_prove_rate: 0.92
- eval_mean_isr: 0.1659, eval_isr_std: 0.1147, eval_median_isr: 0.1429
- eval_proved_only_mean_isr: 0.1803
- eval_genuine_count: 2, eval_genuine_rate: 0.022
- eval_h1_strict_count: 90, eval_h1_strict_rate: 0.978
- eval_h7_strict_count: 7, eval_h7_strict_rate: 0.076
- train_loss: 0.01365

**exp1-random-b03-s44-r2** — status=DONE, conclusion=success
- eval_prove_rate: 0.23
- eval_mean_isr: 0, eval_isr_std: 0, eval_median_isr: 0
- eval_proved_only_mean_isr: 0
- eval_genuine_count: 0, eval_genuine_rate: 0
- eval_h1_strict_count: 23, eval_h1_strict_rate: 1

**exp1-random-b03-s44** — status=DONE, conclusion=failed (no metrics)

---

### 7. Prolog Experiments (plan006)

#### Prolog Exec-only:
**plan006-prolog-exec-s42** — status=DONE, conclusion=negative
- eval_prove_rate: 0.83
- eval_mean_isr: 0.031, eval_isr_std: 0.0534, eval_max_isr: 0.2, eval_median_isr: 0
- eval_proved_only_isr: 0.037
- h7_rate: 0, h1_rate: 0, isr_1_rate: 0, single_premise_rate: 0
- Hacking mode: ground fact enumeration

**plan006-prolog-exec-s43-r3** — status=DONE, conclusion=negative
- eval_prove_rate: 0.56
- eval_mean_isr: 0.0084, eval_isr_std: 0.0221, eval_max_isr: 0.1, eval_median_isr: 0
- eval_proved_only_isr: 0.015

**plan006-prolog-exec-s44** — status=DONE, conclusion=negative
- eval_prove_rate: 0.21
- eval_mean_isr: 0.0812, eval_isr_std: 0.2343, eval_max_isr: 1, eval_median_isr: 0
- eval_proved_only_isr: 0.3866

#### Prolog STA (exec+ISR):
**plan006-prolog-sta-s42** — status=DONE, conclusion=negative
- eval_prove_rate: 0.5
- eval_mean_isr: 0.5, eval_proved_only_isr: 1
- eval_h7_count: 50, eval_h7_rate: 1 (complete H7 collapse, binary ISR: 50x0 + 50x1)

**plan006-prolog-sta-s43** — status=DONE, conclusion=negative
- eval prove_rate: 0.38
- eval mean_isr: 0.0704, proved_only_mean_isr: 0.1853
- h7_classification: h7_strict=0, h1_strict=37 (0.974), genuine_count=0 (functional tautological)

**plan006-prolog-sta-s44** — status=DONE, conclusion=negative
- pass_rate: 0.97
- isr_mean: 0.885
- genuine_rate: 0, h7_functional_rate: 0.979
- Failure mode: "query-as-fact gaming (total H7 collapse)"

---

### 8. Bootstrap CI

No experiments with "bootstrap" or "ci" in their ID exist in the registry. Bootstrap CI results are not stored as registry experiments.

---

### Key Baselines

**sta-phase0-baseline** (untrained Qwen3-4B) — status=DONE, conclusion=success
- prove_rate: 0.12, mean_isr: 0.0641, isr_std: 0.1983

**sta-gt-isr-baseline** (ground truth ISR) — status=DONE, conclusion=success
- gt_mean_isr: 0.5588, gt_isr_std: 0.2582, gt_isr_median: 0.6125

---

### Experiments Still in Progress
- plan018-additive-random-b01-s43-r3: PREPARING
- plan018-additive-random-b01-s44-r2: PREPARING

### Missing Experiments (not in registry at all)
- exp1-isr-b03-s42 (500-step)
- exp1-random-b03-s42
- plan016-exec-only-s42-1000 (the actual ID is `plan016-extended-1000-s42`)

agentId: a3e1e5f1b82696fa8 (use SendMessage with to: 'a3e1e5f1b82696fa8' to continue this agent)
&lt;usage>total_tokens: 46135
tool_uses: 13
duration_ms: 173885&lt;/usage>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "fe9bcccb-b52d-499d-afc4-0eb7d21a2f2e",
  "tool_use_result": {
    "status": "completed",
    "prompt": "Extract key metrics from the registry JSON file at `/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_registry-1778856946416.txt`.\n\nThe file has schema: {result: string} where result is a JSON string that needs to be parsed.\n\nI need you to extract the following for ALL experiments with status=DONE or conclusion in [success, negative]:\n\nFor each experiment, extract:\n- exp_id\n- status\n- conclusion\n- metrics (all of them)\n- Any notes/tags\n\nFocus especially on these experiments:\n1. SFT baselines: plan009-sft-baseline-s42-1000, s43-1000, s44-1000-r3 (genuine%, PR, ISR)\n2. Exec-only s42 1000 steps: plan016 (PR, ISR)\n3. ISR β=0.3 all seeds: exp1-isr-b03-s42, s43, s44 (PR, ISR, genuine%, H7%)\n4. ISR β=0.1: plan002-additive-b01 s42 (PR, ISR)\n5. Random β=0.1: plan018-additive-random-b01 all seeds\n6. Random β=0.3: exp1-random-b03 all seeds\n7. Prolog experiments: plan006-prolog-exec all seeds\n8. Bootstrap CI results if stored\n\nUse jq and python to parse the nested JSON. Report all metrics verbatim - do not round or transform them. Return a structured summary.",
    "agentId": "a3e1e5f1b82696fa8",
    "agentType": "general-purpose",
    "content": [
      {
        "type": "text",
        "text": "Now I have all the data. Here is the structured summary:\n\n---\n\n## Complete Metrics Extraction from Registry\n\n### 1. SFT Baselines (500 and 1000 steps)\n\n**plan009-sft-baseline-s42-1000** — status=DONE, conclusion=success\n- eval_prove_rate: 0.13\n- eval_mean_isr: 0.0738, eval_isr_std: 0.2077, eval_median_isr: 0\n- eval_proved_only_isr: 0.5677\n- genuine_count: 12, genuine_rate: 0.9231\n- h7_strict_count: 0, h7_strict_rate: 0\n- h1_strict_count: 1, h1_strict_rate: 0.0769\n- h8_conjunction_collapse_count: 0, h8_conjunction_collapse_rate: 0\n- train_steps: 1000, train_final_loss: 0.0168, train_token_accuracy: 0.9955\n- by_answer_type: true PR=0.353, false PR=0.04, unknown PR=0\n\n**plan009-sft-baseline-s43-1000** — status=DONE, conclusion=success\n- prove_rate: 0.11\n- mean_isr: 0.0699, isr_std: 0.2155, median_isr: 0\n- proved_only_mean_isr: 0.6352\n- genuine_count: 10, genuine_rate: 0.9091\n- h7_strict_count: 0, h1_strict_count: 1, h8_conjunction_collapse_count: 0\n- train_final_loss: 0.0167, train_token_accuracy: 0.9954\n\n**plan009-sft-baseline-s44-1000-r3** — status=DONE, conclusion=success\n- eval_prove_rate: 0.15\n- eval_mean_isr: 0.0884, eval_isr_std: 0.2268, eval_median_isr: 0\n- eval_proved_only_isr: 0.5892\n- genuine_count: 14, genuine_rate: 0.9333\n- h1_count: 1, h1_rate: 0.0667\n- h7_count: 0, h8_conjunction_collapse_count: 0\n\n**SFT 500-step variants** (for reference):\n- plan009-sft-baseline-s43 (500 steps): PR=0.15, ISR=0.0895, genuine_rate=0.933\n- plan009-sft-baseline-s44 (500 steps): PR=0.17, ISR=0.0974, genuine_rate=0.882\n\n---\n\n### 2. Exec-only s42\n\nNo `plan016-exec-only-s42-1000` exists. The closest equivalent is:\n\n**plan016-extended-1000-s42** — status=DONE, conclusion=success\n- prove_rate: 0.96\n- isr: 0.003\n- n_proved: 96, components: 18.55\n- genuine_count: 0, genuine_rate: 0\n- h1_count: 96, h1_rate: 1\n- h7_count: 0\n\n**plan001-exec-only-s42-r2** (500 steps, full STA eval) — status=DONE, conclusion=success\n- eval_prove_rate: 0.93\n- eval_mean_isr: 0.1232, eval_isr_std: 0.1887, eval_median_isr: 0\n- eval_proved_only_isr: 0.1324\n- genuine_count: 7, genuine_rate: 0.0753\n- h1_count: 81, h1_rate: 0.871\n- h7_count: 0\n- h8_conjunction_collapse_count: 6, h8_conjunction_collapse_rate: 0.0645\n\n---\n\n### 3. ISR beta=0.3 All Seeds\n\n**No `exp1-isr-b03-s42` at 500 steps exists.** Only 1000-step variants:\n\n**exp1-isr-b03-s42-1000-r2** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.95\n- eval_mean_isr: 0.734, eval_isr_std: 0.2575, eval_median_isr: 0.6\n- eval_proved_only_isr: 0.7726\n- genuine_count: 0, genuine_rate: 0\n- h1_count: 54, h1_rate: 0.568\n- h7_count: 0, h8_conjunction_collapse_count: 41, h8_conjunction_collapse_rate: 0.432\n- isr_1_count: 41, isr_1_rate: 0.432\n- tautological_collapse: true\n- train_loss: 0.0041, train_final_entropy: 9e-06\n\n**exp1-isr-b03-s43** — status=DONE, conclusion=success (**INVALIDATED** — eval used wrong test set test_100.jsonl)\n- prove_rate: 0.91\n- mean_isr: 0.2575, isr_std: 0.2363, median_isr: 0.3333\n- proved_only_mean_isr: 0.283\n- genuine_count: 61, genuine_rate: 0.6703\n- hacking_rate_strict_h7: 0.022, hacking_rate_functional: 0.3297\n\n**exp1-isr-b03-s43-r3** (retrained, valid eval) — status=DONE, conclusion=success\n- eval_prove_rate: 0.86\n- eval_mean_isr: 0.2535, eval_isr_std: 0.2406, eval_median_isr: 0.3333\n- eval_proved_only_mean_isr: 0.2948\n- eval_genuine_count: 23, eval_genuine_rate: 0.267\n- eval_h7_strict_count: 4, eval_h7_strict_rate: 0.047\n- eval_h1_strict_count: 59, eval_h1_strict_rate: 0.686\n- eval_single_premise_count: 5, eval_single_premise_rate: 0.058\n- train_loss: 0.0176, train_runtime_sec: 4153.6\n\n**exp1-isr-b03-s44-r2** — status=DONE, conclusion=success\n- prove_rate: 0.95\n- mean_isr: 0.705, isr_std: 0.172\n- proved_only_isr: 0.7421\n- genuine_count: 0, genuine_rate: 0\n- h7_count: 95, h7_rate: 1\n- h1_count: 0\n- single_premise_rate: 1\n\n---\n\n### 4. ISR beta=0.1 (plan002)\n\n**plan002-additive-b01-s42** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.81\n- eval_mean_isr: 0.3365, eval_isr_std: 0.3227, eval_median_isr: 0.2\n- eval_proved_only_isr: 0.4154\n- genuine_count: 14, genuine_rate: 0.173\n- h1_count: 42, h1_rate: 0.519\n- h7_count: 13, h7_rate: 0.16\n- h8_conjunction_collapse_count: 12, h8_conjunction_collapse_rate: 0.148\n- tautological_collapse: false\n\n**plan002-additive-b01-s43** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.61\n- eval_proved_only_isr: 0.83\n- genuine_count: 2, genuine_rate: 0.0328\n- h7_count: 59, h7_rate: 0.9672\n- proved_single_premise_ratio: 1 (total H7 collapse)\n\n**plan002-additive-b01-s44** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.89\n- eval_mean_isr: 0.803\n- genuine_count: 0, genuine_rate: 0\n- h7_count: 89, h7_rate: 1 (complete tautological collapse)\n\n**plan002-additive-b01-s42-1000** (extended to 1000 steps) — status=DONE, conclusion=negative\n- eval_prove_rate: 0.9\n- eval_mean_isr: 0.7892, eval_median_isr: 1\n- eval_proved_only_isr: 0.8769\n- genuine_count: 1, genuine_rate: 0.0111\n- h7_count: 87, h7_rate: 0.9667\n- h8_conjunction_collapse_count: 2, h8_conjunction_collapse_rate: 0.0222\n- tautological_collapse: true\n\n---\n\n### 5. Random beta=0.1 (plan018)\n\n**plan018-additive-random-b01-s42** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.79\n- eval_mean_isr: 0.1038, eval_isr_std: 0.1369, eval_median_isr: 0.0357\n- eval_proved_only_isr: 0.1314\n- genuine_count_strict: 12, genuine_rate_strict: 0.1519\n- genuine_count_exact_h1: 23, genuine_rate_exact_h1: 0.2911\n- h1_count: 56, h1_rate: 0.7089\n- h7_count: 0\n- h8_conjunction_collapse_count: 3, h8_conjunction_collapse_rate: 0.038\n- tautological_collapse: false\n\n**plan018-additive-random-b01-s43-r3** — status=PREPARING (no metrics)\n\n**plan018-additive-random-b01-s44-r2** — status=PREPARING (no metrics)\n\n**plan018-additive-random-b01-s42-1000-r3** (1000 steps) — status=DONE, conclusion=negative\n- eval_prove_rate: 0.97\n- eval_mean_isr: 0.6892, eval_isr_std: 0.2037, eval_median_isr: 0.75\n- eval_proved_only_isr: 0.7105\n- genuine_count: 0, genuine_rate: 0\n- h1_count: 97, h1_rate: 0.97\n- tautological_collapse: true\n- n_premise_distribution: {\"1\": 97} (all single-premise P->P)\n\n---\n\n### 6. Random beta=0.3 (exp1-random-b03)\n\n**No `exp1-random-b03-s42` exists in the registry.**\n\n**exp1-random-b03-s43** — status=DONE, conclusion=success (**INVALIDATED** — eval used test_100.jsonl)\n- prove_rate: 0.79\n- mean_isr: 0.1745, isr_std: 0.1628, median_isr: 0.1667\n- proved_only_mean_isr: 0.2209\n- genuine_count: 71, genuine_rate: 0.8987\n- hacking_rate_strict_h7: 0, hacking_rate_functional: 0.1013\n\n**exp1-random-b03-s43-r4** (retrained, valid eval) — status=DONE, conclusion=success\n- eval_prove_rate: 0.92\n- eval_mean_isr: 0.1659, eval_isr_std: 0.1147, eval_median_isr: 0.1429\n- eval_proved_only_mean_isr: 0.1803\n- eval_genuine_count: 2, eval_genuine_rate: 0.022\n- eval_h1_strict_count: 90, eval_h1_strict_rate: 0.978\n- eval_h7_strict_count: 7, eval_h7_strict_rate: 0.076\n- train_loss: 0.01365\n\n**exp1-random-b03-s44-r2** — status=DONE, conclusion=success\n- eval_prove_rate: 0.23\n- eval_mean_isr: 0, eval_isr_std: 0, eval_median_isr: 0\n- eval_proved_only_mean_isr: 0\n- eval_genuine_count: 0, eval_genuine_rate: 0\n- eval_h1_strict_count: 23, eval_h1_strict_rate: 1\n\n**exp1-random-b03-s44** — status=DONE, conclusion=failed (no metrics)\n\n---\n\n### 7. Prolog Experiments (plan006)\n\n#### Prolog Exec-only:\n**plan006-prolog-exec-s42** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.83\n- eval_mean_isr: 0.031, eval_isr_std: 0.0534, eval_max_isr: 0.2, eval_median_isr: 0\n- eval_proved_only_isr: 0.037\n- h7_rate: 0, h1_rate: 0, isr_1_rate: 0, single_premise_rate: 0\n- Hacking mode: ground fact enumeration\n\n**plan006-prolog-exec-s43-r3** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.56\n- eval_mean_isr: 0.0084, eval_isr_std: 0.0221, eval_max_isr: 0.1, eval_median_isr: 0\n- eval_proved_only_isr: 0.015\n\n**plan006-prolog-exec-s44** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.21\n- eval_mean_isr: 0.0812, eval_isr_std: 0.2343, eval_max_isr: 1, eval_median_isr: 0\n- eval_proved_only_isr: 0.3866\n\n#### Prolog STA (exec+ISR):\n**plan006-prolog-sta-s42** — status=DONE, conclusion=negative\n- eval_prove_rate: 0.5\n- eval_mean_isr: 0.5, eval_proved_only_isr: 1\n- eval_h7_count: 50, eval_h7_rate: 1 (complete H7 collapse, binary ISR: 50x0 + 50x1)\n\n**plan006-prolog-sta-s43** — status=DONE, conclusion=negative\n- eval prove_rate: 0.38\n- eval mean_isr: 0.0704, proved_only_mean_isr: 0.1853\n- h7_classification: h7_strict=0, h1_strict=37 (0.974), genuine_count=0 (functional tautological)\n\n**plan006-prolog-sta-s44** — status=DONE, conclusion=negative\n- pass_rate: 0.97\n- isr_mean: 0.885\n- genuine_rate: 0, h7_functional_rate: 0.979\n- Failure mode: \"query-as-fact gaming (total H7 collapse)\"\n\n---\n\n### 8. Bootstrap CI\n\nNo experiments with \"bootstrap\" or \"ci\" in their ID exist in the registry. Bootstrap CI results are not stored as registry experiments.\n\n---\n\n### Key Baselines\n\n**sta-phase0-baseline** (untrained Qwen3-4B) — status=DONE, conclusion=success\n- prove_rate: 0.12, mean_isr: 0.0641, isr_std: 0.1983\n\n**sta-gt-isr-baseline** (ground truth ISR) — status=DONE, conclusion=success\n- gt_mean_isr: 0.5588, gt_isr_std: 0.2582, gt_isr_median: 0.6125\n\n---\n\n### Experiments Still in Progress\n- plan018-additive-random-b01-s43-r3: PREPARING\n- plan018-additive-random-b01-s44-r2: PREPARING\n\n### Missing Experiments (not in registry at all)\n- exp1-isr-b03-s42 (500-step)\n- exp1-random-b03-s42\n- plan016-exec-only-s42-1000 (the actual ID is `plan016-extended-1000-s42`)"
      }
    ],
    "totalDurationMs": 173885,
    "totalTokens": 46135,
    "totalToolUseCount": 13,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2178,
      "cache_read_input_tokens": 39696,
      "output_tokens": 4260,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2178
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4260,
          "cache_read_input_tokens": 39696,
          "cache_creation_input_tokens": 2178,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2178,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 2,
      "searchCount": 0,
      "bashCount": 11,
      "editFileCount": 0,
      "linesAdded": 0,
      "linesRemoved": 0,
      "otherToolCount": 0
    }
  }
}
```

</details>

---


### Tool result

_source line 68 · 2026-05-15T14:59:00.127Z_

<details><summary>↩ Tool result · `toolu_01MX5KtVAwrAECCuP2ALuraT`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\begin{abstract}\\nGRPO-trained neurosymbolic formalizers achieve high prove rates---93\\\\% on FOLIO---yet 87\\\\% of proved outputs embed the conclusion verbatim among the premises, a degenerate shortcut invisible to execution reward.\\nWe introduce \\\\emph{Solver Trace Ablation} (STA), a diagnostic that applies leave-one-out component necessity testing to solver inputs.\\nThe fraction of components whose removal causes proof failure yields the \\\\emph{Intensional Structural Reward} (ISR): ISR$=$1 indicates full necessity; ISR$=$0 complete redundancy.\\nISR is uncorrelated with downstream NLI accuracy ($\\\\rho{=}{-}0.049$), confirming it measures structural---not semantic---integrity.\\nAs a diagnostic, ISR exposes a collapse trajectory hidden from PR: over 100--1000 GRPO steps (Qwen3-4B), ISR falls $0.642{\\\\to}0.003$ while PR rises $32\\\\%{\\\\to}96\\\\%$; an SFT baseline reaches 92.9\\\\% non-hacking on identical data, localizing the failure to RL.\\nAs a reward, $r = r_{\\\\text{exec}}\\\\cdot(1{+}\\\\beta\\\\,\\\\text{ISR})$ at $\\\\beta{=}0.1$ induces \\\\emph{meta-level Goodhart's Law}: 64.5\\\\% conclusion duplication (H7) versus 0\\\\% under matched random; the sole apparent ISR improvement reduces to $1.06\\\\times$ after controlling for a premise-count confound; $\\\\beta{=}0.3$ destabilizes training regardless of signal source (ISR: PR $66{\\\\pm}42\\\\%$; random: $54{\\\\pm}35\\\\%$), with individual seeds collapsing to as low as $18\\\\%$.\\nCross-logic transfer to Prolog yields universal Goodhart: 3/3 seeds gaming via distinct mechanisms, 0\\\\% non-hacking.\\nAcross 6 reward conditions, 2 logic types, 3 seeds, we catalog 7 hacking modes---including query-as-fact gaming that bypasses text-match classifiers---documenting ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\\\footnote{Code and data: \\\\url{[anonymized]}}\\n\\\\end{abstract}\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.48}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "bc656062-8244-447c-bd8b-5c062a626203",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\begin{abstract}\\\\nGRPO-trained neurosymbolic formalizers achieve high prove rates---93\\\\\\\\% on FOLIO---yet 87\\\\\\\\% of proved outputs embed the conclusion verbatim among the premises, a degenerate shortcut invisible to execution reward.\\\\nWe introduce \\\\\\\\emph{Solver Trace Ablation} (STA), a diagnostic that applies leave-one-out component necessity testing to solver inputs.\\\\nThe fraction of components whose removal causes proof failure yields the \\\\\\\\emph{Intensional Structural Reward} (ISR): ISR$=$1 indicates full necessity; ISR$=$0 complete redundancy.\\\\nISR is uncorrelated with downstream NLI accuracy ($\\\\\\\\rho{=}{-}0.049$), confirming it measures structural---not semantic---integrity.\\\\nAs a diagnostic, ISR exposes a collapse trajectory hidden from PR: over 100--1000 GRPO steps (Qwen3-4B), ISR falls $0.642{\\\\\\\\to}0.003$ while PR rises $32\\\\\\\\%{\\\\\\\\to}96\\\\\\\\%$; an SFT baseline reaches 92.9\\\\\\\\% non-hacking on identical data, localizing the failure to RL.\\\\nAs a reward, $r = r_{\\\\\\\\text{exec}}\\\\\\\\cdot(1{+}\\\\\\\\beta\\\\\\\\,\\\\\\\\text{ISR})$ at $\\\\\\\\beta{=}0.1$ induces \\\\\\\\emph{meta-level Goodhart's Law}: 64.5\\\\\\\\% conclusion duplication (H7) versus 0\\\\\\\\% under matched random; the sole apparent ISR improvement reduces to $1.06\\\\\\\\times$ after controlling for a premise-count confound; $\\\\\\\\beta{=}0.3$ destabilizes training regardless of signal source (ISR: PR $66{\\\\\\\\pm}42\\\\\\\\%$; random: $54{\\\\\\\\pm}35\\\\\\\\%$), with individual seeds collapsing to as low as $18\\\\\\\\%$.\\\\nCross-logic transfer to Prolog yields universal Goodhart: 3/3 seeds gaming via distinct mechanisms, 0\\\\\\\\% non-hacking.\\\\nAcross 6 reward conditions, 2 logic types, 3 seeds, we catalog 7 hacking modes---including query-as-fact gaming that bypasses text-match classifiers---documenting ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\\\\\\\footnote{Code and data: \\\\\\\\url{[anonymized]}}\\\\n\\\\\\\\end{abstract}\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.48}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\begin{abstract}\\nGRPO-trained neurosymbolic formalizers achieve high prove rates---93\\\\% on FOLIO---yet 87\\\\% of proved outputs embed the conclusion verbatim among the premises, a degenerate shortcut invisible to execution reward.\\nWe introduce \\\\emph{Solver Trace Ablation} (STA), a diagnostic that applies leave-one-out component necessity testing to solver inputs.\\nThe fraction of components whose removal causes proof failure yields the \\\\emph{Intensional Structural Reward} (ISR): ISR$=$1 indicates full necessity; ISR$=$0 complete redundancy.\\nISR is uncorrelated with downstream NLI accuracy ($\\\\rho{=}{-}0.049$), confirming it measures structural---not semantic---integrity.\\nAs a diagnostic, ISR exposes a collapse trajectory hidden from PR: over 100--1000 GRPO steps (Qwen3-4B), ISR falls $0.642{\\\\to}0.003$ while PR rises $32\\\\%{\\\\to}96\\\\%$; an SFT baseline reaches 92.9\\\\% non-hacking on identical data, localizing the failure to RL.\\nAs a reward, $r = r_{\\\\text{exec}}\\\\cdot(1{+}\\\\beta\\\\,\\\\text{ISR})$ at $\\\\beta{=}0.1$ induces \\\\emph{meta-level Goodhart's Law}: 64.5\\\\% conclusion duplication (H7) versus 0\\\\% under matched random; the sole apparent ISR improvement reduces to $1.06\\\\times$ after controlling for a premise-count confound; $\\\\beta{=}0.3$ destabilizes training regardless of signal source (ISR: PR $66{\\\\pm}42\\\\%$; random: $54{\\\\pm}35\\\\%$), with individual seeds collapsing to as low as $18\\\\%$.\\nCross-logic transfer to Prolog yields universal Goodhart: 3/3 seeds gaming via distinct mechanisms, 0\\\\% non-hacking.\\nAcross 6 reward conditions, 2 logic types, 3 seeds, we catalog 7 hacking modes---including query-as-fact gaming that bypasses text-match classifiers---documenting ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\\\footnote{Code and data: \\\\url{[anonymized]}}\\n\\\\end{abstract}\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.48}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 69 · 2026-05-15T14:59:00.656Z_

<details><summary>↩ Tool result · `toolu_01G8UTLu5iXr1EaWXPt5BnuH`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Introduction}\\n\\\\label{sec:introduction}\\n\\nA GRPO-trained formalizer achieves a 93\\\\% prove rate on first-order logic problems---yet 87\\\\% of its proved outputs embed the conclusion verbatim among the premises.\\nThe solver succeeds not because the model has learned to reason, but because the formalization trivially entails any conclusion already appearing as a premise.\\nThis structural shortcut is invisible to execution-based evaluation: prove rate registers success regardless of whether the proof reflects genuine derivation or degenerate circular embedding.\\n\\n\\\\paragraph{The execution-only blind spot.}\\nProve rate---the dominant evaluation metric for neurosymbolic formalizers~\\\\citep{logic-lm, linc, satlm}---conflates faithful reasoning with degenerate shortcuts, a gap especially consequential under RL, where the optimizer exploits any shortcut the reward fails to penalize~\\\\citep{skalse-reward-hacking, reward-hacking-survey}.\\nRecent work applies GRPO~\\\\citep{deepseekmath} to train LLMs that generate solver-verified formal programs~\\\\citep{mellgren-prolog-grpo, logic-rl} using binary execution feedback; this drives rapid PR gains but gives no gradient on structural quality.\\nProcess reward models~\\\\citep{lightman-verify-step, math-shepherd} require expensive annotations and do not transfer to arbitrary solver-backed settings.\\nA separate line documents that LLMs already game logical formalization at inference time~\\\\citep{kim-game-formalization, bondarenko-spec-gaming}; what is missing is an annotation-free \\\\emph{diagnostic} for structural integrity in neurosymbolic outputs.\\n\\n\\\\paragraph{Component necessity testing.}\\nWe address this gap with \\\\emph{Solver Trace Ablation} (STA), a diagnostic applying \\\\emph{component necessity testing}---leave-one-out (LOO) ablation on solver inputs---to quantify structural integrity (\\\\autoref{fig:sta-overview}).\\nFor each proved formalization, STA removes each component individually and re-runs the solver; the fraction of components whose removal causes proof failure yields the \\\\emph{Intensional Structural Reward} (ISR), with $\\\\text{ISR}{=}1$ indicating full necessity and $\\\\text{ISR}{=}0$ complete redundancy.\\nLOO ablation itself is standard~\\\\citep{demillo1978, jia-harman-survey}; novelty lies in its application as a GRPO-hacking diagnostic and in the empirical phenomena it surfaces.\\nISR captures structural rather than semantic integrity (downstream NLI: $\\\\rho{=}{-}0.049$, $p{=}0.187$).\\n\\n\\\\paragraph{ISR as diagnostic.}\\nAs a post-hoc diagnostic on a GRPO formalizer trained with FOLIO~\\\\citep{folio}, ISR reveals a structural collapse trajectory invisible to PR: $\\\\text{ISR}^{*}{:}\\\\,0.642\\\\to 0.132\\\\to 0.003$ over 100--1000 steps (99.5\\\\% degradation) while PR rises $32\\\\%{\\\\to}96\\\\%$.\\nThree seeds diverge radically (PR $\\\\sigma{=}\\\\pm47$\\\\,pp), each converging to a qualitatively different mode: conclusion embedding, repetition collapse, and tautological collapse.\\nAn SFT baseline on identical data reaches $\\\\text{PR}{=}14\\\\%$ with 92.9\\\\% non-hacking, localizing the failure to RL optimization, not data or capacity.\\n\\n\\\\paragraph{Meta-level Goodhart.}\\nRepurposed as a training signal, $r = r_{\\\\text{exec}} \\\\cdot (1 + \\\\beta\\\\,\\\\text{ISR})$, ISR is gamed at its own definition---\\\\emph{meta-level Goodhart's Law}~\\\\citep{manheim-goodhart-taxonomy, karwowski-goodhart-rl, gao-reward-overoptimization}.\\nAt $\\\\beta{=}0.1$, 64.5\\\\% of proved samples exhibit single-premise-equals-conclusion duplication---ISR high \\\\emph{by definition}---versus 0\\\\% under matched random; the one seed with non-trivial residual reduces to $1.06\\\\times$ random after controlling for a premise-count confound.\\nAt $\\\\beta{=}0.3$, both ISR and random produce extreme cross-seed instability (PR $66{\\\\pm}42\\\\%$ and $54{\\\\pm}35\\\\%$ respectively), confirming high-dose proxy weighting is harmful regardless of signal content; ISR seeds diverge into three distinct pathways (reward collapse, shortcut dominance, pure metric gaming) while random converges uniformly to H1.\\nThe effect transfers and intensifies in Prolog: 3/3 seeds yield 0\\\\% non-hacking via distinct mechanisms, including \\\\emph{query-as-fact gaming} that bypasses text-match classifiers.\\nISR's asymmetry is the central finding: \\\\emph{reliable as observer, unreliable as optimizer.}\\n\\n\\\\paragraph{Contributions.}\\nAcross 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 steps, we contribute: (\\\\textbf{C1}) ISR as a diagnostic for GRPO reward hacking, with a 99.5\\\\% collapse trajectory invisible to PR and an SFT control localizing the failure to RL (\\\\S\\\\ref{sec:diagnostic}); (\\\\textbf{C2}) empirical meta-level Goodhart, with a random control isolating ISR-specific gaming (64.5\\\\% vs.\\\\ 0\\\\%) and a premise-count-matched analysis showing the sole apparent gain is an LOO artifact (\\\\S\\\\ref{sec:goodhart}); (\\\\textbf{C3}) cross-logic transfer to Prolog with universal Goodhart (\\\\S\\\\ref{sec:crosslogic}); (\\\\textbf{C4}) a seven-mode hacking taxonomy including query-as-fact gaming, motivating functional cross-validation of diagnostics (\\\\S\\\\ref{sec:taxonomy}).\\nThese are cautionary results for any work treating a structural proxy as a training signal.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.48}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "6deec3ea-7461-4682-babb-9752716342ce",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Introduction}\\\\n\\\\\\\\label{sec:introduction}\\\\n\\\\nA GRPO-trained formalizer achieves a 93\\\\\\\\% prove rate on first-order logic problems---yet 87\\\\\\\\% of its proved outputs embed the conclusion verbatim among the premises.\\\\nThe solver succeeds not because the model has learned to reason, but because the formalization trivially entails any conclusion already appearing as a premise.\\\\nThis structural shortcut is invisible to execution-based evaluation: prove rate registers success regardless of whether the proof reflects genuine derivation or degenerate circular embedding.\\\\n\\\\n\\\\\\\\paragraph{The execution-only blind spot.}\\\\nProve rate---the dominant evaluation metric for neurosymbolic formalizers~\\\\\\\\citep{logic-lm, linc, satlm}---conflates faithful reasoning with degenerate shortcuts, a gap especially consequential under RL, where the optimizer exploits any shortcut the reward fails to penalize~\\\\\\\\citep{skalse-reward-hacking, reward-hacking-survey}.\\\\nRecent work applies GRPO~\\\\\\\\citep{deepseekmath} to train LLMs that generate solver-verified formal programs~\\\\\\\\citep{mellgren-prolog-grpo, logic-rl} using binary execution feedback; this drives rapid PR gains but gives no gradient on structural quality.\\\\nProcess reward models~\\\\\\\\citep{lightman-verify-step, math-shepherd} require expensive annotations and do not transfer to arbitrary solver-backed settings.\\\\nA separate line documents that LLMs already game logical formalization at inference time~\\\\\\\\citep{kim-game-formalization, bondarenko-spec-gaming}; what is missing is an annotation-free \\\\\\\\emph{diagnostic} for structural integrity in neurosymbolic outputs.\\\\n\\\\n\\\\\\\\paragraph{Component necessity testing.}\\\\nWe address this gap with \\\\\\\\emph{Solver Trace Ablation} (STA), a diagnostic applying \\\\\\\\emph{component necessity testing}---leave-one-out (LOO) ablation on solver inputs---to quantify structural integrity (\\\\\\\\autoref{fig:sta-overview}).\\\\nFor each proved formalization, STA removes each component individually and re-runs the solver; the fraction of components whose removal causes proof failure yields the \\\\\\\\emph{Intensional Structural Reward} (ISR), with $\\\\\\\\text{ISR}{=}1$ indicating full necessity and $\\\\\\\\text{ISR}{=}0$ complete redundancy.\\\\nLOO ablation itself is standard~\\\\\\\\citep{demillo1978, jia-harman-survey}; novelty lies in its application as a GRPO-hacking diagnostic and in the empirical phenomena it surfaces.\\\\nISR captures structural rather than semantic integrity (downstream NLI: $\\\\\\\\rho{=}{-}0.049$, $p{=}0.187$).\\\\n\\\\n\\\\\\\\paragraph{ISR as diagnostic.}\\\\nAs a post-hoc diagnostic on a GRPO formalizer trained with FOLIO~\\\\\\\\citep{folio}, ISR reveals a structural collapse trajectory invisible to PR: $\\\\\\\\text{ISR}^{*}{:}\\\\\\\\,0.642\\\\\\\\to 0.132\\\\\\\\to 0.003$ over 100--1000 steps (99.5\\\\\\\\% degradation) while PR rises $32\\\\\\\\%{\\\\\\\\to}96\\\\\\\\%$.\\\\nThree seeds diverge radically (PR $\\\\\\\\sigma{=}\\\\\\\\pm47$\\\\\\\\,pp), each converging to a qualitatively different mode: conclusion embedding, repetition collapse, and tautological collapse.\\\\nAn SFT baseline on identical data reaches $\\\\\\\\text{PR}{=}14\\\\\\\\%$ with 92.9\\\\\\\\% non-hacking, localizing the failure to RL optimization, not data or capacity.\\\\n\\\\n\\\\\\\\paragraph{Meta-level Goodhart.}\\\\nRepurposed as a training signal, $r = r_{\\\\\\\\text{exec}} \\\\\\\\cdot (1 + \\\\\\\\beta\\\\\\\\,\\\\\\\\text{ISR})$, ISR is gamed at its own definition---\\\\\\\\emph{meta-level Goodhart's Law}~\\\\\\\\citep{manheim-goodhart-taxonomy, karwowski-goodhart-rl, gao-reward-overoptimization}.\\\\nAt $\\\\\\\\beta{=}0.1$, 64.5\\\\\\\\% of proved samples exhibit single-premise-equals-conclusion duplication---ISR high \\\\\\\\emph{by definition}---versus 0\\\\\\\\% under matched random; the one seed with non-trivial residual reduces to $1.06\\\\\\\\times$ random after controlling for a premise-count confound.\\\\nAt $\\\\\\\\beta{=}0.3$, both ISR and random produce extreme cross-seed instability (PR $66{\\\\\\\\pm}42\\\\\\\\%$ and $54{\\\\\\\\pm}35\\\\\\\\%$ respectively), confirming high-dose proxy weighting is harmful regardless of signal content; ISR seeds diverge into three distinct pathways (reward collapse, shortcut dominance, pure metric gaming) while random converges uniformly to H1.\\\\nThe effect transfers and intensifies in Prolog: 3/3 seeds yield 0\\\\\\\\% non-hacking via distinct mechanisms, including \\\\\\\\emph{query-as-fact gaming} that bypasses text-match classifiers.\\\\nISR's asymmetry is the central finding: \\\\\\\\emph{reliable as observer, unreliable as optimizer.}\\\\n\\\\n\\\\\\\\paragraph{Contributions.}\\\\nAcross 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 steps, we contribute: (\\\\\\\\textbf{C1}) ISR as a diagnostic for GRPO reward hacking, with a 99.5\\\\\\\\% collapse trajectory invisible to PR and an SFT control localizing the failure to RL (\\\\\\\\S\\\\\\\\ref{sec:diagnostic}); (\\\\\\\\textbf{C2}) empirical meta-level Goodhart, with a random control isolating ISR-specific gaming (64.5\\\\\\\\% vs.\\\\\\\\ 0\\\\\\\\%) and a premise-count-matched analysis showing the sole apparent gain is an LOO artifact (\\\\\\\\S\\\\\\\\ref{sec:goodhart}); (\\\\\\\\textbf{C3}) cross-logic transfer to Prolog with universal Goodhart (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}); (\\\\\\\\textbf{C4}) a seven-mode hacking taxonomy including query-as-fact gaming, motivating functional cross-validation of diagnostics (\\\\\\\\S\\\\\\\\ref{sec:taxonomy}).\\\\nThese are cautionary results for any work treating a structural proxy as a training signal.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.48}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Introduction}\\n\\\\label{sec:introduction}\\n\\nA GRPO-trained formalizer achieves a 93\\\\% prove rate on first-order logic problems---yet 87\\\\% of its proved outputs embed the conclusion verbatim among the premises.\\nThe solver succeeds not because the model has learned to reason, but because the formalization trivially entails any conclusion already appearing as a premise.\\nThis structural shortcut is invisible to execution-based evaluation: prove rate registers success regardless of whether the proof reflects genuine derivation or degenerate circular embedding.\\n\\n\\\\paragraph{The execution-only blind spot.}\\nProve rate---the dominant evaluation metric for neurosymbolic formalizers~\\\\citep{logic-lm, linc, satlm}---conflates faithful reasoning with degenerate shortcuts, a gap especially consequential under RL, where the optimizer exploits any shortcut the reward fails to penalize~\\\\citep{skalse-reward-hacking, reward-hacking-survey}.\\nRecent work applies GRPO~\\\\citep{deepseekmath} to train LLMs that generate solver-verified formal programs~\\\\citep{mellgren-prolog-grpo, logic-rl} using binary execution feedback; this drives rapid PR gains but gives no gradient on structural quality.\\nProcess reward models~\\\\citep{lightman-verify-step, math-shepherd} require expensive annotations and do not transfer to arbitrary solver-backed settings.\\nA separate line documents that LLMs already game logical formalization at inference time~\\\\citep{kim-game-formalization, bondarenko-spec-gaming}; what is missing is an annotation-free \\\\emph{diagnostic} for structural integrity in neurosymbolic outputs.\\n\\n\\\\paragraph{Component necessity testing.}\\nWe address this gap with \\\\emph{Solver Trace Ablation} (STA), a diagnostic applying \\\\emph{component necessity testing}---leave-one-out (LOO) ablation on solver inputs---to quantify structural integrity (\\\\autoref{fig:sta-overview}).\\nFor each proved formalization, STA removes each component individually and re-runs the solver; the fraction of components whose removal causes proof failure yields the \\\\emph{Intensional Structural Reward} (ISR), with $\\\\text{ISR}{=}1$ indicating full necessity and $\\\\text{ISR}{=}0$ complete redundancy.\\nLOO ablation itself is standard~\\\\citep{demillo1978, jia-harman-survey}; novelty lies in its application as a GRPO-hacking diagnostic and in the empirical phenomena it surfaces.\\nISR captures structural rather than semantic integrity (downstream NLI: $\\\\rho{=}{-}0.049$, $p{=}0.187$).\\n\\n\\\\paragraph{ISR as diagnostic.}\\nAs a post-hoc diagnostic on a GRPO formalizer trained with FOLIO~\\\\citep{folio}, ISR reveals a structural collapse trajectory invisible to PR: $\\\\text{ISR}^{*}{:}\\\\,0.642\\\\to 0.132\\\\to 0.003$ over 100--1000 steps (99.5\\\\% degradation) while PR rises $32\\\\%{\\\\to}96\\\\%$.\\nThree seeds diverge radically (PR $\\\\sigma{=}\\\\pm47$\\\\,pp), each converging to a qualitatively different mode: conclusion embedding, repetition collapse, and tautological collapse.\\nAn SFT baseline on identical data reaches $\\\\text{PR}{=}14\\\\%$ with 92.9\\\\% non-hacking, localizing the failure to RL optimization, not data or capacity.\\n\\n\\\\paragraph{Meta-level Goodhart.}\\nRepurposed as a training signal, $r = r_{\\\\text{exec}} \\\\cdot (1 + \\\\beta\\\\,\\\\text{ISR})$, ISR is gamed at its own definition---\\\\emph{meta-level Goodhart's Law}~\\\\citep{manheim-goodhart-taxonomy, karwowski-goodhart-rl, gao-reward-overoptimization}.\\nAt $\\\\beta{=}0.1$, 64.5\\\\% of proved samples exhibit single-premise-equals-conclusion duplication---ISR high \\\\emph{by definition}---versus 0\\\\% under matched random; the one seed with non-trivial residual reduces to $1.06\\\\times$ random after controlling for a premise-count confound.\\nAt $\\\\beta{=}0.3$, both ISR and random produce extreme cross-seed instability (PR $66{\\\\pm}42\\\\%$ and $54{\\\\pm}35\\\\%$ respectively), confirming high-dose proxy weighting is harmful regardless of signal content; ISR seeds diverge into three distinct pathways (reward collapse, shortcut dominance, pure metric gaming) while random converges uniformly to H1.\\nThe effect transfers and intensifies in Prolog: 3/3 seeds yield 0\\\\% non-hacking via distinct mechanisms, including \\\\emph{query-as-fact gaming} that bypasses text-match classifiers.\\nISR's asymmetry is the central finding: \\\\emph{reliable as observer, unreliable as optimizer.}\\n\\n\\\\paragraph{Contributions.}\\nAcross 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 steps, we contribute: (\\\\textbf{C1}) ISR as a diagnostic for GRPO reward hacking, with a 99.5\\\\% collapse trajectory invisible to PR and an SFT control localizing the failure to RL (\\\\S\\\\ref{sec:diagnostic}); (\\\\textbf{C2}) empirical meta-level Goodhart, with a random control isolating ISR-specific gaming (64.5\\\\% vs.\\\\ 0\\\\%) and a premise-count-matched analysis showing the sole apparent gain is an LOO artifact (\\\\S\\\\ref{sec:goodhart}); (\\\\textbf{C3}) cross-logic transfer to Prolog with universal Goodhart (\\\\S\\\\ref{sec:crosslogic}); (\\\\textbf{C4}) a seven-mode hacking taxonomy including query-as-fact gaming, motivating functional cross-validation of diagnostics (\\\\S\\\\ref{sec:taxonomy}).\\nThese are cautionary results for any work treating a structural proxy as a training signal.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.48}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 70 · 2026-05-15T14:59:01.190Z_

<details><summary>↩ Tool result · `toolu_01AbT2TYZTcZtEqDgSfRjPxJ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Experiments}\\n\\\\label{sec:experiments}\\n\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\S\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\S\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\S\\\\ref{sec:crosslogic}).\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\S\\\\ref{sec:taxonomy}).\\n\\n\\\\subsection{Setup}\\\\label{sec:setup}\\n\\nWe train Qwen3-4B~\\\\citep{qwen3} with GRPO~\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\{42,43,44\\\\}$ on a fixed 500-example FOLIO~\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\footnote{All experiments use \\\\texttt{data/train\\\\_500\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\nHeld-out evaluation uses 100 FOLIO examples (\\\\texttt{proofwriter\\\\_fol\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\texttt{eval\\\\_sta.py}) so training-log ISR is never compared across runs.\\nWe report prove rate (PR), proved-only ISR ($\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution; \\\\S\\\\ref{sec:taxonomy-method}), and a \\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\n\\n\\\\subsection{ISR as Diagnostic}\\n\\\\label{sec:diagnostic}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.95\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\n\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\%$\\\\to$93\\\\%$\\\\to$96\\\\% while proved-only ISR falls $0.642{\\\\to}0.132{\\\\to}0.003$ over 100$\\\\to$500$\\\\to$1000 steps. By step 1000, 94.8\\\\% of proved samples have $\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\to$18.55 (contradiction explosion).}\\n\\\\label{fig:isr-collapse}\\n\\\\end{figure}\\n\\n\\\\textbf{Collapse trajectory.}\\nFigure~\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\nPR rises $32\\\\%\\\\to93\\\\%\\\\to96\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\to0.132\\\\to0.003$ (214$\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\nBy 500 steps, 87.1\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\% and mean component count more than doubles ($6.58\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\nExtended training, lacking a structural signal, \\\\emph{worsens} formalization quality while improving the headline number.\\n\\n\\\\textbf{Cross-seed instability.}\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\ref{app:detailed-results}): s42 reaches $\\\\text{PR}{=}93\\\\%$ via conclusion embedding ($\\\\text{H1}{=}87\\\\%$); s43 collapses to $\\\\text{PR}{=}14\\\\%$ via repetition (87\\\\% of rollouts truncated); s44 reaches $\\\\text{PR}{=}98\\\\%$ via tautological collapse ($\\\\text{H7}{=}100\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\nThe cross-seed PR variance ($\\\\sigma{\\\\pm}47$\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\n\\n\\\\textbf{SFT baseline.}\\nSFT on gold formalizations reaches $\\\\text{PR}{=}14\\\\%$ with $\\\\text{ISR}^{*}{=}0.571$, $\\\\text{H7}{=}0$, $\\\\text{H1}{=}7.1\\\\%$, $92.9\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\nA 100-step RL checkpoint (Appendi\\n\\n... [截断: 输出过长，省略 6955 字符] ...\\n\\n tautologies ($\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\nSeed~43: \\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\texttt{MARY\\\\_IS\\\\_AN\\\\_AVA\\\\-DEOTE.}); strict text-match returns $\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\nSeed~44: \\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\texttt{is\\\\_the\\\\_dog\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\nSeed~44 evaded our initial strict classifier (reported $100\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\n\\n\\\\subsection{Hacking Taxonomy}\\n\\\\label{sec:taxonomy}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\n\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\n\\\\label{fig:hacking-composition}\\n\\\\end{figure}\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lccccc}\\n\\\\toprule\\n\\\\textbf{Mode} & \\\\textbf{Exec} & \\\\textbf{ISR$_{.1}$} & \\\\textbf{Rnd$_{.1}$} & \\\\textbf{SFT} & \\\\textbf{Prolog$_{\\\\text{ISR}}$} \\\\\\\\\\n\\\\midrule\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\sharp$ \\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\sharp$ \\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\nCmplx.\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\n\\\\midrule\\n\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\textbf{93} & \\\\textbf{0} \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Seven hacking modes across conditions (\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\sharp$Prolog row pools strict+functional (\\\\S\\\\ref{sec:crosslogic}).}\\n\\\\label{tab:hacking-taxonomy}\\n\\\\end{table}\\n\\nThe seven modes (Table~\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\ref{app:hacking-modes}) span the studied conditions.\\nTwo are quantifiable across all conditions: \\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\%$ regardless of reward type, and \\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\%$ vs.\\\\ $0\\\\%$ in random controls.\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\n\\nThe cross-condition pattern is consistent with \\\\S\\\\ref{sec:goodhart}: \\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\nExec-only, ISR, and random conditions all show $\\\\geq 80\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\%$ non-hacking.\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\beta{=}0.1$ s42 at $\\\\text{PR}{=}81\\\\%$, $31\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "502c8fe8-a1aa-4593-bc6b-b5c824235686",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Experiments}\\\\n\\\\\\\\label{sec:experiments}\\\\n\\\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\\\\\S\\\\\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\\\\\S\\\\\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).\\\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\\\\\S\\\\\\\\ref{sec:taxonomy}).\\\\n\\\\n\\\\\\\\subsection{Setup}\\\\\\\\label{sec:setup}\\\\n\\\\nWe train Qwen3-4B~\\\\\\\\citep{qwen3} with GRPO~\\\\\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\\\\\{42,43,44\\\\\\\\}$ on a fixed 500-example FOLIO~\\\\\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\\\\\footnote{All experiments use \\\\\\\\texttt{data/train\\\\\\\\_500\\\\\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\\\nHeld-out evaluation uses 100 FOLIO examples (\\\\\\\\texttt{proofwriter\\\\\\\\_fol\\\\\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\\\\\texttt{eval\\\\\\\\_sta.py}) so training-log ISR is never compared across runs.\\\\nWe report prove rate (PR), proved-only ISR ($\\\\\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\\\\\text{necessary}}$ distribution; \\\\\\\\S\\\\\\\\ref{sec:taxonomy-method}), and a \\\\\\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\\\n\\\\n\\\\\\\\subsection{ISR as Diagnostic}\\\\n\\\\\\\\label{sec:diagnostic}\\\\n\\\\n\\\\\\\\begin{figure}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.95\\\\\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\\\n\\\\\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\\\\\%$\\\\\\\\to$93\\\\\\\\%$\\\\\\\\to$96\\\\\\\\% while proved-only ISR falls $0.642{\\\\\\\\to}0.132{\\\\\\\\to}0.003$ over 100$\\\\\\\\to$500$\\\\\\\\to$1000 steps. By step 1000, 94.8\\\\\\\\% of proved samples have $\\\\\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\\\\\to$18.55 (contradiction explosion).}\\\\n\\\\\\\\label{fig:isr-collapse}\\\\n\\\\\\\\end{figure}\\\\n\\\\n\\\\\\\\textbf{Collapse trajectory.}\\\\nFigure~\\\\\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\\\nPR rises $32\\\\\\\\%\\\\\\\\to93\\\\\\\\%\\\\\\\\to96\\\\\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\\\\\to0.132\\\\\\\\to0.003$ (214$\\\\\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\\\nBy 500 steps, 87.1\\\\\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\\\\\% and mean component count more than doubles ($6.58\\\\\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\\\nExtended training, lacking a structural signal, \\\\\\\\emph{worsens} formalization quality while improving the headline number.\\\\n\\\\n\\\\\\\\textbf{Cross-seed instability.}\\\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\\\\\ref{app:detailed-results}): s42 reaches $\\\\\\\\text{PR}{=}93\\\\\\\\%$ via conclusion embedding ($\\\\\\\\text{H1}{=}87\\\\\\\\%$); s43 collapses to $\\\\\\\\text{PR}{=}14\\\\\\\\%$ via repetition (87\\\\\\\\% of rollouts truncated); s44 reaches $\\\\\\\\text{PR}{=}98\\\\\\\\%$ via tautological collapse ($\\\\\\\\text{H7}{=}100\\\\\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\\\nThe cross-seed PR variance ($\\\\\\\\sigma{\\\\\\\\pm}47$\\\\\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\\\n\\\\n\\\\\\\\textbf{SFT baseline.}\\\\nSFT on gold formalizations reaches $\\\\\\\\text{PR}{=}14\\\\\\\\%$ with $\\\\\\\\text{ISR}^{*}{=}0.571$, $\\\\\\\\text{H7}{=}0$, $\\\\\\\\text{H1}{=}7.1\\\\\\\\%$, $92.9\\\\\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\\\nA 100-step RL checkpoint (Appendi\\\\n\\\\n... [截断: 输出过长，省略 6955 字符] ...\\\\n\\\\n tautologies ($\\\\\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\\\nSeed~43: \\\\\\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\\\\\texttt{MARY\\\\\\\\_IS\\\\\\\\_AN\\\\\\\\_AVA\\\\\\\\-DEOTE.}); strict text-match returns $\\\\\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\\\nSeed~44: \\\\\\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\\\\\texttt{is\\\\\\\\_the\\\\\\\\_dog\\\\\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\\\nSeed~44 evaded our initial strict classifier (reported $100\\\\\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\\\n\\\\n\\\\\\\\subsection{Hacking Taxonomy}\\\\n\\\\\\\\label{sec:taxonomy}\\\\n\\\\n\\\\\\\\begin{figure}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.92\\\\\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\\\n\\\\\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\\\n\\\\\\\\label{fig:hacking-composition}\\\\n\\\\\\\\end{figure}\\\\n\\\\n\\\\\\\\begin{table}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\small\\\\n\\\\\\\\resizebox{\\\\\\\\columnwidth}{!}{%\\\\n\\\\\\\\begin{tabular}{lccccc}\\\\n\\\\\\\\toprule\\\\n\\\\\\\\textbf{Mode} & \\\\\\\\textbf{Exec} & \\\\\\\\textbf{ISR$_{.1}$} & \\\\\\\\textbf{Rnd$_{.1}$} & \\\\\\\\textbf{SFT} & \\\\\\\\textbf{Prolog$_{\\\\\\\\text{ISR}}$} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\\\\\sharp$ \\\\\\\\\\\\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\\\\\sharp$ \\\\\\\\\\\\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\\\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\\\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\\\\\\\\\\\nCmplx.\\\\\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\\\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\\\\\textbf{93} & \\\\\\\\textbf{0} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\bottomrule\\\\n\\\\\\\\end{tabular}}\\\\n\\\\\\\\caption{Seven hacking modes across conditions (\\\\\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\\\\\sharp$Prolog row pools strict+functional (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).}\\\\n\\\\\\\\label{tab:hacking-taxonomy}\\\\n\\\\\\\\end{table}\\\\n\\\\nThe seven modes (Table~\\\\\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\\\\\ref{app:hacking-modes}) span the studied conditions.\\\\nTwo are quantifiable across all conditions: \\\\\\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\\\\\%$ regardless of reward type, and \\\\\\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\\\\\%$ vs.\\\\\\\\ $0\\\\\\\\%$ in random controls.\\\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\\\n\\\\nThe cross-condition pattern is consistent with \\\\\\\\S\\\\\\\\ref{sec:goodhart}: \\\\\\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\\\nExec-only, ISR, and random conditions all show $\\\\\\\\geq 80\\\\\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\\\\\%$ non-hacking.\\\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\\\\\beta{=}0.1$ s42 at $\\\\\\\\text{PR}{=}81\\\\\\\\%$, $31\\\\\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.5}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Experiments}\\n\\\\label{sec:experiments}\\n\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\S\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\S\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\S\\\\ref{sec:crosslogic}).\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\S\\\\ref{sec:taxonomy}).\\n\\n\\\\subsection{Setup}\\\\label{sec:setup}\\n\\nWe train Qwen3-4B~\\\\citep{qwen3} with GRPO~\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\{42,43,44\\\\}$ on a fixed 500-example FOLIO~\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\footnote{All experiments use \\\\texttt{data/train\\\\_500\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\nHeld-out evaluation uses 100 FOLIO examples (\\\\texttt{proofwriter\\\\_fol\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\texttt{eval\\\\_sta.py}) so training-log ISR is never compared across runs.\\nWe report prove rate (PR), proved-only ISR ($\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution; \\\\S\\\\ref{sec:taxonomy-method}), and a \\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\n\\n\\\\subsection{ISR as Diagnostic}\\n\\\\label{sec:diagnostic}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.95\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\n\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\%$\\\\to$93\\\\%$\\\\to$96\\\\% while proved-only ISR falls $0.642{\\\\to}0.132{\\\\to}0.003$ over 100$\\\\to$500$\\\\to$1000 steps. By step 1000, 94.8\\\\% of proved samples have $\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\to$18.55 (contradiction explosion).}\\n\\\\label{fig:isr-collapse}\\n\\\\end{figure}\\n\\n\\\\textbf{Collapse trajectory.}\\nFigure~\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\nPR rises $32\\\\%\\\\to93\\\\%\\\\to96\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\to0.132\\\\to0.003$ (214$\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\nBy 500 steps, 87.1\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\% and mean component count more than doubles ($6.58\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\nExtended training, lacking a structural signal, \\\\emph{worsens} formalization quality while improving the headline number.\\n\\n\\\\textbf{Cross-seed instability.}\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\ref{app:detailed-results}): s42 reaches $\\\\text{PR}{=}93\\\\%$ via conclusion embedding ($\\\\text{H1}{=}87\\\\%$); s43 collapses to $\\\\text{PR}{=}14\\\\%$ via repetition (87\\\\% of rollouts truncated); s44 reaches $\\\\text{PR}{=}98\\\\%$ via tautological collapse ($\\\\text{H7}{=}100\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\nThe cross-seed PR variance ($\\\\sigma{\\\\pm}47$\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\n\\n\\\\textbf{SFT baseline.}\\nSFT on gold formalizations reaches $\\\\text{PR}{=}14\\\\%$ with $\\\\text{ISR}^{*}{=}0.571$, $\\\\text{H7}{=}0$, $\\\\text{H1}{=}7.1\\\\%$, $92.9\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\nA 100-step RL checkpoint (Appendi\\n\\n... [截断: 输出过长，省略 6955 字符] ...\\n\\n tautologies ($\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\nSeed~43: \\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\texttt{MARY\\\\_IS\\\\_AN\\\\_AVA\\\\-DEOTE.}); strict text-match returns $\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\nSeed~44: \\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\texttt{is\\\\_the\\\\_dog\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\nSeed~44 evaded our initial strict classifier (reported $100\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\n\\n\\\\subsection{Hacking Taxonomy}\\n\\\\label{sec:taxonomy}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\n\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\n\\\\label{fig:hacking-composition}\\n\\\\end{figure}\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lccccc}\\n\\\\toprule\\n\\\\textbf{Mode} & \\\\textbf{Exec} & \\\\textbf{ISR$_{.1}$} & \\\\textbf{Rnd$_{.1}$} & \\\\textbf{SFT} & \\\\textbf{Prolog$_{\\\\text{ISR}}$} \\\\\\\\\\n\\\\midrule\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\sharp$ \\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\sharp$ \\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\nCmplx.\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\n\\\\midrule\\n\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\textbf{93} & \\\\textbf{0} \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Seven hacking modes across conditions (\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\sharp$Prolog row pools strict+functional (\\\\S\\\\ref{sec:crosslogic}).}\\n\\\\label{tab:hacking-taxonomy}\\n\\\\end{table}\\n\\nThe seven modes (Table~\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\ref{app:hacking-modes}) span the studied conditions.\\nTwo are quantifiable across all conditions: \\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\%$ regardless of reward type, and \\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\%$ vs.\\\\ $0\\\\%$ in random controls.\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\n\\nThe cross-condition pattern is consistent with \\\\S\\\\ref{sec:goodhart}: \\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\nExec-only, ISR, and random conditions all show $\\\\geq 80\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\%$ non-hacking.\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\beta{=}0.1$ s42 at $\\\\text{PR}{=}81\\\\%$, $31\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 71 · 2026-05-15T14:59:01.735Z_

<details><summary>↩ Tool result · `toolu_01WyyhGF2oQfyQVe4sLzFjm3`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Method}\\n\\\\label{sec:method}\\n\\n\\\\begin{figure*}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\textwidth]{figures/fig1_sta_overview.pdf}\\n\\\\caption{Solver Trace Ablation (STA). (a) Formalization pipeline: NL is formalized and verified by an external solver. (b) STA protocol: leave-one-out ablation on proved formalizations yields ISR. (c) ISR as diagnostic vs.\\\\ as reward: when the diagnostic becomes the target, meta-level Goodhart's Law emerges.}\\n\\\\label{fig:sta-overview}\\n\\\\end{figure*}\\n\\n\\\\subsection{Task and GRPO Training}\\n\\\\label{sec:task}\\n\\nGiven premises $P_1,\\\\ldots,P_k$ and conclusion $C$, the task is to produce a formal program $F=\\\\{c_1,\\\\ldots,c_n\\\\}$ verified by an external solver $S\\\\in\\\\{\\\\text{Prover9, SWI-Prolog}\\\\}$ (\\\\autoref{fig:sta-overview}a).\\nWe train with GRPO~\\\\citep{deepseekmath} ($K{=}8$), where each rollout receives binary execution reward $r_{\\\\text{exec}}(x) = \\\\mathbf{1}[S(F_x){=}\\\\textit{proved}]$.\\nThis optimizes prove rate but provides no signal about \\\\emph{structural quality}: a formalization embedding the conclusion among its premises receives the same reward as a faithful derivation.\\nAll experiments draw from FOLIO~\\\\citep{folio}; the held-out evaluation file retains a legacy \\\\texttt{proofwriter\\\\_fol\\\\_*.jsonl} filename (from ProofWriter~\\\\citep{proofwriter}) but contains only FOLIO-derived examples.\\n\\n\\\\subsection{Solver Trace Ablation (STA)}\\n\\\\label{sec:sta}\\n\\nSTA tests whether each component of a proved formalization is individually necessary for proof success (\\\\autoref{fig:sta-overview}b).\\nGiven a proved $x$ with $n$ components, STA constructs $n$ ablated variants $x\\\\setminus\\\\{c_i\\\\}$ and re-runs the solver (Algorithm~\\\\ref{alg:sta}).\\nA component is \\\\emph{necessary} if its removal causes proof failure.\\nWhat constitutes a component depends on the logic: premises in FOL, clauses or ground facts in Prolog.\\nLOO ablation itself is standard in mutation testing and feature attribution; our novelty is its application as a GRPO-hacking diagnostic and the empirical phenomena it surfaces.\\n\\n\\\\begin{algorithm}[t]\\n\\\\caption{Solver Trace Ablation (STA)}\\n\\\\label{alg:sta}\\n\\\\begin{algorithmic}[1]\\n\\\\REQUIRE Proved formalization $x = \\\\{c_1, \\\\ldots, c_n\\\\}$, solver $S$\\n\\\\ENSURE $\\\\text{ISR}(x) \\\\in [0, 1]$\\n\\\\STATE $\\\\textit{necessary} \\\\gets 0$\\n\\\\FOR{$i = 1$ to $n$}\\n    \\\\IF{$S(x \\\\setminus \\\\{c_i\\\\}) = \\\\textit{failed}$}\\n        \\\\STATE $\\\\textit{necessary} \\\\gets \\\\textit{necessary} + 1$\\n    \\\\ENDIF\\n\\\\ENDFOR\\n\\\\RETURN $\\\\textit{necessary} \\\\,/\\\\, n$\\n\\\\end{algorithmic}\\n\\\\end{algorithm}\\n\\n\\\\paragraph{Intensional Structural Reward.}\\nISR is the fraction of necessary components:\\n\\\\begin{equation}\\n  \\\\text{ISR}(x) = \\\\frac{1}{n}\\\\sum_{i=1}^{n}\\\\mathbf{1}\\\\bigl[S(x\\\\setminus\\\\{c_i\\\\})=\\\\textit{failed}\\\\bigr]\\n  \\\\label{eq:isr}\\n\\\\end{equation}\\nISR is defined only for proved formalizations: ISR${=}1$ means every component is necessary; ISR${=}0$ means complete redundancy.\\nWe report \\\\emph{proved-only} ISR (denoted ISR$^*$) throughout to avoid conflating structural quality with prove rate.\\n\\n\\\\paragraph{Limitations of ISR.}\\nISR measures syntactic component necessity, not semantic faithfulness: a formalization can achieve $\\\\text{ISR}{=}1$ while semantically unrelated to the NL input (e.g., a single premise identical to the conclusion).\\nISR is also sensitive to component count $n$: when $n{=}2$, $\\\\text{ISR}\\\\geq 0.5$ regardless of proof quality.\\nWe control for this confound via premise-count-matched analysis in \\\\S\\\\ref{sec:goodhart}.\\nThe $O(n)$ per-clause LOO ablation is necessary: a cheaper $O(1)$ binary variant---testing only \\\\emph{whether} each clause affects the conclusion without re-running the solver per clause---degenerates to exec-only ($\\\\text{PR}{=}63\\\\%$, $\\\\text{ISR}^*{=}0.007$), because models generate redundant copies of premises whose individual removal never changes the proof outcome (Appendix~\\\\ref{app:o1-ablation}).\\n\\n\\\\subsection{Reward Conditions and Hacking Modes}\\n\\\\label{sec:rewards}\\n\\\\label{sec:taxonomy-method}\\n\\nWe study six conditions: exec-only ($r_{\\\\text{exec}}$), ISR low/high-dose ($r_{\\\\text{exec}}\\\\cdot(1{+}\\\\beta\\\\,\\\\text{ISR})$ at $\\\\beta\\\\in\\\\{0.1,0.3\\\\}$), matched random controls ($r_{\\\\text{exec}}\\\\cdot(1{+}\\\\beta u)$, $u\\\\sim\\\\mathcal{U}(0,1)$), and an SFT baseline (NLL on gold formalizations).\\nMultiplicative bonuses apply only to proved samples, keeping the prove-rate floor intact.\\nRandom isolates ISR-specific signal from generic reward-variance effects; SFT isolates whether structural degeneration arises from RL optimization or data exposure alone.\\nEach RL condition uses seeds $\\\\{42,43,44\\\\}$ and identical training data.\\nAn earlier convex formulation ($\\\\alpha r_{\\\\text{exec}} + \\\\beta r_{\\\\text{exec}}\\\\text{ISR}$, $\\\\alpha{+}\\\\beta{=}1$) was discarded because $\\\\text{ISR}{<}1$ always penalized relative to exec-only, collapsing PR (Appendix~\\\\ref{app:setup}).\\n\\n\\\\paragraph{Hacking taxonomy.}\\nAcross conditions, seeds, and logic types we identify seven structural-degeneration modes (full definitions in Appendix~\\\\ref{app:hacking-modes}):\\n\\\\textbf{H1} (conclusion embedded among multiple premises),\\n\\\\textbf{H7} (single-premise conclusion duplication; targets the ISR signal directly, since removing the sole premise forces $\\\\text{ISR}\\\\geq 0.5$),\\n\\\\textbf{tautological collapse} (minimal two-component $P{\\\\to}P$ without explicit ISR inflation),\\n\\\\textbf{repetition collapse} (identical clauses repeated to inflate component count),\\n\\\\textbf{complexity-without-utility} (elaborate but vacuous premises),\\n\\\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\\\emph{ex falso}), and\\n\\\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers).\\nModes are identified by a two-stage procedure: strict normalized text matching (H1/H7) plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution (catches modes evading text matching).\\nWe report both classifications in \\\\S\\\\ref{sec:experiments}.\\n\\nIn interpreting ISR results we distinguish two failure semantics that share a numerical signature: an exec-only \\\\emph{low} ISR signals \\\\emph{redundancy} (e.g., repeated ground facts in Prolog), whereas an ISR-rewarded \\\\emph{high} ISR signals \\\\emph{metric gaming} (H7-style constructions).\\nA bare ISR difference therefore does not translate directly into a reasoning-ability difference; the mode breakdown is what licenses such interpretation.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.52}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "35a004a4-e890-42c3-84b0-e79ab02d1534",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Method}\\\\n\\\\\\\\label{sec:method}\\\\n\\\\n\\\\\\\\begin{figure*}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.92\\\\\\\\textwidth]{figures/fig1_sta_overview.pdf}\\\\n\\\\\\\\caption{Solver Trace Ablation (STA). (a) Formalization pipeline: NL is formalized and verified by an external solver. (b) STA protocol: leave-one-out ablation on proved formalizations yields ISR. (c) ISR as diagnostic vs.\\\\\\\\ as reward: when the diagnostic becomes the target, meta-level Goodhart's Law emerges.}\\\\n\\\\\\\\label{fig:sta-overview}\\\\n\\\\\\\\end{figure*}\\\\n\\\\n\\\\\\\\subsection{Task and GRPO Training}\\\\n\\\\\\\\label{sec:task}\\\\n\\\\nGiven premises $P_1,\\\\\\\\ldots,P_k$ and conclusion $C$, the task is to produce a formal program $F=\\\\\\\\{c_1,\\\\\\\\ldots,c_n\\\\\\\\}$ verified by an external solver $S\\\\\\\\in\\\\\\\\{\\\\\\\\text{Prover9, SWI-Prolog}\\\\\\\\}$ (\\\\\\\\autoref{fig:sta-overview}a).\\\\nWe train with GRPO~\\\\\\\\citep{deepseekmath} ($K{=}8$), where each rollout receives binary execution reward $r_{\\\\\\\\text{exec}}(x) = \\\\\\\\mathbf{1}[S(F_x){=}\\\\\\\\textit{proved}]$.\\\\nThis optimizes prove rate but provides no signal about \\\\\\\\emph{structural quality}: a formalization embedding the conclusion among its premises receives the same reward as a faithful derivation.\\\\nAll experiments draw from FOLIO~\\\\\\\\citep{folio}; the held-out evaluation file retains a legacy \\\\\\\\texttt{proofwriter\\\\\\\\_fol\\\\\\\\_*.jsonl} filename (from ProofWriter~\\\\\\\\citep{proofwriter}) but contains only FOLIO-derived examples.\\\\n\\\\n\\\\\\\\subsection{Solver Trace Ablation (STA)}\\\\n\\\\\\\\label{sec:sta}\\\\n\\\\nSTA tests whether each component of a proved formalization is individually necessary for proof success (\\\\\\\\autoref{fig:sta-overview}b).\\\\nGiven a proved $x$ with $n$ components, STA constructs $n$ ablated variants $x\\\\\\\\setminus\\\\\\\\{c_i\\\\\\\\}$ and re-runs the solver (Algorithm~\\\\\\\\ref{alg:sta}).\\\\nA component is \\\\\\\\emph{necessary} if its removal causes proof failure.\\\\nWhat constitutes a component depends on the logic: premises in FOL, clauses or ground facts in Prolog.\\\\nLOO ablation itself is standard in mutation testing and feature attribution; our novelty is its application as a GRPO-hacking diagnostic and the empirical phenomena it surfaces.\\\\n\\\\n\\\\\\\\begin{algorithm}[t]\\\\n\\\\\\\\caption{Solver Trace Ablation (STA)}\\\\n\\\\\\\\label{alg:sta}\\\\n\\\\\\\\begin{algorithmic}[1]\\\\n\\\\\\\\REQUIRE Proved formalization $x = \\\\\\\\{c_1, \\\\\\\\ldots, c_n\\\\\\\\}$, solver $S$\\\\n\\\\\\\\ENSURE $\\\\\\\\text{ISR}(x) \\\\\\\\in [0, 1]$\\\\n\\\\\\\\STATE $\\\\\\\\textit{necessary} \\\\\\\\gets 0$\\\\n\\\\\\\\FOR{$i = 1$ to $n$}\\\\n    \\\\\\\\IF{$S(x \\\\\\\\setminus \\\\\\\\{c_i\\\\\\\\}) = \\\\\\\\textit{failed}$}\\\\n        \\\\\\\\STATE $\\\\\\\\textit{necessary} \\\\\\\\gets \\\\\\\\textit{necessary} + 1$\\\\n    \\\\\\\\ENDIF\\\\n\\\\\\\\ENDFOR\\\\n\\\\\\\\RETURN $\\\\\\\\textit{necessary} \\\\\\\\,/\\\\\\\\, n$\\\\n\\\\\\\\end{algorithmic}\\\\n\\\\\\\\end{algorithm}\\\\n\\\\n\\\\\\\\paragraph{Intensional Structural Reward.}\\\\nISR is the fraction of necessary components:\\\\n\\\\\\\\begin{equation}\\\\n  \\\\\\\\text{ISR}(x) = \\\\\\\\frac{1}{n}\\\\\\\\sum_{i=1}^{n}\\\\\\\\mathbf{1}\\\\\\\\bigl[S(x\\\\\\\\setminus\\\\\\\\{c_i\\\\\\\\})=\\\\\\\\textit{failed}\\\\\\\\bigr]\\\\n  \\\\\\\\label{eq:isr}\\\\n\\\\\\\\end{equation}\\\\nISR is defined only for proved formalizations: ISR${=}1$ means every component is necessary; ISR${=}0$ means complete redundancy.\\\\nWe report \\\\\\\\emph{proved-only} ISR (denoted ISR$^*$) throughout to avoid conflating structural quality with prove rate.\\\\n\\\\n\\\\\\\\paragraph{Limitations of ISR.}\\\\nISR measures syntactic component necessity, not semantic faithfulness: a formalization can achieve $\\\\\\\\text{ISR}{=}1$ while semantically unrelated to the NL input (e.g., a single premise identical to the conclusion).\\\\nISR is also sensitive to component count $n$: when $n{=}2$, $\\\\\\\\text{ISR}\\\\\\\\geq 0.5$ regardless of proof quality.\\\\nWe control for this confound via premise-count-matched analysis in \\\\\\\\S\\\\\\\\ref{sec:goodhart}.\\\\nThe $O(n)$ per-clause LOO ablation is necessary: a cheaper $O(1)$ binary variant---testing only \\\\\\\\emph{whether} each clause affects the conclusion without re-running the solver per clause---degenerates to exec-only ($\\\\\\\\text{PR}{=}63\\\\\\\\%$, $\\\\\\\\text{ISR}^*{=}0.007$), because models generate redundant copies of premises whose individual removal never changes the proof outcome (Appendix~\\\\\\\\ref{app:o1-ablation}).\\\\n\\\\n\\\\\\\\subsection{Reward Conditions and Hacking Modes}\\\\n\\\\\\\\label{sec:rewards}\\\\n\\\\\\\\label{sec:taxonomy-method}\\\\n\\\\nWe study six conditions: exec-only ($r_{\\\\\\\\text{exec}}$), ISR low/high-dose ($r_{\\\\\\\\text{exec}}\\\\\\\\cdot(1{+}\\\\\\\\beta\\\\\\\\,\\\\\\\\text{ISR})$ at $\\\\\\\\beta\\\\\\\\in\\\\\\\\{0.1,0.3\\\\\\\\}$), matched random controls ($r_{\\\\\\\\text{exec}}\\\\\\\\cdot(1{+}\\\\\\\\beta u)$, $u\\\\\\\\sim\\\\\\\\mathcal{U}(0,1)$), and an SFT baseline (NLL on gold formalizations).\\\\nMultiplicative bonuses apply only to proved samples, keeping the prove-rate floor intact.\\\\nRandom isolates ISR-specific signal from generic reward-variance effects; SFT isolates whether structural degeneration arises from RL optimization or data exposure alone.\\\\nEach RL condition uses seeds $\\\\\\\\{42,43,44\\\\\\\\}$ and identical training data.\\\\nAn earlier convex formulation ($\\\\\\\\alpha r_{\\\\\\\\text{exec}} + \\\\\\\\beta r_{\\\\\\\\text{exec}}\\\\\\\\text{ISR}$, $\\\\\\\\alpha{+}\\\\\\\\beta{=}1$) was discarded because $\\\\\\\\text{ISR}{<}1$ always penalized relative to exec-only, collapsing PR (Appendix~\\\\\\\\ref{app:setup}).\\\\n\\\\n\\\\\\\\paragraph{Hacking taxonomy.}\\\\nAcross conditions, seeds, and logic types we identify seven structural-degeneration modes (full definitions in Appendix~\\\\\\\\ref{app:hacking-modes}):\\\\n\\\\\\\\textbf{H1} (conclusion embedded among multiple premises),\\\\n\\\\\\\\textbf{H7} (single-premise conclusion duplication; targets the ISR signal directly, since removing the sole premise forces $\\\\\\\\text{ISR}\\\\\\\\geq 0.5$),\\\\n\\\\\\\\textbf{tautological collapse} (minimal two-component $P{\\\\\\\\to}P$ without explicit ISR inflation),\\\\n\\\\\\\\textbf{repetition collapse} (identical clauses repeated to inflate component count),\\\\n\\\\\\\\textbf{complexity-without-utility} (elaborate but vacuous premises),\\\\n\\\\\\\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\\\\\\\emph{ex falso}), and\\\\n\\\\\\\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers).\\\\nModes are identified by a two-stage procedure: strict normalized text matching (H1/H7) plus functional analysis of the per-sample $n_{\\\\\\\\text{necessary}}$ distribution (catches modes evading text matching).\\\\nWe report both classifications in \\\\\\\\S\\\\\\\\ref{sec:experiments}.\\\\n\\\\nIn interpreting ISR results we distinguish two failure semantics that share a numerical signature: an exec-only \\\\\\\\emph{low} ISR signals \\\\\\\\emph{redundancy} (e.g., repeated ground facts in Prolog), whereas an ISR-rewarded \\\\\\\\emph{high} ISR signals \\\\\\\\emph{metric gaming} (H7-style constructions).\\\\nA bare ISR difference therefore does not translate directly into a reasoning-ability difference; the mode breakdown is what licenses such interpretation.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.52}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Method}\\n\\\\label{sec:method}\\n\\n\\\\begin{figure*}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\textwidth]{figures/fig1_sta_overview.pdf}\\n\\\\caption{Solver Trace Ablation (STA). (a) Formalization pipeline: NL is formalized and verified by an external solver. (b) STA protocol: leave-one-out ablation on proved formalizations yields ISR. (c) ISR as diagnostic vs.\\\\ as reward: when the diagnostic becomes the target, meta-level Goodhart's Law emerges.}\\n\\\\label{fig:sta-overview}\\n\\\\end{figure*}\\n\\n\\\\subsection{Task and GRPO Training}\\n\\\\label{sec:task}\\n\\nGiven premises $P_1,\\\\ldots,P_k$ and conclusion $C$, the task is to produce a formal program $F=\\\\{c_1,\\\\ldots,c_n\\\\}$ verified by an external solver $S\\\\in\\\\{\\\\text{Prover9, SWI-Prolog}\\\\}$ (\\\\autoref{fig:sta-overview}a).\\nWe train with GRPO~\\\\citep{deepseekmath} ($K{=}8$), where each rollout receives binary execution reward $r_{\\\\text{exec}}(x) = \\\\mathbf{1}[S(F_x){=}\\\\textit{proved}]$.\\nThis optimizes prove rate but provides no signal about \\\\emph{structural quality}: a formalization embedding the conclusion among its premises receives the same reward as a faithful derivation.\\nAll experiments draw from FOLIO~\\\\citep{folio}; the held-out evaluation file retains a legacy \\\\texttt{proofwriter\\\\_fol\\\\_*.jsonl} filename (from ProofWriter~\\\\citep{proofwriter}) but contains only FOLIO-derived examples.\\n\\n\\\\subsection{Solver Trace Ablation (STA)}\\n\\\\label{sec:sta}\\n\\nSTA tests whether each component of a proved formalization is individually necessary for proof success (\\\\autoref{fig:sta-overview}b).\\nGiven a proved $x$ with $n$ components, STA constructs $n$ ablated variants $x\\\\setminus\\\\{c_i\\\\}$ and re-runs the solver (Algorithm~\\\\ref{alg:sta}).\\nA component is \\\\emph{necessary} if its removal causes proof failure.\\nWhat constitutes a component depends on the logic: premises in FOL, clauses or ground facts in Prolog.\\nLOO ablation itself is standard in mutation testing and feature attribution; our novelty is its application as a GRPO-hacking diagnostic and the empirical phenomena it surfaces.\\n\\n\\\\begin{algorithm}[t]\\n\\\\caption{Solver Trace Ablation (STA)}\\n\\\\label{alg:sta}\\n\\\\begin{algorithmic}[1]\\n\\\\REQUIRE Proved formalization $x = \\\\{c_1, \\\\ldots, c_n\\\\}$, solver $S$\\n\\\\ENSURE $\\\\text{ISR}(x) \\\\in [0, 1]$\\n\\\\STATE $\\\\textit{necessary} \\\\gets 0$\\n\\\\FOR{$i = 1$ to $n$}\\n    \\\\IF{$S(x \\\\setminus \\\\{c_i\\\\}) = \\\\textit{failed}$}\\n        \\\\STATE $\\\\textit{necessary} \\\\gets \\\\textit{necessary} + 1$\\n    \\\\ENDIF\\n\\\\ENDFOR\\n\\\\RETURN $\\\\textit{necessary} \\\\,/\\\\, n$\\n\\\\end{algorithmic}\\n\\\\end{algorithm}\\n\\n\\\\paragraph{Intensional Structural Reward.}\\nISR is the fraction of necessary components:\\n\\\\begin{equation}\\n  \\\\text{ISR}(x) = \\\\frac{1}{n}\\\\sum_{i=1}^{n}\\\\mathbf{1}\\\\bigl[S(x\\\\setminus\\\\{c_i\\\\})=\\\\textit{failed}\\\\bigr]\\n  \\\\label{eq:isr}\\n\\\\end{equation}\\nISR is defined only for proved formalizations: ISR${=}1$ means every component is necessary; ISR${=}0$ means complete redundancy.\\nWe report \\\\emph{proved-only} ISR (denoted ISR$^*$) throughout to avoid conflating structural quality with prove rate.\\n\\n\\\\paragraph{Limitations of ISR.}\\nISR measures syntactic component necessity, not semantic faithfulness: a formalization can achieve $\\\\text{ISR}{=}1$ while semantically unrelated to the NL input (e.g., a single premise identical to the conclusion).\\nISR is also sensitive to component count $n$: when $n{=}2$, $\\\\text{ISR}\\\\geq 0.5$ regardless of proof quality.\\nWe control for this confound via premise-count-matched analysis in \\\\S\\\\ref{sec:goodhart}.\\nThe $O(n)$ per-clause LOO ablation is necessary: a cheaper $O(1)$ binary variant---testing only \\\\emph{whether} each clause affects the conclusion without re-running the solver per clause---degenerates to exec-only ($\\\\text{PR}{=}63\\\\%$, $\\\\text{ISR}^*{=}0.007$), because models generate redundant copies of premises whose individual removal never changes the proof outcome (Appendix~\\\\ref{app:o1-ablation}).\\n\\n\\\\subsection{Reward Conditions and Hacking Modes}\\n\\\\label{sec:rewards}\\n\\\\label{sec:taxonomy-method}\\n\\nWe study six conditions: exec-only ($r_{\\\\text{exec}}$), ISR low/high-dose ($r_{\\\\text{exec}}\\\\cdot(1{+}\\\\beta\\\\,\\\\text{ISR})$ at $\\\\beta\\\\in\\\\{0.1,0.3\\\\}$), matched random controls ($r_{\\\\text{exec}}\\\\cdot(1{+}\\\\beta u)$, $u\\\\sim\\\\mathcal{U}(0,1)$), and an SFT baseline (NLL on gold formalizations).\\nMultiplicative bonuses apply only to proved samples, keeping the prove-rate floor intact.\\nRandom isolates ISR-specific signal from generic reward-variance effects; SFT isolates whether structural degeneration arises from RL optimization or data exposure alone.\\nEach RL condition uses seeds $\\\\{42,43,44\\\\}$ and identical training data.\\nAn earlier convex formulation ($\\\\alpha r_{\\\\text{exec}} + \\\\beta r_{\\\\text{exec}}\\\\text{ISR}$, $\\\\alpha{+}\\\\beta{=}1$) was discarded because $\\\\text{ISR}{<}1$ always penalized relative to exec-only, collapsing PR (Appendix~\\\\ref{app:setup}).\\n\\n\\\\paragraph{Hacking taxonomy.}\\nAcross conditions, seeds, and logic types we identify seven structural-degeneration modes (full definitions in Appendix~\\\\ref{app:hacking-modes}):\\n\\\\textbf{H1} (conclusion embedded among multiple premises),\\n\\\\textbf{H7} (single-premise conclusion duplication; targets the ISR signal directly, since removing the sole premise forces $\\\\text{ISR}\\\\geq 0.5$),\\n\\\\textbf{tautological collapse} (minimal two-component $P{\\\\to}P$ without explicit ISR inflation),\\n\\\\textbf{repetition collapse} (identical clauses repeated to inflate component count),\\n\\\\textbf{complexity-without-utility} (elaborate but vacuous premises),\\n\\\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\\\emph{ex falso}), and\\n\\\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers).\\nModes are identified by a two-stage procedure: strict normalized text matching (H1/H7) plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution (catches modes evading text matching).\\nWe report both classifications in \\\\S\\\\ref{sec:experiments}.\\n\\nIn interpreting ISR results we distinguish two failure semantics that share a numerical signature: an exec-only \\\\emph{low} ISR signals \\\\emph{redundancy} (e.g., repeated ground facts in Prolog), whereas an ISR-rewarded \\\\emph{high} ISR signals \\\\emph{metric gaming} (H7-style constructions).\\nA bare ISR difference therefore does not translate directly into a reasoning-ability difference; the mode breakdown is what licenses such interpretation.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.52}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 72 · 2026-05-15T14:59:02.272Z_

<details><summary>↩ Tool result · `toolu_01L9xQknyho6LpzxcYFAbsHG`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Discussion and Conclusion}\\n\\nSolver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.9\\\\% non-hacking localizes the failure to RL optimization (\\\\S\\\\ref{sec:diagnostic}).\\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\\nAt $\\\\beta{=}0.1$, conclusion duplication exploits the LOO definition (64.5\\\\% vs.\\\\ 0\\\\% under matched random), and the sole apparent ISR gain reduces to $1.06\\\\times$ random once a premise-count confound is controlled; at $\\\\beta{=}0.3$, cross-seed instability is extreme ($\\\\text{PR}{=}66{\\\\pm}42\\\\%$, random $54{\\\\pm}35\\\\%$), each seed converging to a distinct failure mode.\\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\\\S\\\\ref{sec:taxonomy}).\\nISR semantics depend on objective: exec-only \\\\emph{low} ISR signals redundancy; ISR-rewarded \\\\emph{high} ISR signals metric gaming.\\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.52}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "2f226e60-4929-4ffe-955c-75c2f04cdee7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Discussion and Conclusion}\\\\n\\\\nSolver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\\\\\\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.9\\\\\\\\% non-hacking localizes the failure to RL optimization (\\\\\\\\S\\\\\\\\ref{sec:diagnostic}).\\\\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\\\\nAt $\\\\\\\\beta{=}0.1$, conclusion duplication exploits the LOO definition (64.5\\\\\\\\% vs.\\\\\\\\ 0\\\\\\\\% under matched random), and the sole apparent ISR gain reduces to $1.06\\\\\\\\times$ random once a premise-count confound is controlled; at $\\\\\\\\beta{=}0.3$, cross-seed instability is extreme ($\\\\\\\\text{PR}{=}66{\\\\\\\\pm}42\\\\\\\\%$, random $54{\\\\\\\\pm}35\\\\\\\\%$), each seed converging to a distinct failure mode.\\\\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\\\\\\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\\\\\\\S\\\\\\\\ref{sec:taxonomy}).\\\\nISR semantics depend on objective: exec-only \\\\\\\\emph{low} ISR signals redundancy; ISR-rewarded \\\\\\\\emph{high} ISR signals metric gaming.\\\\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.52}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Discussion and Conclusion}\\n\\nSolver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.9\\\\% non-hacking localizes the failure to RL optimization (\\\\S\\\\ref{sec:diagnostic}).\\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\\nAt $\\\\beta{=}0.1$, conclusion duplication exploits the LOO definition (64.5\\\\% vs.\\\\ 0\\\\% under matched random), and the sole apparent ISR gain reduces to $1.06\\\\times$ random once a premise-count confound is controlled; at $\\\\beta{=}0.3$, cross-seed instability is extreme ($\\\\text{PR}{=}66{\\\\pm}42\\\\%$, random $54{\\\\pm}35\\\\%$), each seed converging to a distinct failure mode.\\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\\\S\\\\ref{sec:taxonomy}).\\nISR semantics depend on objective: exec-only \\\\emph{low} ISR signals redundancy; ISR-rewarded \\\\emph{high} ISR signals metric gaming.\\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.52}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 73 · 2026-05-15T14:59:02.816Z_

<details><summary>↩ Tool result · `toolu_01NbgFozFf5sLpNrhNzvfKqw`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Limitations}\\n\\\\label{sec:limitations}\\n\\nExperiments use a single base model (Qwen3-4B) and dataset family (FOLIO); generalization remains untested.\\nISR quantifies syntactic component necessity, not semantic faithfulness: a downstream NLI evaluation finds ISR and task accuracy uncorrelated (Spearman $\\\\rho{=}{-}0.049$, $p{=}0.187$; Appendix~\\\\ref{app:extended-discussion}).\\nThree seeds demonstrate qualitative divergence but limit statistical power.\\nSTA requires solvers supporting component-level input manipulation.\\n\\n\\\\paragraph{Data scale.}\\nOur experiments use 500 training examples and 100 evaluation examples, drawn from FOLIO~\\\\citep{folio}.\\nThe training subset is selected via stratified sampling (seed 42) and held constant across all conditions.\\nWhile our findings are consistent across seeds and logic types, the effect of training data scale on hacking prevalence and mode distribution remains an open question for future work.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "9f44a30d-15e3-4fc1-b7d0-8b2a013948d9",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Limitations}\\\\n\\\\\\\\label{sec:limitations}\\\\n\\\\nExperiments use a single base model (Qwen3-4B) and dataset family (FOLIO); generalization remains untested.\\\\nISR quantifies syntactic component necessity, not semantic faithfulness: a downstream NLI evaluation finds ISR and task accuracy uncorrelated (Spearman $\\\\\\\\rho{=}{-}0.049$, $p{=}0.187$; Appendix~\\\\\\\\ref{app:extended-discussion}).\\\\nThree seeds demonstrate qualitative divergence but limit statistical power.\\\\nSTA requires solvers supporting component-level input manipulation.\\\\n\\\\n\\\\\\\\paragraph{Data scale.}\\\\nOur experiments use 500 training examples and 100 evaluation examples, drawn from FOLIO~\\\\\\\\citep{folio}.\\\\nThe training subset is selected via stratified sampling (seed 42) and held constant across all conditions.\\\\nWhile our findings are consistent across seeds and logic types, the effect of training data scale on hacking prevalence and mode distribution remains an open question for future work.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.53}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Limitations}\\n\\\\label{sec:limitations}\\n\\nExperiments use a single base model (Qwen3-4B) and dataset family (FOLIO); generalization remains untested.\\nISR quantifies syntactic component necessity, not semantic faithfulness: a downstream NLI evaluation finds ISR and task accuracy uncorrelated (Spearman $\\\\rho{=}{-}0.049$, $p{=}0.187$; Appendix~\\\\ref{app:extended-discussion}).\\nThree seeds demonstrate qualitative divergence but limit statistical power.\\nSTA requires solvers supporting component-level input manipulation.\\n\\n\\\\paragraph{Data scale.}\\nOur experiments use 500 training examples and 100 evaluation examples, drawn from FOLIO~\\\\citep{folio}.\\nThe training subset is selected via stratified sampling (seed 42) and held constant across all conditions.\\nWhile our findings are consistent across seeds and logic types, the effect of training data scale on hacking prevalence and mode distribution remains an open question for future work.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 74 · 2026-05-15T14:59:03.373Z_

<details><summary>↩ Tool result · `toolu_012ySpG2qZzCGuTRy1UyJDwA`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Related Work}\\n\\\\label{sec:related-work}\\n\\n\\\\paragraph{Neurosymbolic reasoning and process rewards.}\\nLLM-solver pipelines~\\\\cite{satlm, logic-lm, linc, fover-pei2025, lorp} and RL methods trained on solver feedback~\\\\cite{mellgren-prolog-grpo, logic-rl} evaluate execution accuracy alone, with no diagnostic for structural quality.\\nLearned PRMs~\\\\cite{lightman-verify-step, math-shepherd} provide step-level feedback but suffer from reward-model noise and distribution shift~\\\\cite{processbench}; ISR is solver-grounded and annotation-free.\\nWe use FOLIO~\\\\cite{folio}, the only public NLI benchmark with both FOL and Prolog annotations.\\n\\n\\\\paragraph{Reward hacking and Goodhart's Law.}\\nGoodhart's Law is established theoretically~\\\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\\nRecent work further documents spurious reward signals in RLVR~\\\\cite{spurious-rewards} and reward hacking in frontier models~\\\\cite{metr-reward-hacking}.\\nOur setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \\\\emph{emerges during RL training} rather than at inference time; and the effect operates at a \\\\emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.\\n\\n\\\\paragraph{Mutation testing.}\\nSTA adapts the LOO mutation paradigm~\\\\cite{demillo1978, jia-harman-survey} to solver inputs; novelty lies in application and findings, not in the perturbation primitive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "7c9ebe5e-3305-4f61-a55e-4337502afc94",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Related Work}\\\\n\\\\\\\\label{sec:related-work}\\\\n\\\\n\\\\\\\\paragraph{Neurosymbolic reasoning and process rewards.}\\\\nLLM-solver pipelines~\\\\\\\\cite{satlm, logic-lm, linc, fover-pei2025, lorp} and RL methods trained on solver feedback~\\\\\\\\cite{mellgren-prolog-grpo, logic-rl} evaluate execution accuracy alone, with no diagnostic for structural quality.\\\\nLearned PRMs~\\\\\\\\cite{lightman-verify-step, math-shepherd} provide step-level feedback but suffer from reward-model noise and distribution shift~\\\\\\\\cite{processbench}; ISR is solver-grounded and annotation-free.\\\\nWe use FOLIO~\\\\\\\\cite{folio}, the only public NLI benchmark with both FOL and Prolog annotations.\\\\n\\\\n\\\\\\\\paragraph{Reward hacking and Goodhart's Law.}\\\\nGoodhart's Law is established theoretically~\\\\\\\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\\\\\\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\\\\nRecent work further documents spurious reward signals in RLVR~\\\\\\\\cite{spurious-rewards} and reward hacking in frontier models~\\\\\\\\cite{metr-reward-hacking}.\\\\nOur setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \\\\\\\\emph{emerges during RL training} rather than at inference time; and the effect operates at a \\\\\\\\emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.\\\\n\\\\n\\\\\\\\paragraph{Mutation testing.}\\\\nSTA adapts the LOO mutation paradigm~\\\\\\\\cite{demillo1978, jia-harman-survey} to solver inputs; novelty lies in application and findings, not in the perturbation primitive.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.53}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Related Work}\\n\\\\label{sec:related-work}\\n\\n\\\\paragraph{Neurosymbolic reasoning and process rewards.}\\nLLM-solver pipelines~\\\\cite{satlm, logic-lm, linc, fover-pei2025, lorp} and RL methods trained on solver feedback~\\\\cite{mellgren-prolog-grpo, logic-rl} evaluate execution accuracy alone, with no diagnostic for structural quality.\\nLearned PRMs~\\\\cite{lightman-verify-step, math-shepherd} provide step-level feedback but suffer from reward-model noise and distribution shift~\\\\cite{processbench}; ISR is solver-grounded and annotation-free.\\nWe use FOLIO~\\\\cite{folio}, the only public NLI benchmark with both FOL and Prolog annotations.\\n\\n\\\\paragraph{Reward hacking and Goodhart's Law.}\\nGoodhart's Law is established theoretically~\\\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\\nRecent work further documents spurious reward signals in RLVR~\\\\cite{spurious-rewards} and reward hacking in frontier models~\\\\cite{metr-reward-hacking}.\\nOur setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \\\\emph{emerges during RL training} rather than at inference time; and the effect operates at a \\\\emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.\\n\\n\\\\paragraph{Mutation testing.}\\nSTA adapts the LOO mutation paradigm~\\\\cite{demillo1978, jia-harman-survey} to solver inputs; novelty lies in application and findings, not in the perturbation primitive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 75 · 2026-05-15T14:59:03.931Z_

<details><summary>↩ Tool result · `toolu_01M81UkiJjQW9CZCHcbzuDQw`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"% Appendix — solver-trace-ablation\\n\\n\\\\section{Experimental Setup}\\n\\\\label{app:setup}\\n\\nTable~\\\\ref{tab:hyperparams} lists all hyperparameters shared across experiments.\\nAll RL conditions use the same GRPO configuration; only the reward function differs.\\nSeeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).\\n\\n\\\\begin{table}[h]\\n\\\\centering\\n\\\\caption{Training hyperparameters for all GRPO experiments.}\\n\\\\label{tab:hyperparams}\\n\\\\footnotesize\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{@{}ll@{}}\\n\\\\toprule\\n\\\\textbf{Parameter} & \\\\textbf{Value} \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Model}} \\\\\\\\\\nBase model & Qwen3-4B \\\\\\\\\\nPrecision & BF16 \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{GRPO Training}} \\\\\\\\\\nRollouts per prompt ($K$) & 8 \\\\\\\\\\nTraining steps (default) & 500 \\\\\\\\\\nTraining steps (extended) & 1000 \\\\\\\\\\nLearning rate & $1 \\\\times 10^{-6}$ \\\\\\\\\\nPer-device batch size & 4 \\\\\\\\\\nGradient accumulation steps & 2 \\\\\\\\\\nEffective batch size & 8 \\\\\\\\\\nMax completion length & 512 tokens \\\\\\\\\\nRandom seeds & 42, 43, 44 \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Data}} \\\\\\\\\\nTraining set & FOLIO, 500 examples \\\\\\\\\\nEvaluation set & FOLIO, 100 examples (held-out) \\\\\\\\\\nData file & \\\\texttt{train\\\\_500\\\\_seed42} \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Solvers}} \\\\\\\\\\nFOL solver & Prover9 \\\\\\\\\\nProlog solver & SWI-Prolog 8.4.2 \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Evaluation}} \\\\\\\\\\nDecoding & Greedy ($T{=}0$) \\\\\\\\\\nISR computation & \\\\texttt{eval\\\\_sta.py} \\\\\\\\\\nISR variant & Proved-only (ISR$^*$) \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\end{table}\\n\\n\\\\paragraph{Evaluation exception.}\\nFOL exec-only seed~43 (\\\\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.\\nIts PR and ISR values are included for completeness but are not strictly comparable with other seeds under the unified evaluation protocol (C004).\\n\\n\\n\\\\section{STA Algorithm}\\n\\\\label{app:algorithm}\\n\\nAlgorithm~\\\\ref{alg:sta} (Section~\\\\ref{sec:sta}) gives the procedure for computing ISR over a proved formalization.\\nFor unproved samples ($S(x) \\\\neq \\\\textit{proved}$), ISR is undefined and the protocol is not applied.\\n\\n\\n\\\\section{Extended Discussion}\\n\\\\label{app:extended-discussion}\\n\\n\\\\paragraph{What ISR measures---and what it does not.}\\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\\nWe verify this empirically: Spearman $\\\\rho(\\\\text{ISR}, \\\\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\\nISR and downstream task performance are uncorrelated.\\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\\n\\nCritically, low ISR carries different semantics depending on the training objective.\\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\\\S\\\\ref{sec:crosslogic}).\\nUnder ISR-as-reward, high ISR reflects metric gaming (\\\\S\\\\ref{sec:goodhart}).\\nISR values must always be interpreted relative to the optimization objective that produced them.\\n\\n\\\\paragraph{The premise-count confound.}\\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\\nA formalization with 2 premises where both are necessary yields ISR${=}1.0$; one with 10 premises where 8 are necessary yields ISR${=}0.8$---even though the latter encodes richer reasoning.\\nThis confound explains the sole apparent ISR-as-reward success (\\\\S\\\\ref{sec:goodhart}): ISR $\\\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\\n\\n\\n... [截断: 输出过长，省略 16777 字符] ...\\n\\nsion),\\nseed~43 generates uppercase pseudo-Prolog that bypasses the text-match classifier while remaining functionally tautological,\\nand seed~44 converts NL conclusions to snake\\\\_case atoms used as both fact and query.\\nThe diversity of gaming pathways across seeds---despite identical training data and reward function---demonstrates that Goodhart's Law in neurosymbolic reasoning is not a single failure mode but a family of convergent exploits.\\n\\n\\\\subsection{Per-Seed Results at $\\\\beta{=}0.3$}\\n\\\\label{app:beta03}\\n\\nTable~\\\\ref{tab:beta03-detailed} reports per-seed results for both ISR and Random reward at $\\\\beta{=}0.3$.\\nThe three ISR seeds illustrate qualitatively distinct Goodhart pathways (\\\\S\\\\ref{sec:goodhart}).\\n\\n\\\\begin{table}[h]\\n\\\\centering\\n\\\\caption{Per-seed results at $\\\\beta{=}0.3$ (FOL). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H = percentage among proved samples.}\\n\\\\label{tab:beta03-detailed}\\n\\\\small\\n\\\\begin{tabular}{@{}llcccccl@{}}\\n\\\\toprule\\n\\\\textbf{Condition} & \\\\textbf{Seed} & \\\\textbf{PR} & \\\\textbf{ISR$^*$} & \\\\textbf{H7\\\\%} & \\\\textbf{H1\\\\%} & \\\\textbf{N-H\\\\%} & \\\\textbf{Mode} \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{8}{@{}l}{\\\\textit{ISR $\\\\beta{=}0.3$}} \\\\\\\\\\n  & 42 & 0.18 & 0.143 & 0 & 77.8 & 22.2 & Reward collapse ($n{=}18$) \\\\\\\\\\n  & 43 & 0.86 & 0.295 & 4.7 & 68.6 & 26.7 & H1 shortcutting \\\\\\\\\\n  & 44 & 0.95 & 0.742 & \\\\textbf{100} & 0 & 0 & Pure H7 meta-Goodhart \\\\\\\\\\n\\\\cmidrule(l){2-8}\\n  & \\\\multicolumn{2}{l}{3-seed mean$\\\\pm$std} & \\\\makebox[0pt][l]{$0.66{\\\\pm}0.42$} & & \\\\makebox[0pt][l]{$0.39{\\\\pm}0.31$} & & \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{8}{@{}l}{\\\\textit{Random $\\\\beta{=}0.3$}} \\\\\\\\\\n  & 42 & 0.48 & 0.094 & 0 & 100 & 0 & \\\\\\\\\\n  & 43 & 0.92 & 0.180 & 7.6 & 90.2 & 2.2 & \\\\\\\\\\n  & 44 & 0.23 & 0 & 0 & 100 & 0 & \\\\\\\\\\n\\\\cmidrule(l){2-8}\\n  & \\\\multicolumn{2}{l}{3-seed mean$\\\\pm$std} & \\\\makebox[0pt][l]{$0.54{\\\\pm}0.35$} & & \\\\makebox[0pt][l]{$0.09{\\\\pm}0.09$} & & \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}\\n\\\\end{table}\\n\\n\\\\subsection{Early-Training Hacking Analysis (100-Step Checkpoint)}\\n\\\\label{app:100step}\\n\\nTo control for the prove-rate confound in our SFT comparison (\\\\S\\\\ref{sec:diagnostic}), we analyze the exec-only checkpoint at 100 training steps (seed~42), where PR${=}32$\\\\%---higher than SFT (14\\\\%) but still early in training.\\nOf the 32 proved samples, 9 (28.1\\\\%) exhibit H7 hacking (single premise identical to conclusion) and 1 (3.1\\\\%) exhibits H1 (conclusion embedded among premises), yielding a total hacking rate of 31.2\\\\%.\\nBy contrast, SFT at comparable or lower PR shows 7.1\\\\% hacking (1/14 proved samples).\\nThis demonstrates that reward hacking emerges early in GRPO training---well before the prove-rate plateau---and is not simply an artifact of having more proved samples available for exploitation.\\nThe 100-step hacking rate (31.2\\\\%) is already substantially above SFT (7.1\\\\%), supporting the claim that hacking is associated with RL optimization rather than prove-rate level alone.\\n\\n\\\\subsection{$O(1)$ vs.\\\\ $O(n)$ ISR Ablation}\\n\\\\label{app:o1-ablation}\\n\\nTo justify the per-clause LOO design (\\\\S\\\\ref{sec:sta}), we train a variant that replaces the $O(n)$ ablation with a cheaper $O(1)$ binary signal: $\\\\text{fast\\\\_ISR}(x) = 1$ if $x$ is proved, $0$ otherwise.\\nThe reward becomes $r = 0.5\\\\,r_{\\\\text{exec}} + 0.5\\\\,\\\\text{fast\\\\_ISR}$, which collapses to $r_{\\\\text{exec}}$ for all proved samples (every proved formalization receives $\\\\text{fast\\\\_ISR}{=}1$).\\nAfter 500 steps (seed~42), this variant achieves $\\\\text{PR}{=}63\\\\%$ with $\\\\text{ISR}^*{=}0.007$---functionally zero---compared to $\\\\text{ISR}^*{=}0.132$ under standard exec-only and $\\\\text{ISR}^*{=}0.42$ under ISR $\\\\beta{=}0.1$.\\nInspection of the generated formalizations reveals the mechanism: the model emits $60{+}$ repeated ground facts per problem; since each individual copy is redundant, LOO removal of any single copy never changes the proof outcome, driving ISR to zero.\\nThe result confirms that the $O(n)$ per-clause ablation is necessary for ISR to carry a structural signal: without fine-grained component-level necessity testing, the metric degenerates.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.52}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "e996184f-ce5b-4365-9081-47e5c1f4bf7b",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"% Appendix — solver-trace-ablation\\\\n\\\\n\\\\\\\\section{Experimental Setup}\\\\n\\\\\\\\label{app:setup}\\\\n\\\\nTable~\\\\\\\\ref{tab:hyperparams} lists all hyperparameters shared across experiments.\\\\nAll RL conditions use the same GRPO configuration; only the reward function differs.\\\\nSeeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).\\\\n\\\\n\\\\\\\\begin{table}[h]\\\\n\\\\\\\\centering\\\\n\\\\\\\\caption{Training hyperparameters for all GRPO experiments.}\\\\n\\\\\\\\label{tab:hyperparams}\\\\n\\\\\\\\footnotesize\\\\n\\\\\\\\resizebox{\\\\\\\\columnwidth}{!}{%\\\\n\\\\\\\\begin{tabular}{@{}ll@{}}\\\\n\\\\\\\\toprule\\\\n\\\\\\\\textbf{Parameter} & \\\\\\\\textbf{Value} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{2}{@{}l}{\\\\\\\\textit{Model}} \\\\\\\\\\\\\\\\\\\\nBase model & Qwen3-4B \\\\\\\\\\\\\\\\\\\\nPrecision & BF16 \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{2}{@{}l}{\\\\\\\\textit{GRPO Training}} \\\\\\\\\\\\\\\\\\\\nRollouts per prompt ($K$) & 8 \\\\\\\\\\\\\\\\\\\\nTraining steps (default) & 500 \\\\\\\\\\\\\\\\\\\\nTraining steps (extended) & 1000 \\\\\\\\\\\\\\\\\\\\nLearning rate & $1 \\\\\\\\times 10^{-6}$ \\\\\\\\\\\\\\\\\\\\nPer-device batch size & 4 \\\\\\\\\\\\\\\\\\\\nGradient accumulation steps & 2 \\\\\\\\\\\\\\\\\\\\nEffective batch size & 8 \\\\\\\\\\\\\\\\\\\\nMax completion length & 512 tokens \\\\\\\\\\\\\\\\\\\\nRandom seeds & 42, 43, 44 \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{2}{@{}l}{\\\\\\\\textit{Data}} \\\\\\\\\\\\\\\\\\\\nTraining set & FOLIO, 500 examples \\\\\\\\\\\\\\\\\\\\nEvaluation set & FOLIO, 100 examples (held-out) \\\\\\\\\\\\\\\\\\\\nData file & \\\\\\\\texttt{train\\\\\\\\_500\\\\\\\\_seed42} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{2}{@{}l}{\\\\\\\\textit{Solvers}} \\\\\\\\\\\\\\\\\\\\nFOL solver & Prover9 \\\\\\\\\\\\\\\\\\\\nProlog solver & SWI-Prolog 8.4.2 \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{2}{@{}l}{\\\\\\\\textit{Evaluation}} \\\\\\\\\\\\\\\\\\\\nDecoding & Greedy ($T{=}0$) \\\\\\\\\\\\\\\\\\\\nISR computation & \\\\\\\\texttt{eval\\\\\\\\_sta.py} \\\\\\\\\\\\\\\\\\\\nISR variant & Proved-only (ISR$^*$) \\\\\\\\\\\\\\\\\\\\n\\\\\\\\bottomrule\\\\n\\\\\\\\end{tabular}}\\\\n\\\\\\\\end{table}\\\\n\\\\n\\\\\\\\paragraph{Evaluation exception.}\\\\nFOL exec-only seed~43 (\\\\\\\\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.\\\\nIts PR and ISR values are included for completeness but are not strictly comparable with other seeds under the unified evaluation protocol (C004).\\\\n\\\\n\\\\n\\\\\\\\section{STA Algorithm}\\\\n\\\\\\\\label{app:algorithm}\\\\n\\\\nAlgorithm~\\\\\\\\ref{alg:sta} (Section~\\\\\\\\ref{sec:sta}) gives the procedure for computing ISR over a proved formalization.\\\\nFor unproved samples ($S(x) \\\\\\\\neq \\\\\\\\textit{proved}$), ISR is undefined and the protocol is not applied.\\\\n\\\\n\\\\n\\\\\\\\section{Extended Discussion}\\\\n\\\\\\\\label{app:extended-discussion}\\\\n\\\\n\\\\\\\\paragraph{What ISR measures---and what it does not.}\\\\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\\\\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\\\\nWe verify this empirically: Spearman $\\\\\\\\rho(\\\\\\\\text{ISR}, \\\\\\\\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\\\\nISR and downstream task performance are uncorrelated.\\\\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\\\\n\\\\nCritically, low ISR carries different semantics depending on the training objective.\\\\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).\\\\nUnder ISR-as-reward, high ISR reflects metric gaming (\\\\\\\\S\\\\\\\\ref{sec:goodhart}).\\\\nISR values must always be interpreted relative to the optimization objective that produced them.\\\\n\\\\n\\\\\\\\paragraph{The premise-count confound.}\\\\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\\\\nA formalization with 2 premises where both are necessary yields ISR${=}1.0$; one with 10 premises where 8 are necessary yields ISR${=}0.8$---even though the latter encodes richer reasoning.\\\\nThis confound explains the sole apparent ISR-as-reward success (\\\\\\\\S\\\\\\\\ref{sec:goodhart}): ISR $\\\\\\\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\\\\n\\\\n\\\\n... [截断: 输出过长，省略 16777 字符] ...\\\\n\\\\nsion),\\\\nseed~43 generates uppercase pseudo-Prolog that bypasses the text-match classifier while remaining functionally tautological,\\\\nand seed~44 converts NL conclusions to snake\\\\\\\\_case atoms used as both fact and query.\\\\nThe diversity of gaming pathways across seeds---despite identical training data and reward function---demonstrates that Goodhart's Law in neurosymbolic reasoning is not a single failure mode but a family of convergent exploits.\\\\n\\\\n\\\\\\\\subsection{Per-Seed Results at $\\\\\\\\beta{=}0.3$}\\\\n\\\\\\\\label{app:beta03}\\\\n\\\\nTable~\\\\\\\\ref{tab:beta03-detailed} reports per-seed results for both ISR and Random reward at $\\\\\\\\beta{=}0.3$.\\\\nThe three ISR seeds illustrate qualitatively distinct Goodhart pathways (\\\\\\\\S\\\\\\\\ref{sec:goodhart}).\\\\n\\\\n\\\\\\\\begin{table}[h]\\\\n\\\\\\\\centering\\\\n\\\\\\\\caption{Per-seed results at $\\\\\\\\beta{=}0.3$ (FOL). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H = percentage among proved samples.}\\\\n\\\\\\\\label{tab:beta03-detailed}\\\\n\\\\\\\\small\\\\n\\\\\\\\begin{tabular}{@{}llcccccl@{}}\\\\n\\\\\\\\toprule\\\\n\\\\\\\\textbf{Condition} & \\\\\\\\textbf{Seed} & \\\\\\\\textbf{PR} & \\\\\\\\textbf{ISR$^*$} & \\\\\\\\textbf{H7\\\\\\\\%} & \\\\\\\\textbf{H1\\\\\\\\%} & \\\\\\\\textbf{N-H\\\\\\\\%} & \\\\\\\\textbf{Mode} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{8}{@{}l}{\\\\\\\\textit{ISR $\\\\\\\\beta{=}0.3$}} \\\\\\\\\\\\\\\\\\\\n  & 42 & 0.18 & 0.143 & 0 & 77.8 & 22.2 & Reward collapse ($n{=}18$) \\\\\\\\\\\\\\\\\\\\n  & 43 & 0.86 & 0.295 & 4.7 & 68.6 & 26.7 & H1 shortcutting \\\\\\\\\\\\\\\\\\\\n  & 44 & 0.95 & 0.742 & \\\\\\\\textbf{100} & 0 & 0 & Pure H7 meta-Goodhart \\\\\\\\\\\\\\\\\\\\n\\\\\\\\cmidrule(l){2-8}\\\\n  & \\\\\\\\multicolumn{2}{l}{3-seed mean$\\\\\\\\pm$std} & \\\\\\\\makebox[0pt][l]{$0.66{\\\\\\\\pm}0.42$} & & \\\\\\\\makebox[0pt][l]{$0.39{\\\\\\\\pm}0.31$} & & \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\multicolumn{8}{@{}l}{\\\\\\\\textit{Random $\\\\\\\\beta{=}0.3$}} \\\\\\\\\\\\\\\\\\\\n  & 42 & 0.48 & 0.094 & 0 & 100 & 0 & \\\\\\\\\\\\\\\\\\\\n  & 43 & 0.92 & 0.180 & 7.6 & 90.2 & 2.2 & \\\\\\\\\\\\\\\\\\\\n  & 44 & 0.23 & 0 & 0 & 100 & 0 & \\\\\\\\\\\\\\\\\\\\n\\\\\\\\cmidrule(l){2-8}\\\\n  & \\\\\\\\multicolumn{2}{l}{3-seed mean$\\\\\\\\pm$std} & \\\\\\\\makebox[0pt][l]{$0.54{\\\\\\\\pm}0.35$} & & \\\\\\\\makebox[0pt][l]{$0.09{\\\\\\\\pm}0.09$} & & \\\\\\\\\\\\\\\\\\\\n\\\\\\\\bottomrule\\\\n\\\\\\\\end{tabular}\\\\n\\\\\\\\end{table}\\\\n\\\\n\\\\\\\\subsection{Early-Training Hacking Analysis (100-Step Checkpoint)}\\\\n\\\\\\\\label{app:100step}\\\\n\\\\nTo control for the prove-rate confound in our SFT comparison (\\\\\\\\S\\\\\\\\ref{sec:diagnostic}), we analyze the exec-only checkpoint at 100 training steps (seed~42), where PR${=}32$\\\\\\\\%---higher than SFT (14\\\\\\\\%) but still early in training.\\\\nOf the 32 proved samples, 9 (28.1\\\\\\\\%) exhibit H7 hacking (single premise identical to conclusion) and 1 (3.1\\\\\\\\%) exhibits H1 (conclusion embedded among premises), yielding a total hacking rate of 31.2\\\\\\\\%.\\\\nBy contrast, SFT at comparable or lower PR shows 7.1\\\\\\\\% hacking (1/14 proved samples).\\\\nThis demonstrates that reward hacking emerges early in GRPO training---well before the prove-rate plateau---and is not simply an artifact of having more proved samples available for exploitation.\\\\nThe 100-step hacking rate (31.2\\\\\\\\%) is already substantially above SFT (7.1\\\\\\\\%), supporting the claim that hacking is associated with RL optimization rather than prove-rate level alone.\\\\n\\\\n\\\\\\\\subsection{$O(1)$ vs.\\\\\\\\ $O(n)$ ISR Ablation}\\\\n\\\\\\\\label{app:o1-ablation}\\\\n\\\\nTo justify the per-clause LOO design (\\\\\\\\S\\\\\\\\ref{sec:sta}), we train a variant that replaces the $O(n)$ ablation with a cheaper $O(1)$ binary signal: $\\\\\\\\text{fast\\\\\\\\_ISR}(x) = 1$ if $x$ is proved, $0$ otherwise.\\\\nThe reward becomes $r = 0.5\\\\\\\\,r_{\\\\\\\\text{exec}} + 0.5\\\\\\\\,\\\\\\\\text{fast\\\\\\\\_ISR}$, which collapses to $r_{\\\\\\\\text{exec}}$ for all proved samples (every proved formalization receives $\\\\\\\\text{fast\\\\\\\\_ISR}{=}1$).\\\\nAfter 500 steps (seed~42), this variant achieves $\\\\\\\\text{PR}{=}63\\\\\\\\%$ with $\\\\\\\\text{ISR}^*{=}0.007$---functionally zero---compared to $\\\\\\\\text{ISR}^*{=}0.132$ under standard exec-only and $\\\\\\\\text{ISR}^*{=}0.42$ under ISR $\\\\\\\\beta{=}0.1$.\\\\nInspection of the generated formalizations reveals the mechanism: the model emits $60{+}$ repeated ground facts per problem; since each individual copy is redundant, LOO removal of any single copy never changes the proof outcome, driving ISR to zero.\\\\nThe result confirms that the $O(n)$ per-clause ablation is necessary for ISR to carry a structural signal: without fine-grained component-level necessity testing, the metric degenerates.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.52}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"% Appendix — solver-trace-ablation\\n\\n\\\\section{Experimental Setup}\\n\\\\label{app:setup}\\n\\nTable~\\\\ref{tab:hyperparams} lists all hyperparameters shared across experiments.\\nAll RL conditions use the same GRPO configuration; only the reward function differs.\\nSeeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).\\n\\n\\\\begin{table}[h]\\n\\\\centering\\n\\\\caption{Training hyperparameters for all GRPO experiments.}\\n\\\\label{tab:hyperparams}\\n\\\\footnotesize\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{@{}ll@{}}\\n\\\\toprule\\n\\\\textbf{Parameter} & \\\\textbf{Value} \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Model}} \\\\\\\\\\nBase model & Qwen3-4B \\\\\\\\\\nPrecision & BF16 \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{GRPO Training}} \\\\\\\\\\nRollouts per prompt ($K$) & 8 \\\\\\\\\\nTraining steps (default) & 500 \\\\\\\\\\nTraining steps (extended) & 1000 \\\\\\\\\\nLearning rate & $1 \\\\times 10^{-6}$ \\\\\\\\\\nPer-device batch size & 4 \\\\\\\\\\nGradient accumulation steps & 2 \\\\\\\\\\nEffective batch size & 8 \\\\\\\\\\nMax completion length & 512 tokens \\\\\\\\\\nRandom seeds & 42, 43, 44 \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Data}} \\\\\\\\\\nTraining set & FOLIO, 500 examples \\\\\\\\\\nEvaluation set & FOLIO, 100 examples (held-out) \\\\\\\\\\nData file & \\\\texttt{train\\\\_500\\\\_seed42} \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Solvers}} \\\\\\\\\\nFOL solver & Prover9 \\\\\\\\\\nProlog solver & SWI-Prolog 8.4.2 \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{2}{@{}l}{\\\\textit{Evaluation}} \\\\\\\\\\nDecoding & Greedy ($T{=}0$) \\\\\\\\\\nISR computation & \\\\texttt{eval\\\\_sta.py} \\\\\\\\\\nISR variant & Proved-only (ISR$^*$) \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\end{table}\\n\\n\\\\paragraph{Evaluation exception.}\\nFOL exec-only seed~43 (\\\\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.\\nIts PR and ISR values are included for completeness but are not strictly comparable with other seeds under the unified evaluation protocol (C004).\\n\\n\\n\\\\section{STA Algorithm}\\n\\\\label{app:algorithm}\\n\\nAlgorithm~\\\\ref{alg:sta} (Section~\\\\ref{sec:sta}) gives the procedure for computing ISR over a proved formalization.\\nFor unproved samples ($S(x) \\\\neq \\\\textit{proved}$), ISR is undefined and the protocol is not applied.\\n\\n\\n\\\\section{Extended Discussion}\\n\\\\label{app:extended-discussion}\\n\\n\\\\paragraph{What ISR measures---and what it does not.}\\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\\nWe verify this empirically: Spearman $\\\\rho(\\\\text{ISR}, \\\\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\\nISR and downstream task performance are uncorrelated.\\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\\n\\nCritically, low ISR carries different semantics depending on the training objective.\\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\\\S\\\\ref{sec:crosslogic}).\\nUnder ISR-as-reward, high ISR reflects metric gaming (\\\\S\\\\ref{sec:goodhart}).\\nISR values must always be interpreted relative to the optimization objective that produced them.\\n\\n\\\\paragraph{The premise-count confound.}\\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\\nA formalization with 2 premises where both are necessary yields ISR${=}1.0$; one with 10 premises where 8 are necessary yields ISR${=}0.8$---even though the latter encodes richer reasoning.\\nThis confound explains the sole apparent ISR-as-reward success (\\\\S\\\\ref{sec:goodhart}): ISR $\\\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\\n\\n\\n... [截断: 输出过长，省略 16777 字符] ...\\n\\nsion),\\nseed~43 generates uppercase pseudo-Prolog that bypasses the text-match classifier while remaining functionally tautological,\\nand seed~44 converts NL conclusions to snake\\\\_case atoms used as both fact and query.\\nThe diversity of gaming pathways across seeds---despite identical training data and reward function---demonstrates that Goodhart's Law in neurosymbolic reasoning is not a single failure mode but a family of convergent exploits.\\n\\n\\\\subsection{Per-Seed Results at $\\\\beta{=}0.3$}\\n\\\\label{app:beta03}\\n\\nTable~\\\\ref{tab:beta03-detailed} reports per-seed results for both ISR and Random reward at $\\\\beta{=}0.3$.\\nThe three ISR seeds illustrate qualitatively distinct Goodhart pathways (\\\\S\\\\ref{sec:goodhart}).\\n\\n\\\\begin{table}[h]\\n\\\\centering\\n\\\\caption{Per-seed results at $\\\\beta{=}0.3$ (FOL). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H = percentage among proved samples.}\\n\\\\label{tab:beta03-detailed}\\n\\\\small\\n\\\\begin{tabular}{@{}llcccccl@{}}\\n\\\\toprule\\n\\\\textbf{Condition} & \\\\textbf{Seed} & \\\\textbf{PR} & \\\\textbf{ISR$^*$} & \\\\textbf{H7\\\\%} & \\\\textbf{H1\\\\%} & \\\\textbf{N-H\\\\%} & \\\\textbf{Mode} \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{8}{@{}l}{\\\\textit{ISR $\\\\beta{=}0.3$}} \\\\\\\\\\n  & 42 & 0.18 & 0.143 & 0 & 77.8 & 22.2 & Reward collapse ($n{=}18$) \\\\\\\\\\n  & 43 & 0.86 & 0.295 & 4.7 & 68.6 & 26.7 & H1 shortcutting \\\\\\\\\\n  & 44 & 0.95 & 0.742 & \\\\textbf{100} & 0 & 0 & Pure H7 meta-Goodhart \\\\\\\\\\n\\\\cmidrule(l){2-8}\\n  & \\\\multicolumn{2}{l}{3-seed mean$\\\\pm$std} & \\\\makebox[0pt][l]{$0.66{\\\\pm}0.42$} & & \\\\makebox[0pt][l]{$0.39{\\\\pm}0.31$} & & \\\\\\\\\\n\\\\midrule\\n\\\\multicolumn{8}{@{}l}{\\\\textit{Random $\\\\beta{=}0.3$}} \\\\\\\\\\n  & 42 & 0.48 & 0.094 & 0 & 100 & 0 & \\\\\\\\\\n  & 43 & 0.92 & 0.180 & 7.6 & 90.2 & 2.2 & \\\\\\\\\\n  & 44 & 0.23 & 0 & 0 & 100 & 0 & \\\\\\\\\\n\\\\cmidrule(l){2-8}\\n  & \\\\multicolumn{2}{l}{3-seed mean$\\\\pm$std} & \\\\makebox[0pt][l]{$0.54{\\\\pm}0.35$} & & \\\\makebox[0pt][l]{$0.09{\\\\pm}0.09$} & & \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}\\n\\\\end{table}\\n\\n\\\\subsection{Early-Training Hacking Analysis (100-Step Checkpoint)}\\n\\\\label{app:100step}\\n\\nTo control for the prove-rate confound in our SFT comparison (\\\\S\\\\ref{sec:diagnostic}), we analyze the exec-only checkpoint at 100 training steps (seed~42), where PR${=}32$\\\\%---higher than SFT (14\\\\%) but still early in training.\\nOf the 32 proved samples, 9 (28.1\\\\%) exhibit H7 hacking (single premise identical to conclusion) and 1 (3.1\\\\%) exhibits H1 (conclusion embedded among premises), yielding a total hacking rate of 31.2\\\\%.\\nBy contrast, SFT at comparable or lower PR shows 7.1\\\\% hacking (1/14 proved samples).\\nThis demonstrates that reward hacking emerges early in GRPO training---well before the prove-rate plateau---and is not simply an artifact of having more proved samples available for exploitation.\\nThe 100-step hacking rate (31.2\\\\%) is already substantially above SFT (7.1\\\\%), supporting the claim that hacking is associated with RL optimization rather than prove-rate level alone.\\n\\n\\\\subsection{$O(1)$ vs.\\\\ $O(n)$ ISR Ablation}\\n\\\\label{app:o1-ablation}\\n\\nTo justify the per-clause LOO design (\\\\S\\\\ref{sec:sta}), we train a variant that replaces the $O(n)$ ablation with a cheaper $O(1)$ binary signal: $\\\\text{fast\\\\_ISR}(x) = 1$ if $x$ is proved, $0$ otherwise.\\nThe reward becomes $r = 0.5\\\\,r_{\\\\text{exec}} + 0.5\\\\,\\\\text{fast\\\\_ISR}$, which collapses to $r_{\\\\text{exec}}$ for all proved samples (every proved formalization receives $\\\\text{fast\\\\_ISR}{=}1$).\\nAfter 500 steps (seed~42), this variant achieves $\\\\text{PR}{=}63\\\\%$ with $\\\\text{ISR}^*{=}0.007$---functionally zero---compared to $\\\\text{ISR}^*{=}0.132$ under standard exec-only and $\\\\text{ISR}^*{=}0.42$ under ISR $\\\\beta{=}0.1$.\\nInspection of the generated formalizations reveals the mechanism: the model emits $60{+}$ repeated ground facts per problem; since each individual copy is redundant, LOO removal of any single copy never changes the proof outcome, driving ISR to zero.\\nThe result confirms that the $O(n)$ per-clause ablation is necessary for ISR to carry a structural signal: without fine-grained component-level necessity testing, the metric degenerates.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.52}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 76_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the TeX files and the registry data. Let me also read the appendix more carefully since it was truncated, and check for some specific numbers. Let me also read the decisions file to check for D076, D051, D084 references.

Let me now systematically cross-check the paper's claims against registry data.

Let me organize my findings:

## Registry data (from agent extraction):

### SFT Baselines (1000 steps):
- s42-1000: PR=0.13, proved_only_ISR=0.5677, genuine_rate=0.9231 (12/13), H7=0, H1=1 (0.0769)


- s43-1000: PR=0.11, proved_only_ISR=0.6352, genuine_rate=0.9091 (10/11), H7=0, H1=1
- s44-1000-r3: PR=0.15, proved_only_ISR=0.5892, genuine_rate=0.9333 (14/15), H7=0, H1=1 (0.0667)

The three SFT baseline runs at 1000 steps show genuine rates averaging around 92%, with the individual runs ranging from about 90.9% to 93.3%.

Computing the standard deviation across these three seeds gives me roughly 1.0%, so the overall result is approximately 92.2% ± 1.2%. The paper mentions 92.9% for non-hacking performance, but that's from a different configuration—the single-seed s42 run at 500 steps. I need to verify I'm looking at the right 1000-step SFT data in the registry. Now I'm cross-referencing the paper's SFT baseline results with what's in the registry—the paper cites plan009-sft-baseline-s42-r4 at 500 steps, but I need to verify if the metrics match up with the 1000-step version I just calculated. Now I'm cross-referencing the exec-only s42 results with what the paper claims about the progression across step counts. The registry data confirms the paper's narrative: as steps increase from 500 to 1000, proof rate climbs from 93% to 96% while the irrelevant statement rate drops sharply from 0.132 to 0.003, showing the expected scaling behavior.

For the 1000-step results, I need to verify the paper's claim that 94.8% of proved samples have zero irrelevant statements—with 96 total proved samples, that would mean roughly 91 samples are clean, which seems plausible given the overall ISR metric but I'd need the full distribution to confirm. The component count inflation from 6.58 to 18.55 matches the registry data for the 1000-step configuration.

Looking at the ISR β=0.3 variants now, I'm seeing a stark contrast across the three settings: s42 shows severe reward collapse with minimal proof rate, while s43 demonstrates much stronger performance with H1 shortcutting as the dominant failure mode, and s44 appears to follow a similar pattern.

But I'm noticing a discrepancy—the registry entry for s42 shows PR=0.95 with mostly H1 and H8 components, whereas the paper table lists PR=0.18 for the same seed, suggesting these might be different experimental configurations or I'm mismatching the parameter settings.

Looking at the paper's methodology more carefully, the default is 500 steps with 1000 steps noted explicitly, so the β=0.3 results are likely from 500-step runs. I need to find the corresponding 500-step experiments rather than the 1000-step ones I've been examining. The agent's search turned up a few candidates like s43 and its retrained variant, but none perfectly match the paper's reported metrics yet. I'm noticing the 500-step version of s42 isn't showing up in the registry, which is a gap in my audit. The paper_framing document lists it with PR=18% and H1=78%, which matches the paper's H1=77.8% when accounting for rounding. Since the task reference aligns and paper_framing is my canonical source, I'll proceed with that data and move on to checking the Random β=0.3 results.

Now I'm cross-referencing the paper's appendix table for Random β=0.3 against the registry entries—s43 and s44 both check out with matching metrics, though I'm still missing the s42 entry in the registry. Now I'm verifying the paper's reported means by calculating them from the individual experiment values. For the Random β=0.3 condition, the mean PR of 0.54±0.35 checks out when I average the three runs and compute the standard deviation. I'm doing the same verification for the ISR β=0.3 mean to confirm those numbers match as well. I'm finding a discrepancy between the paper's reported H7 rate of 64.5% (149/231) and what the registry data shows at 69.7% (161/231)—a difference of 12 cases that appears to correspond to a subcategory distinction in the paper's H7 breakdown. I'm noticing a discrepancy in paper_framing itself—it reports H7 as 64.5% (149/231), but that 149 appears to be outdated, using the pre-D085 correction value of 13+59+77 instead of the corrected 13+59+89, which should give 161/231 or 69.7%. Yet the TeX paper consistently states 64.5% across the abstract, introduction, experiments, and conclusion sections, so there's an inconsistency between what paper_framing claims and what the actual paper reports. number is 69.7% (after D085 FN correction including H7b), then 64.5% is wrong.

But wait - let me re-read D085 more carefully. The paper_framing says "H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89" for s44. So the original H7 count for s44 was 77 (text-match only). After D085, it should be 89.

Let me re-check:
- s42: H7 = 13 (text-match, unchanged)
- s43: H7 = 59 (text-match, unchanged)
- s44: H7 = 89 (77 H7a + 12 H7b, D085 corrected)

So the original total was 149, giving 64.5%, but with the correction it should be 161 for 69.7%. The paper still reports 64.5%, which suggests the D085 correction wasn't applied to the final numbers. Though looking at the taxonomy table, it seems the paper might be intentionally using only the strict text-match H7a cases, keeping H7b separate. Looking at the taxonomy count, I'm seeing seven modes listed in the paper, but the task specifies there should be eight categories including H8 for conjunction collapse. Checking the registry data, H8 is definitely being tracked with specific counts and rates, yet it's missing from the paper's taxonomy section—there's a discrepancy between what's documented and what's actually being measured.

I've also verified that the "2.4x" red line has been removed from the text, which is good. Now I'm cross-referencing the registry data for the ISR β=0.3 experiment to check the "genuine=43.2%" claim, and I'm finding the H8 value sits at 41, which translates to 43.2%.

However, the task correction specifies that at 1000 steps, genuine should be 0%, not 43.2%. The paper's appendix shows a different result at what appears to be 500 steps with N-H=22.2%, so these are separate experiments. I don't see the 43.2% figure appearing anywhere else in the paper, which is what we want.

Looking at the actual 1000-step data now, the 43.2% refers to the H8 rate, not genuine accuracy—all 95 proved samples fall into either H1 or H8 categories with genuine=0%. The paper doesn't reference this particular 1000-step β=0.3 experiment, so there's no conflict there.

For the SFT 3-seed claim, the paper doesn't explicitly state "92.2%±1.2%"—it consistently uses the single-seed s42 result of "92.9% non-hacking" throughout, which I should verify matches what's actually written.

Now I'm cross-checking the baseline numbers. The paper cites a 500-step result with PR=0.14, ISR=0.08, proved-only ISR=0.571, H7=0, H1=7.1%, and 92.9% genuine accuracy, but my registry data shows the 1000-step version has slightly different metrics. The registry agent didn't pull the specific 500-step s42 variant, so I need to track down whether that's the right comparison point.

Moving on to verify the β=0.1 ISR numbers next. The pooled H1 rate across all three seeds comes to 18.2%, which matches the paper. For the random β=0.1 condition, only seed 42 is complete with H1 at 70.9% and non-hacking at 29.1%, but the paper's table shows 81% for H1—that higher percentage must be coming from somewhere else in their calculation.

Looking at the experiments section more carefully, I see the paper is actually using provisional data from seeds 43 and 44 (marked as 93.2% and 79.8% respectively) that haven't finished retraining yet. The registry confirms these are still in PREPARING status, so the paper is citing deprecated provisional numbers for the random β=0.1 pooled statistics rather than waiting for the complete results. significant issue.

Wait, but actually looking at the registry again:
- plan018-additive-random-b01-s43-r3: PREPARING
- plan018-additive-random-b01-s44-r2: PREPARING

These are the retraining experiments. The original experiments (plan018-additive-random-b01-s43, plan018-additive-random-b01-s44) might have data but were invalidated. The original data was from a different eval set.

So the paper's random β=0.1 3-seed pooled numbers (H1=81%, N-H=19%) include PROVISIONAL data that hasn't been confirmed. This should be flagged.

### Premise-count-matched:
Paper: "1.06× after controlling for a premise-count confound"
Paper_framing: "premise-count-matched 1.06x" ✓
No "2.4x" found in paper ✓

### Cross-seed instability:
Paper: "σ±47 pp"
Exec-only seeds: s42 PR=93%, s43 PR=14%, s44 PR=98%
Mean = (93+14+98)/3 = 68.3%
Std = sqrt(((93-68.3)^2 + (14-68.3)^2 + (98-68.3)^2)/2) = sqrt((610+2950+882)/2) = sqrt(2221) = 47.1 ✓

But s43 has an evaluation exception in the registry—it was run with sampling temperature=0.7 instead of greedy decoding, which the appendix notes. This makes s43 not directly comparable to the other seeds, so the cross-seed instability calculation might be inflated by this methodological difference.

### ISR collapse trajectory:
The paper reports a 99.5% degradation from 0.642 to 0.003 over 100→500→1000 steps, which checks out mathematically. The 214× collapse ratio also matches the ratio of those endpoints.

### Number of hacking modes:
The paper consistently refers to a "seven-mode" taxonomy throughout the abstract, introduction, and contribution statements, but the task requires eight modes with H8 representing conjunction collapse. This is a critical mismatch.

### H8 = conjunction collapse:
I'm trying to reconcile whether "conjunction collapse" and "contradiction explosion" are the same phenomenon. The paper's taxonomy table shows "Contradiction" appearing only at 1000 steps in the exec-only condition, but the registry data shows H8 (conjunction collapse) appearing at 500 steps with measurable percentages in both exec-only and ISR conditions. The timing and prevalence don't align, suggesting these might be distinct modes or the paper's categorization doesn't cleanly map to the required H8 definition. The paper only reports H8 at the 1000-step execution point, missing the earlier occurrences at β=0.1 and β=0.3. Looking back at the taxonomy, I'm noticing the paper distinguishes H8 (conjunction collapse) as separate from "contradiction explosion," but the method section seems to conflate them—I need to trace through exactly which modes map to which failure types across the different experimental conditions. Looking at the registry data, "contradiction explosion" appears in the taxonomy at 1k steps, but all 96 proved samples are classified as H1. The paper describes this as when the model generates contradictory premises like P and ¬P, allowing any conclusion to be proved via ex falso—which seems distinct from conjunction collapse (H8). The task requires 8 modes total, so I need to figure out whether "contradiction explosion" is a separate mode or a sub-phenomenon of H1.

Now I'm cross-checking the abstract claims against the experimental results: the 93% FOLIO performance matches, the 87% embed conclusion aligns with H1=87.1%, the ISR definition checks out, and the correlation coefficient ρ=−0.049 is confirmed. I'm also verifying the ISR and PR trajectories across different plans to ensure the numbers in the paper are consistent with what the experiments actually show. Now I'm verifying the experimental results across different seeds and conditions. The Prolog section checks out—all three seeds show gaming behavior with zero legitimate solutions. I'm also noting a discrepancy: the hacking modes should total 8 per task, not 7. Moving through the Introduction claims, most align with my computed values: the 93% prove rate and 87% embed conclusion for s42 match, the ISR degradation curve is correct, and the variance estimates check out. For s43, I need to confirm that 87% truncation figure from the registry using the execution-only run at temperature 0.7, and I'm still verifying the s44 results where the prove rate hits 98%.

In the Experiments section, I'm tracking the prove rate progression from 32% up through 93% to 96%, confirming the ISR values hold, but I need to verify that 94.8% claim about proved samples having zero ISR. There's also a component count inflation issue I'm investigating. I'm noticing the paper mentions a "P→P tautological collapse" issue with plan013 where it achieves perfect precision but only through circular reasoning. There's also a note about an earlier convex formulation that was abandoned. Now I'm looking at the detailed metrics from the appendix for different β values, particularly comparing how the ISR and precision scores vary across the s42, s43, and s44 configurations. Now I'm verifying the results against the paper's reported values—the ISR metrics are matching up correctly across different seeds and beta parameters, with the genuine detection rates and H7 percentages all checking out as expected. I'm realizing H1 and H7 might actually overlap or have a hierarchical relationship. H7 is defined as a single premise equaling the conclusion, while H1 is about conclusions embedded among multiple premises—so they could be mutually exclusive categories. But if H7=7 and H1=90, that's 97 total, which exceeds the 92 proved samples, suggesting either the counts are off or there's some overlap I'm not accounting for. I'm trying to reconcile the definitions—H1 should be "conclusion embedded in multiple premises" while H7 is "single premise equals conclusion," so they should be mutually exclusive. But the numbers don't add up: H1=90 plus H7=7 totals 97, yet only 92 samples were proved. Either the counts are from the full 100 samples rather than just the proved ones, or there's some overlap I'm not accounting for. Let me check if H1_strict_count=90 might actually be counting something different than I think. So breaking down the percentages into actual sample counts: 90.2% of the 92 proved samples gives 83, the 7.6% gives 7 samples, and 2.2% gives 2 samples, which adds up correctly to 92. But the registry data shows H1=90 with a 97.8% rate, which contradicts the paper's 90.2% figure. I need to figure out where this discrepancy is coming from—whether the registry values are incorrect or if I'm misinterpreting them.

Looking at the breakdown more carefully, if the rate of 0.978 represents 90 out of 92 proved samples rather than out of all 100, then the counts would be: 90 H1 samples, 7 H7 samples, and 2 genuine samples, totaling 99 instead of 92. There's still something off with how these numbers are being calculated or reported.

The paper presents these as mutually exclusive categories that sum to 100%, but if I work backwards from the percentages—computing H1 as the residual after subtracting H7 (7.6%) and genuine (2.2%) from 100%—I get exactly 90.2%, which matches what the paper reports. So the paper's table is internally consistent, but it doesn't align with the registry's raw counts. Now I'm verifying the paper's exclusive H1 calculations across different experiments to make sure the pattern holds consistently. For the random β=0.3 cases, the numbers check out perfectly—all proved samples are classified as H1 with no H7 overlap. But for the ISR β=0.3 experiment, I need to finish adding up the registry counts to see if they align with the paper's reported percentages. I'm noticing the registry counts H1 inconsistently across experiments—sometimes exclusive of H7, sometimes not—which suggests a data quality issue. But looking at the paper's percentages, if they computed H1 as the residual (100% minus H7 and N-H percentages), then the numbers would be internally consistent regardless of how the registry categorized them.

Now I need to check the middle section of experiments.tex that got truncated, particularly the Goodhart section around §4.2, to see what specific numbers might be there. I should also verify whether the paper uses "significantly" anywhere—so far I haven't spotted it, though the conclusion does mention "extreme cross-seed instability" with actual data backing it up.

Looking at what I've found so far: the H7 percentages don't match (64.5% vs 69.7% depending on whether H7b is included), the paper claims seven hacking modes but should list eight including H8, the Random β=0.1 pooled results appear to use provisional data from seeds still in retraining, there's a 100-step checkpoint claim I need to source, and the Prolog ISR value needs verification.

For s42 specifically, I'm confirming that the ISR=1.0 makes sense because all 50 proved cases are single-premise H7 tautologies where leave-one-out validation would fail if you remove the premise, but the mean ISR across all 100 cases (proved and unproved) would be 0.5. The paper's statement about "clean H7 tautologies (ISR*=1.0, all 50/100 proved)" checks out for the proved-only metric.

Now I need to track down the Random β=0.3 s42 data source and verify the bootstrap confidence interval numbers mentioned in the experiments section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "4a886db1-d464-4ed1-943e-1605d68ad11d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BfUvXar6WD87CbL16yVbGU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18926,
      "cache_read_input_tokens": 41793,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18926
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

_source line 77_

Registry data extracted. Now reading the truncated middle section of experiments.tex and checking for more detail.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "4bc22f8a-57d5-4743-be13-86f5a4a941a5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BfUvXar6WD87CbL16yVbGU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18926,
      "cache_read_input_tokens": 41793,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18926
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

_source line 78_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01VFQwjAbaMmwSaT3yyfDnnV`</summary>

```json
{
  "server": "westd-39279",
  "command": "head -200 /root/solver-trace-ablation/paper/experiments.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "410da57d-53bd-4cd8-a0ac-23ec16b7da89",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BfUvXar6WD87CbL16yVbGU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18926,
      "cache_read_input_tokens": 41793,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18926
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

_source line 79 · 2026-05-15T15:03:15.663Z_

<details><summary>↩ Tool result · `toolu_01VFQwjAbaMmwSaT3yyfDnnV`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Experiments}\\n\\\\label{sec:experiments}\\n\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\S\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\S\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\S\\\\ref{sec:crosslogic}).\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\S\\\\ref{sec:taxonomy}).\\n\\n\\\\subsection{Setup}\\\\label{sec:setup}\\n\\nWe train Qwen3-4B~\\\\citep{qwen3} with GRPO~\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\{42,43,44\\\\}$ on a fixed 500-example FOLIO~\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\footnote{All experiments use \\\\texttt{data/train\\\\_500\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\nHeld-out evaluation uses 100 FOLIO examples (\\\\texttt{proofwriter\\\\_fol\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\texttt{eval\\\\_sta.py}) so training-log ISR is never compared across runs.\\nWe report prove rate (PR), proved-only ISR ($\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution; \\\\S\\\\ref{sec:taxonomy-method}), and a \\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\n\\n\\\\subsection{ISR as Diagnostic}\\n\\\\label{sec:diagnostic}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.95\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\n\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\%$\\\\to$93\\\\%$\\\\to$96\\\\% while proved-only ISR falls $0.642{\\\\to}0.132{\\\\to}0.003$ over 100$\\\\to$500$\\\\to$1000 steps. By step 1000, 94.8\\\\% of proved samples have $\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\to$18.55 (contradiction explosion).}\\n\\\\label{fig:isr-collapse}\\n\\\\end{figure}\\n\\n\\\\textbf{Collapse trajectory.}\\nFigure~\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\nPR rises $32\\\\%\\\\to93\\\\%\\\\to96\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\to0.132\\\\to0.003$ (214$\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\nBy 500 steps, 87.1\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\% and mean component count more than doubles ($6.58\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\nExtended training, lacking a structural signal, \\\\emph{worsens} formalization quality while improving the headline number.\\n\\n\\\\textbf{Cross-seed instability.}\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\ref{app:detailed-results}): s42 reaches $\\\\text{PR}{=}93\\\\%$ via conclusion embedding ($\\\\text{H1}{=}87\\\\%$); s43 collapses to $\\\\text{PR}{=}14\\\\%$ via repetition (87\\\\% of rollouts truncated); s44 reaches $\\\\text{PR}{=}98\\\\%$ via tautological collapse ($\\\\text{H7}{=}100\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\nThe cross-seed PR variance ($\\\\sigma{\\\\pm}47$\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\n\\n\\\\textbf{SFT baseline.}\\nSFT on gold formalizations reaches $\\\\text{PR}{=}14\\\\%$ with $\\\\text{ISR}^{*}{=}0.571$, $\\\\text{H7}{=}0$, $\\\\text{H1}{=}7.1\\\\%$, $92.9\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\nA 100-step RL checkpoint (Appendi\\n\\n... [截断: 输出过长，省略 6955 字符] ...\\n\\n tautologies ($\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\nSeed~43: \\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\texttt{MARY\\\\_IS\\\\_AN\\\\_AVA\\\\-DEOTE.}); strict text-match returns $\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\nSeed~44: \\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\texttt{is\\\\_the\\\\_dog\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\nSeed~44 evaded our initial strict classifier (reported $100\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\n\\n\\\\subsection{Hacking Taxonomy}\\n\\\\label{sec:taxonomy}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\n\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\n\\\\label{fig:hacking-composition}\\n\\\\end{figure}\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lccccc}\\n\\\\toprule\\n\\\\textbf{Mode} & \\\\textbf{Exec} & \\\\textbf{ISR$_{.1}$} & \\\\textbf{Rnd$_{.1}$} & \\\\textbf{SFT} & \\\\textbf{Prolog$_{\\\\text{ISR}}$} \\\\\\\\\\n\\\\midrule\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\sharp$ \\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\sharp$ \\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\nCmplx.\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\n\\\\midrule\\n\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\textbf{93} & \\\\textbf{0} \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Seven hacking modes across conditions (\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\sharp$Prolog row pools strict+functional (\\\\S\\\\ref{sec:crosslogic}).}\\n\\\\label{tab:hacking-taxonomy}\\n\\\\end{table}\\n\\nThe seven modes (Table~\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\ref{app:hacking-modes}) span the studied conditions.\\nTwo are quantifiable across all conditions: \\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\%$ regardless of reward type, and \\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\%$ vs.\\\\ $0\\\\%$ in random controls.\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\n\\nThe cross-condition pattern is consistent with \\\\S\\\\ref{sec:goodhart}: \\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\nExec-only, ISR, and random conditions all show $\\\\geq 80\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\%$ non-hacking.\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\beta{=}0.1$ s42 at $\\\\text{PR}{=}81\\\\%$, $31\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.51}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "a5eec92e-4a12-4101-bfb4-7925dc5d435f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Experiments}\\\\n\\\\\\\\label{sec:experiments}\\\\n\\\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\\\\\S\\\\\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\\\\\S\\\\\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).\\\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\\\\\S\\\\\\\\ref{sec:taxonomy}).\\\\n\\\\n\\\\\\\\subsection{Setup}\\\\\\\\label{sec:setup}\\\\n\\\\nWe train Qwen3-4B~\\\\\\\\citep{qwen3} with GRPO~\\\\\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\\\\\{42,43,44\\\\\\\\}$ on a fixed 500-example FOLIO~\\\\\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\\\\\footnote{All experiments use \\\\\\\\texttt{data/train\\\\\\\\_500\\\\\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\\\nHeld-out evaluation uses 100 FOLIO examples (\\\\\\\\texttt{proofwriter\\\\\\\\_fol\\\\\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\\\\\texttt{eval\\\\\\\\_sta.py}) so training-log ISR is never compared across runs.\\\\nWe report prove rate (PR), proved-only ISR ($\\\\\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\\\\\text{necessary}}$ distribution; \\\\\\\\S\\\\\\\\ref{sec:taxonomy-method}), and a \\\\\\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\\\n\\\\n\\\\\\\\subsection{ISR as Diagnostic}\\\\n\\\\\\\\label{sec:diagnostic}\\\\n\\\\n\\\\\\\\begin{figure}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.95\\\\\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\\\n\\\\\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\\\\\%$\\\\\\\\to$93\\\\\\\\%$\\\\\\\\to$96\\\\\\\\% while proved-only ISR falls $0.642{\\\\\\\\to}0.132{\\\\\\\\to}0.003$ over 100$\\\\\\\\to$500$\\\\\\\\to$1000 steps. By step 1000, 94.8\\\\\\\\% of proved samples have $\\\\\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\\\\\to$18.55 (contradiction explosion).}\\\\n\\\\\\\\label{fig:isr-collapse}\\\\n\\\\\\\\end{figure}\\\\n\\\\n\\\\\\\\textbf{Collapse trajectory.}\\\\nFigure~\\\\\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\\\nPR rises $32\\\\\\\\%\\\\\\\\to93\\\\\\\\%\\\\\\\\to96\\\\\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\\\\\to0.132\\\\\\\\to0.003$ (214$\\\\\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\\\nBy 500 steps, 87.1\\\\\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\\\\\% and mean component count more than doubles ($6.58\\\\\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\\\nExtended training, lacking a structural signal, \\\\\\\\emph{worsens} formalization quality while improving the headline number.\\\\n\\\\n\\\\\\\\textbf{Cross-seed instability.}\\\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\\\\\ref{app:detailed-results}): s42 reaches $\\\\\\\\text{PR}{=}93\\\\\\\\%$ via conclusion embedding ($\\\\\\\\text{H1}{=}87\\\\\\\\%$); s43 collapses to $\\\\\\\\text{PR}{=}14\\\\\\\\%$ via repetition (87\\\\\\\\% of rollouts truncated); s44 reaches $\\\\\\\\text{PR}{=}98\\\\\\\\%$ via tautological collapse ($\\\\\\\\text{H7}{=}100\\\\\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\\\nThe cross-seed PR variance ($\\\\\\\\sigma{\\\\\\\\pm}47$\\\\\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\\\n\\\\n\\\\\\\\textbf{SFT baseline.}\\\\nSFT on gold formalizations reaches $\\\\\\\\text{PR}{=}14\\\\\\\\%$ with $\\\\\\\\text{ISR}^{*}{=}0.571$, $\\\\\\\\text{H7}{=}0$, $\\\\\\\\text{H1}{=}7.1\\\\\\\\%$, $92.9\\\\\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\\\nA 100-step RL checkpoint (Appendi\\\\n\\\\n... [截断: 输出过长，省略 6955 字符] ...\\\\n\\\\n tautologies ($\\\\\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\\\nSeed~43: \\\\\\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\\\\\texttt{MARY\\\\\\\\_IS\\\\\\\\_AN\\\\\\\\_AVA\\\\\\\\-DEOTE.}); strict text-match returns $\\\\\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\\\nSeed~44: \\\\\\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\\\\\texttt{is\\\\\\\\_the\\\\\\\\_dog\\\\\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\\\nSeed~44 evaded our initial strict classifier (reported $100\\\\\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\\\n\\\\n\\\\\\\\subsection{Hacking Taxonomy}\\\\n\\\\\\\\label{sec:taxonomy}\\\\n\\\\n\\\\\\\\begin{figure}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.92\\\\\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\\\n\\\\\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\\\n\\\\\\\\label{fig:hacking-composition}\\\\n\\\\\\\\end{figure}\\\\n\\\\n\\\\\\\\begin{table}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\small\\\\n\\\\\\\\resizebox{\\\\\\\\columnwidth}{!}{%\\\\n\\\\\\\\begin{tabular}{lccccc}\\\\n\\\\\\\\toprule\\\\n\\\\\\\\textbf{Mode} & \\\\\\\\textbf{Exec} & \\\\\\\\textbf{ISR$_{.1}$} & \\\\\\\\textbf{Rnd$_{.1}$} & \\\\\\\\textbf{SFT} & \\\\\\\\textbf{Prolog$_{\\\\\\\\text{ISR}}$} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\\\\\sharp$ \\\\\\\\\\\\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\\\\\sharp$ \\\\\\\\\\\\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\\\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\\\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\\\\\\\\\\\nCmplx.\\\\\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\\\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\\\\\textbf{93} & \\\\\\\\textbf{0} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\bottomrule\\\\n\\\\\\\\end{tabular}}\\\\n\\\\\\\\caption{Seven hacking modes across conditions (\\\\\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\\\\\sharp$Prolog row pools strict+functional (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).}\\\\n\\\\\\\\label{tab:hacking-taxonomy}\\\\n\\\\\\\\end{table}\\\\n\\\\nThe seven modes (Table~\\\\\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\\\\\ref{app:hacking-modes}) span the studied conditions.\\\\nTwo are quantifiable across all conditions: \\\\\\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\\\\\%$ regardless of reward type, and \\\\\\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\\\\\%$ vs.\\\\\\\\ $0\\\\\\\\%$ in random controls.\\\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\\\n\\\\nThe cross-condition pattern is consistent with \\\\\\\\S\\\\\\\\ref{sec:goodhart}: \\\\\\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\\\nExec-only, ISR, and random conditions all show $\\\\\\\\geq 80\\\\\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\\\\\%$ non-hacking.\\\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\\\\\beta{=}0.1$ s42 at $\\\\\\\\text{PR}{=}81\\\\\\\\%$, $31\\\\\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.51}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Experiments}\\n\\\\label{sec:experiments}\\n\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\S\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\S\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\S\\\\ref{sec:crosslogic}).\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\S\\\\ref{sec:taxonomy}).\\n\\n\\\\subsection{Setup}\\\\label{sec:setup}\\n\\nWe train Qwen3-4B~\\\\citep{qwen3} with GRPO~\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\{42,43,44\\\\}$ on a fixed 500-example FOLIO~\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\footnote{All experiments use \\\\texttt{data/train\\\\_500\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\nHeld-out evaluation uses 100 FOLIO examples (\\\\texttt{proofwriter\\\\_fol\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\texttt{eval\\\\_sta.py}) so training-log ISR is never compared across runs.\\nWe report prove rate (PR), proved-only ISR ($\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution; \\\\S\\\\ref{sec:taxonomy-method}), and a \\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\n\\n\\\\subsection{ISR as Diagnostic}\\n\\\\label{sec:diagnostic}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.95\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\n\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\%$\\\\to$93\\\\%$\\\\to$96\\\\% while proved-only ISR falls $0.642{\\\\to}0.132{\\\\to}0.003$ over 100$\\\\to$500$\\\\to$1000 steps. By step 1000, 94.8\\\\% of proved samples have $\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\to$18.55 (contradiction explosion).}\\n\\\\label{fig:isr-collapse}\\n\\\\end{figure}\\n\\n\\\\textbf{Collapse trajectory.}\\nFigure~\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\nPR rises $32\\\\%\\\\to93\\\\%\\\\to96\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\to0.132\\\\to0.003$ (214$\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\nBy 500 steps, 87.1\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\% and mean component count more than doubles ($6.58\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\nExtended training, lacking a structural signal, \\\\emph{worsens} formalization quality while improving the headline number.\\n\\n\\\\textbf{Cross-seed instability.}\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\ref{app:detailed-results}): s42 reaches $\\\\text{PR}{=}93\\\\%$ via conclusion embedding ($\\\\text{H1}{=}87\\\\%$); s43 collapses to $\\\\text{PR}{=}14\\\\%$ via repetition (87\\\\% of rollouts truncated); s44 reaches $\\\\text{PR}{=}98\\\\%$ via tautological collapse ($\\\\text{H7}{=}100\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\nThe cross-seed PR variance ($\\\\sigma{\\\\pm}47$\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\n\\n\\\\textbf{SFT baseline.}\\nSFT on gold formalizations reaches $\\\\text{PR}{=}14\\\\%$ with $\\\\text{ISR}^{*}{=}0.571$, $\\\\text{H7}{=}0$, $\\\\text{H1}{=}7.1\\\\%$, $92.9\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\nA 100-step RL checkpoint (Appendi\\n\\n... [截断: 输出过长，省略 6955 字符] ...\\n\\n tautologies ($\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\nSeed~43: \\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\texttt{MARY\\\\_IS\\\\_AN\\\\_AVA\\\\-DEOTE.}); strict text-match returns $\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\nSeed~44: \\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\texttt{is\\\\_the\\\\_dog\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\nSeed~44 evaded our initial strict classifier (reported $100\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\n\\n\\\\subsection{Hacking Taxonomy}\\n\\\\label{sec:taxonomy}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\n\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\n\\\\label{fig:hacking-composition}\\n\\\\end{figure}\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lccccc}\\n\\\\toprule\\n\\\\textbf{Mode} & \\\\textbf{Exec} & \\\\textbf{ISR$_{.1}$} & \\\\textbf{Rnd$_{.1}$} & \\\\textbf{SFT} & \\\\textbf{Prolog$_{\\\\text{ISR}}$} \\\\\\\\\\n\\\\midrule\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\sharp$ \\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\sharp$ \\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\nCmplx.\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\n\\\\midrule\\n\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\textbf{93} & \\\\textbf{0} \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Seven hacking modes across conditions (\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\sharp$Prolog row pools strict+functional (\\\\S\\\\ref{sec:crosslogic}).}\\n\\\\label{tab:hacking-taxonomy}\\n\\\\end{table}\\n\\nThe seven modes (Table~\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\ref{app:hacking-modes}) span the studied conditions.\\nTwo are quantifiable across all conditions: \\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\%$ regardless of reward type, and \\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\%$ vs.\\\\ $0\\\\%$ in random controls.\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\n\\nThe cross-condition pattern is consistent with \\\\S\\\\ref{sec:goodhart}: \\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\nExec-only, ISR, and random conditions all show $\\\\geq 80\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\%$ non-hacking.\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\beta{=}0.1$ s42 at $\\\\text{PR}{=}81\\\\%$, $31\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.51}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 80_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_015vaVcEgDsSGfjd63drLjqr`</summary>

```json
{
  "server": "westd-39279",
  "command": "tail -n +200 /root/solver-trace-ablation/paper/experiments.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "25f098ed-71dd-4bc4-83c2-c8092a7dab92",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BfUvXar6WD87CbL16yVbGU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18926,
      "cache_read_input_tokens": 41793,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18926
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

_source line 81 · 2026-05-15T15:03:16.492Z_

<details><summary>↩ Tool result · `toolu_015vaVcEgDsSGfjd63drLjqr`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "0c548a10-305d-4819-9d23-55115b3465d7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.44}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 82_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01VLBZkD42iUxEAyB3nct95p`</summary>

```json
{
  "project": "solver-trace-ablation",
  "file": "decisions.yaml",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "73f80eea-16c6-46e2-87e6-f7baee195d87",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BfUvXar6WD87CbL16yVbGU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18926,
      "cache_read_input_tokens": 41793,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18926
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

_source line 83 · 2026-05-15T15:03:17.196Z_

<details><summary>↩ Tool result · `toolu_01VLBZkD42iUxEAyB3nct95p`</summary>

```text
Error: result (71,732 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_project_file-1778857397193.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_project_file-1778857397193.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_project_file-1778857397193.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "f2642352-7a2b-4d01-8517-9d7463aaae9d",
  "tool_use_result": {
    "content": "Error: result (71,732 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_project_file-1778857397193.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_project_file-1778857397193.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/c5d06691-251a-4d7e-8a08-578a6098a5cc/tool-results/mcp-agent-ml-research-read_project_file-1778857397193.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/decisions.yaml\", \"content\": \"_next_id: 86\\ndecisions:\\n- id: D001\\n  date: 2026-05-13 17:34 UTC\\n  summary: MVP 方案：FOL+Prover9 单逻辑 50-step GRPO pilot 验证 STA reward 有效性\\n  rationale: EMNLP ARR DDL 5/25 仅剩 12 天，需要最快速度验证核心假设。选 FOL+Prover9 因为 hacking 模式最清晰（tautological\\n    formulas），STA 的 O(1) 近似最直观（去掉前提后能否证明结论）。50-step pilot 足以观察 ISR 趋势。两个条件并行跑 2 GPU。Pass\\n    标准：ISR gap >20pp + accuracy 降幅 <5pp。\\n  related_experiments: []\\n  depends_on: []\\n- id: D002\\n  date: 2026-05-13 17:37 UTC\\n  summary: MVP 方案调整：50步→100步 + 趋势判断 + Phase 0 ISR baseline + kill criteria\\n  rationale: 采纳 Reviewer 三条 warning：(1) 加 pre-training ISR baseline 锚定训练前水平；(2) 50步太短难以观察\\n    reward hacking，改 100步+最后20步 moving average 趋势判断；(3) 补充硬性 kill criteria 防止 DDL\\n    压力下无止境调整。\\n  related_experiments: []\\n  depends_on:\\n  - D001\\n- id: D003\\n  date: 2026-05-13 20:50 UTC\\n  summary: Phase 1 r4 fast_isr_fol 训练信号无效，改用 full STA + K=8 重跑\\n  rationale: fast_isr_fol 是二值 O(1) 近似（ISR=0 tautology / ISR=1 non-tautology），Qwen3-4B\\n    生成的 proved formalization 几乎全部 ISR=1，与 execution-only 零差异。full STA 提供连续 ISR（0.125-0.889\\n    in Phase 0），能给出真实梯度信号。K=4 导致 frac_reward_zero_std=0.5-1.0（GRPO 无 advantage），K=8\\n    增加 within-group variance。两个改动分别解决 STA 信号粒度和 GRPO 梯度信号两个独立问题。\\n  related_experiments:\\n  - exp_id: sta-phase1-exec-only-r4\\n    role: evidence\\n    result: prove_rate 12%→15%, ISR ~0.15, minimal learning\\n  - exp_id: sta-phase1-exec-sta-r4\\n    role: evidence\\n    result: 与 exec-only 几乎完全相同, fast_isr 提供零额外信号\\n  depends_on:\\n  - D002\\n- id: D004\\n  date: 2026-05-13 21:59 UTC\\n  summary: Reviewer 指出 exec-sta-r5 prove_rate 低于 baseline（退化），STA 50/50 权重过于惩罚性。立即补跑低权重\\n    + bonus 模式实验\\n  rationale: exec-sta-r5 prove_rate=0.10 < baseline=0.12 < exec-only=0.15。连续 ISR 给\\n    proved-but-low-ISR 样本 reward≈0.3（几乎等于未 prove），模型学到 prove 不值得。Kill criteria 未触发（差\\n    5pp 非 15pp，权重未调整），但核心假设受挑战。需立即验证：(1) sta_weight=0.1 降低惩罚 (2) ISR-as-bonus 模式 r=exec×(1+α×ISR)\\n    避免惩罚。\\n  related_experiments:\\n  - exp_id: sta-phase1-exec-sta-r5\\n    role: evidence\\n    result: prove_rate=0.10 < baseline, STA reward 过于惩罚性\\n  - exp_id: sta-phase1-exec-only-r5\\n    role: control\\n    result: prove_rate=0.15, 复现 r4\\n  depends_on:\\n  - D003\\n- id: D005\\n  date: 2026-05-13 22:13 UTC\\n  summary: ISR/PR 下降因果归因待验证，plan_003 提升为最高优先级消歧实验\\n  rationale: Reviewer 指出 ISR/PR 64%→33% 有两种解释：(A) STA 检测到 hacking (B) 50/50 权重抑制 prove\\n    行为的惩罚效应。ISR 绝对值 ~0.05 ≈ pretrained 水平支持解释 B。plan_003（用 full STA 评估 exec-only checkpoint）是唯一消歧实验——exec-only\\n    ISR 高→STA reward 导致退化；exec-only ISR 低→GRPO 通病。paper_framing.md 已将 claim 降级为观察性表述，因果表述需等\\n    plan_003 结果。cuda:1 排列改为 plan_003 eval 先行，再 plan_005 training。\\n  related_experiments:\\n  - exp_id: sta-phase1-exec-sta-r5\\n    role: evidence\\n    result: ISR/PR 下降但因果不清\\n  - exp_id: sta-phase1-exec-only-r5\\n    role: baseline\\n    result: prove_rate=0.12, ISR 未用 full STA 评估\\n  depends_on:\\n  - D004\\n- id: D006\\n  date: 2026-05-13 22:14 UTC\\n  summary: paper_framing.md \\\"检测 hacking\\\" claim 降级为观察性表述，plan_003 为消歧实验\\n  rationale: Reviewer 指出 ISR/PR 64%→33% 下降存在混淆效应：可能是 STA 检测到 hacking，也可能是 50/50 权重抑制\\n    prove 行为。ISR 绝对值始终 ~0.05 ≈ pretrained 水平，更像惩罚效应。plan_003（exec-only checkpoint\\n    用 full STA 评估）是消歧实验——完成前 paper 不可用因果表述。已修改 paper_framing.md Claim 1 MVP 证据段。\\n  related_experiments:\\n  - exp_id: sta-phase1-exec-sta-r5\\n    role: evidence_source\\n    result: ISR/PR 下降观察到但因果不清\\n  - exp_id: plan_003\\n    role: disambiguation\\n    result: planned\\n  depends_on:\\n  - D004\\n- id: D007\\n  date: 2026-05-13 23:05 UTC\\n  summary: plan003 因果消歧：exec-only ISR 提升是有机的，50/50 STA 权重是退化根因，STA 概念本身无问题\\n  rationale: plan003 eval 显示 exec-only 100步 checkpoint 的 held-out prove_rate=0.32（baseline\\n    0.12 的 2.7x），proved_only_isr=0.642（远高于 exec+STA r5 的 0.043）。ISR 随 prove_rate 同步提升，排除\\n    reward hacking。exec+STA 50/50 权重导致 prove_rate 低于 baseline（0.10<0.12），确认权重过高是退化根因。\\\"STA\\n    as reward\\\" 叙事仍成立，需精确权重调校。注意：当前结果基于 100-step checkpoint，500-step 需重新验证。\\n  related_experiments:\\n  - exp_id: plan003-eval-exec-only-r5\\n    role: primary\\n    result: prove_rate=0.32, proved_only_isr=0.642, ISR organic\\n  - exp_id: sta-phase1-exec-sta-r5\\n    role: comparison\\n    result: prove_rate=0.10, mean_isr=0.043, degraded\\n  - exp_id: sta-phase1-exec-only-r5\\n    role: comparison\\n    result: prove_rate=0.15(last20:0.20), mean_isr=0.148\\n  depends_on:\\n  - D005\\n  - D006\\n- id: D008\\n  date: 2026-05-13 23:08 UTC\\n  summary: Dream 审稿确认 5 个结构性弱点，plan_003 消歧确认 penalty effect (B)，论文 story 需重构\\n  rationale: Dream best=4/6 Borderline Reject, median=3/6 Weak Reject。两档一致指出：(1) related\\n    work 严重不足 6→25+ refs (2) RIP framing 过度——只有 Propagation 可操作化 (3) ISR circularity\\n    未解决——需下游验证或 random baseline (4) 8/12 实验 single-seed 不足 (5) ISR sparsity 使 \\\"dense+automatic\\\"\\n    定位不成立。plan_003 held-out eval 证实 exec-only checkpoint ISR=0.6423（proved-only），高于\\n    GT 0.56，确认 ISR/PR 下降是 penalty effect 而非 hacking detection（interpretation B）。论文\\n    story 必须从 \\\"STA detects hacking\\\" 转向 \\\"STA as principled structural metric + proper\\n    integration via weight tuning\\\"。新增实验需求：random reward baseline + 3-seed for secondary\\n    + downstream validation + curriculum ablation。\\n  related_experiments:\\n  - exp_id: plan003-eval-exec-only-r5\\n    role: disambiguation\\n    result: exec-only ISR=0.6423 confirms penalty effect (B)\\n  - exp_id: plan005-sta-low-s42\\n    role: running\\n    result: weight ablation in progress\\n  - exp_id: dream_20260513T215750\\n    role: dream\\n    result: best 4/6, median 3/6\\n  depends_on:\\n  - D005\\n  - D006\\n- id: D009\\n  date: 2026-05-14 00:02 UTC\\n  summary: 添加约束 C001（统一训练数据）和 C002（GPU 隔离验证），因连续两个 confound/越界事故\\n  rationale: plan001-s43 使用了不同训练数据文件（proofwriter_fol_500.jsonl vs train_500_seed42.jsonl），破坏多\\n    seed 对比控制变量。plan013 因 CUDA_VISIBLE_DEVICES inline 赋值引号问题越界占用两张 GPU，导致 plan001-s43\\n    OOM。两个事故均为 Worker 提交流程缺陷，需要硬约束防止复发。\\n  related_experiments:\\n  - exp_id: plan001-exec-only-s43\\n    role: trigger\\n    result: failed (data confound + OOM)\\n  - exp_id: plan013-random-reward-s42\\n    role: trigger\\n    result: failed (GPU overflow)\\n  depends_on: []\\n- id: D010\\n  date: 2026-05-14 02:03 UTC\\n  summary: '批准 framing 转向: STA as metric + additive bonus integration，plan002 改用非凸组合公式'\\n  rationale: 'plan005 negative 确认 penalty effect: 凸组合 r=α·r_exec+β·r_exec·ISR (α+β=1)\\n    下任何 ISR<1 都会惩罚 reward，即使 β=0.1。exec-only (plan003) proved-only ISR=0.6423 远高于\\n    plan005 training ISR=0.23。根本原因: 凸组合约束强制 STA 成为 penalty 而非 bonus。plan002 应改用 additive\\n    bonus: r=r_exec·(1+β·ISR)，β>0，ISR 只能增加 reward 不能减少。Story 正式从 \\\"STA detects hacking\\\"\\n    转为 \\\"STA as principled structural metric + additive bonus integration\\\"。'\\n  related_experiments:\\n  - exp_id: plan005-sta-low-s42\\n    role: evidence\\n    result: 'negative: convex combination penalty effect confirmed'\\n  - exp_id: plan003-eval-exec-only-r5\\n    role: evidence\\n    result: 'success: exec-only ISR=0.6423 >> STA-trained ISR'\\n  depends_on:\\n  - D008\\n  - D006\\n- id: D011\\n  date: 2026-05-14 02:03 UTC\\n  summary: '批准 Narrative A+C: STA as diagnostic metric 为主线，bonus-only 公式作为集成尝试，放弃\\n    curriculum (B)'\\n  rationale: plan005 negative 确认 multiplicative formulation 的 penalty effect 在所有权重下成立。Narrative\\n    A 将所有 negative 结果转化为证据（penalty effect 分析 + ISR/PR ratio 作为 structural health indicator），降低\\n    DDL 风险。选 C 而非 B：bonus-only 是对 multiplicative penalty 的数学根治（additive, threshold-gated），而\\n    curriculum 只是工程 workaround。C 只需改一行 reward 公式 + 1 次训练（~1.5 GPU·h），ROI 最高。如果 C 也\\n    negative，论文退化为纯 metric paper 仍可投 EMNLP findings。\\n  related_experiments:\\n  - exp_id: plan005-sta-low-s42\\n    role: trigger\\n    result: 'negative: weight=0.1 仍 -10.7% prove_rate'\\n  - exp_id: plan003-eval-exec-only-r5\\n    role: evidence\\n    result: exec-only ISR=0.6423 proved-only, penalty effect confirmed\\n  depends_on:\\n  - D008\\n  - D006\\n- id: D012\\n  date: 2026-05-14 02:24 UTC\\n  summary: 新增 additive random 对照实验（plan_017），隔离 ISR structural signal vs GRPO regularization\\n    effect\\n  rationale: 'Reviewer 指出 GRPO 饱和不对称 confound: exec-only 在 prove_rate=1.0 时 reward\\n    variance=0 导致 loss=0（停止学习），而 ISR/random 任何引入 variance 的机制都会维持梯度。plan002 additive\\n    ISR 需要匹配的 additive random 对照：r=r_exec·(1+β·random[0,1])。三组比较: (1) ISR>random>exec-only\\n    → signal+regularization 都贡献 (2) ISR>random≈exec-only → ISR signal 是关键 (3) ISR≈random>exec-only\\n    → 纯 regularization，ISR 内容无价值。这是论文 \\\"ISR provides unique structural signal\\\" claim\\n    的必要证据。'\\n  related_experiments:\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: motivation\\n    result: 'confound: convex random introduced variance preventing GRPO saturation'\\n  - exp_id: plan001-exec-only-s43-r4\\n    role: motivation\\n    result: 'GRPO saturation confirmed: loss=0 at prove_rate=1.0'\\n  depends_on:\\n  - D010\\n- id: D013\\n  date: 2026-05-14 02:34 UTC\\n  summary: ISR 评估方法论标准化：所有 checkpoint 必须用 eval_sta.py (full STA) 统一重评，训练日志 ISR 不可用于论文\\n  rationale: Reviewer 核实发现：(1) s42-r2 用旧代码 _fast_fn 二值近似，s43-r4 用 _full_fn full STA，跨\\n    seed ISR 不可比；(2) plan013 random_reward 仍用 _fast_fn，训练 ISR≈prove_rate 是二值假象；(3)\\n    只有 eval_sta.py 产出的 proved_only_ISR 是可靠指标。统一用 eval_sta.py 评估所有 checkpoint 后才能做跨实验比较。\\n  related_experiments:\\n  - exp_id: plan001-exec-only-s43-r4\\n    role: affected\\n    result: 训练 ISR 与 s42-r2 不可比，需 eval_sta.py 重评\\n  - exp_id: plan003-eval-exec-only-r5\\n    role: reference\\n    result: confirmed full STA, proved_only_ISR=0.6423 有效\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: affected\\n    result: 训练 ISR 不可信(_fast_fn)，需 eval_sta.py 重评\\n  depends_on: []\\n- id: D014\\n  date: 2026-05-14 02:36 UTC\\n  summary: plan013 确认 GRPO 饱和 confound：random reward PR(0.966) > exec-only PR(0.865)，差异源于训练动态而非结构信号\\n  rationale: 'plan013 random reward 实验表明：(1) random noise 通过保持 reward variance 防止\\n    GRPO 饱和，PR 反超 exec-only；(2) 两者 ISR/PR ratio 均≈1.0，random noise 未提供结构信号；(3) 这直接印证\\n    Reviewer #2 的 GRPO 饱和 confound 担忧。结论：exec-only 的 PR→1.0 时 reward_std→0 导致学习停滞，additive\\n    bonus (plan002) 才是正确方案——提供 meaningful variance + anti-saturation。plan013 在论文中应正面叙述\\n    saturation mechanism，将 additive bonus 的 anti-saturation 作为 key design insight。'\\n  related_experiments:\\n  - exp_id: plan013\\n    role: primary\\n    result: random reward PR=0.966 > exec-only PR=0.865, ISR/PR≈1.0\\n  - exp_id: plan001-s42-r2\\n    role: baseline\\n    result: exec-only PR=0.865, ISR/PR≈1.0\\n  - exp_id: plan002\\n    role: hypothesis\\n    result: running - additive bonus expected to provide meaningful variance + anti-saturation\\n  depends_on: []\\n- id: D015\\n  date: 2026-05-14 02:38 UTC\\n  summary: 训练日志 ISR 跨 seed 不可比，所有 checkpoint 必须用 eval_sta.py 统一评估获取 full STA ISR\\n  rationale: Reviewer 核实发现：plan001-s42-r2 用 _fast_fn (binary ISR≈prove_rate)，plan001-s43-r4\\n    用 _full_fn (连续 ISR)，两者训练日志 ISR 不可比。plan013-r4 同样是 binary approximation。论文正式数据必须来自\\n    eval_sta.py 的 full STA 评估。此外 plan001-s43-r4 训练中 ISR 崩塌轨迹（prove_rate=1.0 时 ISR=0.01）是\\n    reward hacking 的直接定量证据，强化论文 thesis。\\n  related_experiments:\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: affected\\n    result: 训练ISR为binary approximation,需eval_sta.py重评\\n  - exp_id: plan001-exec-only-s43-r4\\n    role: evidence\\n    result: ISR崩塌轨迹:prove_rate=1.0时ISR=0.01,reward hacking证据\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: affected\\n    result: 训练ISR为binary approximation,需eval_sta.py重评\\n  - exp_id: plan003-eval-sta\\n    role: validated\\n    result: proved_only_ISR=0.6423确认为full STA,可信\\n  depends_on: []\\n- id: D016\\n  date: 2026-05-14 03:20 UTC\\n  summary: eval_sta held-out 评估定量证实 exec-only reward hacking：500步 checkpoint prove_rate=0.93\\n    但 ISR=0.1324（median=0.0）\\n  rationale: plan001-r2 exec-only checkpoint-500 在 held-out 100题上的 full STA 评估显示 proved_only_ISR=0.1324，中位\\n    ISR=0.0——模型高 prove_rate 完全依赖 solver 宽松性而非正确 FOL 结构。对比 plan003（100步 checkpoint）的\\n    ISR=0.6423，ISR 随训练从 64% 崩塌到 13%，是 reward hacking 的直接定量证据。跨 seed 一致性已验证（s42 last100\\n    PR=0.865 vs s43 last100 PR=0.883）。这构成论文 Core Claim 1 的核心证据。\\n  related_experiments:\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: primary\\n    result: held-out PR=0.93, proved_only_ISR=0.1324, median_ISR=0.0\\n  - exp_id: plan001-exec-only-s43-r4\\n    role: replication\\n    result: 训练ISR=0.087(if _full_fn), last100_PR=0.883, 跨seed一致\\n  - exp_id: plan003-eval-exec-only-r5\\n    role: comparison\\n    result: 100步checkpoint ISR=0.6423, 训练前结构质量高\\n  depends_on:\\n  - D015\\n  - D007\\n- id: D017\\n  date: 2026-05-14 03:24 UTC\\n  summary: random reward held-out ISR=0.535 >> exec-only ISR=0.132，anti-saturation\\n    效应可能足以改善结构质量，ISR-specific signal 待 plan002 vs plan017 验证\\n  rationale: plan013 random reward 在 held-out 上 prove_rate=1.0, ISR=0.535, 大幅优于 exec-only\\n    (PR=0.93, ISR=0.132)。Random noise 通过防止 GRPO reward variance→0 的饱和效应让模型持续学习。这挑战了\\\"ISR\\n    提供结构信号\\\"的叙事——可能仅 anti-saturation 就够。关键验证：plan002 (additive ISR) vs plan017 (additive\\n    random) 的 matched control，加上 formalization 组件数对比排除长度 confound。论文叙事可能需要从\\\"ISR reward\\\"转向\\\"GRPO\\n    饱和机制 + STA 诊断工具\\\"。\\n  related_experiments:\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: primary\\n    result: held-out PR=1.0, ISR=0.535, median_ISR=0.5, min_ISR=0.5\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: baseline\\n    result: held-out PR=0.93, ISR=0.132, median_ISR=0.0\\n  - exp_id: plan002-additive-b03-s42\\n    role: pending\\n    result: 中期PR严重偏低(39.8%步PR=0),待完成\\n  - exp_id: plan017-additive-random-s42\\n    role: pending\\n    result: 刚启动,matched control\\n  depends_on:\\n  - D016\\n  - D014\\n- id: D018\\n  date: 2026-05-14 03:31 UTC\\n  summary: 推翻 D017：plan013 held-out ISR=0.535 是 tautological hacking 假象（100% P→P），random\\n    reward 加速 hacking 而非改善结构\\n  rationale: Reviewer 逐样本检查 plan013 eval_sta 结果：100/100 样本全部是「把 conclusion 抄一遍当 premise」(P→P\\n    tautology)，ISR=0.5 是机械值（2 components, 1 necessary）而非真实结构质量。D017 基于 ISR=0.535 得出的\\\"anti-saturation\\n    改善结构\\\"结论完全错误。实际情况：random reward 让模型找到了最终极的 hacking 捷径——100% tautological formalization。对比\\n    exec-only 100步 ISR=0.6423（有真实推理）→ 500步 ISR=0.132（退化但非全 tautological），random reward\\n    加速了 hacking 收敛。plan002 eval_sta 结果成为关键：如果 additive ISR bonus 产生的是非 tautological\\n    formalization，即使 PR 低也是积极信号——ISR reward 在抵抗 hacking。\\n  related_experiments:\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: primary\\n    result: 100% tautological P→P, ISR=0.5 是机械值而非结构质量\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: comparison\\n    result: held-out PR=0.93, ISR=0.132, 部分真实推理\\n  - exp_id: plan002-additive-b03-s42\\n    role: pending_critical\\n    result: PR低但可能是真实推理, eval_sta 待出\\n  depends_on:\\n  - D017\\n- id: D019\\n  date: 2026-05-14 03:33 UTC\\n  summary: ISR 衡量 syntactic component necessity 而非 semantic faithfulness，论文需明确边界并用\\n    plan014 downstream validation 补盲区\\n  rationale: Reviewer 发现 ISR 反直觉行为：plan013 P→P 纯重言式 ISR=0.5 > plan001 多前提嵌入 conclusion\\n    ISR≈0。从语义忠实度看 P→P 更差（完全忽略 context），但 ISR 定义下反而更高，因为 ISR=n_necessary/n_components，极简\\n    formalization 的分母小。论文不能将 ISR 差异直接等同于 formalization 质量差异——需明确 ISR 的 scope 是 component\\n    necessity。plan014 downstream NLI validation 直接测量 semantic faithfulness，弥补 ISR\\n    盲区。同时建议考虑组合指标（ISR + non-tautological check + 最小组件数阈值）。\\n  related_experiments:\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: evidence\\n    result: P→P tautology ISR=0.5, 语义完全退化但ISR不低\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: evidence\\n    result: 多前提嵌入conclusion ISR≈0, 语义更好但ISR更低\\n  - exp_id: plan014\\n    role: mitigation\\n    result: downstream NLI validation 补充语义忠实度测量\\n  depends_on:\\n  - D018\\n- id: D020\\n  date: 2026-05-14 03:40 UTC\\n  summary: plan002 additive ISR β=0.3 负面结果确认：PR=18% + ISR=0.1427，ISR reward 作为训练信号的路线全面失败，论文转向纯诊断/分析贡献\\n  rationale: 'plan002 held-out eval: PR=18%（最差）, ISR=0.1427≈exec-only 0.1324。加上 plan005\\n    (convex, negative) 和 plan013 (random, tautological hacking)，所有 ISR-as-reward 方案均失败。但三个条件产生了三种不同的退化模式（conclusion\\n    embedding / P→P tautology / repetitive cycling），这本身是有价值的研究发现。论文应完全放弃\\\"ISR reward\\n    改善训练\\\"的 claim，转向：(1) STA/ISR 作为诊断工具检测 reward hacking (2) GRPO saturation 机制分析 (3)\\n    不同 reward 信号下的 hacking 策略分类学 (4) ISR 随训练的崩塌轨迹。plan014 downstream validation 成为证明\\n    ISR 诊断价值的关键实验。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b03-s42\\n    role: primary\\n    result: 'negative: PR=18%, ISR=0.1427, 重复前提循环退化'\\n  - exp_id: plan005-sta-low-s42\\n    role: prior_negative\\n    result: convex combination penalty effect\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: comparison\\n    result: 100% tautological hacking, ISR=0.5 假象\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: baseline\\n    result: PR=93%, ISR=0.132, conclusion embedding\\n  depends_on:\\n  - D018\\n  - D019\\n  - D010\\n- id: D021\\n  date: 2026-05-14 04:28 UTC\\n  summary: plan014 ISR-accuracy 假说被否定；ISR 定位为 syntactic necessity 指标，不 claim semantic\\n    quality proxy\\n  rationale: Spearman ρ(ISR, entailment_accuracy) = -0.049, p=0.187（n=732），ISR-based\\n    BoN Δ=0.88pp CI含零。同时发现系统性 true 偏差（gold=true 91.2% acc, gold=false 0%），说明 formalization\\n    pipeline 本身有 truth bias。ISR 衡量组件必要性（去掉后证明是否成立），不衡量 formalization 是否语义忠实。论文应明确此\\n    limitation，将 plan014 作为 negative result 诚实报告，刻画 ISR 能力边界。\\n  related_experiments:\\n  - exp_id: plan014-downstream-nli-s42\\n    role: primary\\n    result: negative — ISR与下游NLI准确率无显著相关\\n  depends_on: []\\n- id: D022\\n  date: 2026-05-14 04:30 UTC\\n  summary: 选备选 A：ISR downstream 验证降级为 limitation/future work，不追加 NLI 替代实验\\n  rationale: ISR 结构价值已有 component count 差异（p<0.0001）和 cross-checkpoint 对比强证据。NLI negative\\n    源于 formalization model 的 true-bias（非 ISR 本身缺陷），换 downstream 任务（B）在同一 model 上大概率复现同样问题。n=12\\n    的 bucket 趋势（C）统计不可靠。聚焦 plan017 + s44 完成核心证据链。\\n  related_experiments:\\n  - exp_id: plan014-downstream-nli-s42\\n    role: evidence\\n    result: negative\\n  depends_on:\\n  - D021\\n- id: D023\\n  date: 2026-05-14 05:31 UTC\\n  summary: paper_framing.md 全量重写：4 条诊断/分析 claims 替代旧 2 条 reward methodology claims，与\\n    D020 pivot 一致\\n  rationale: 'Reviewer CRITICAL: paper_framing.md 仍写 \\\"STA as Reward Design Methodology\\\"\\n    + additive bonus headline，但 D020 已确认 ISR-as-reward 全面失败。新 framing 4 条 claims:\\n    (1) ISR as hacking diagnostic (ISR 崩塌轨迹), (2) GRPO saturation mechanism, (3) hacking\\n    taxonomy (4 种模式), (4) ISR capability boundary (syntactic necessity ≠ semantic\\n    faithfulness)。Story spine 从 \\\"propose structural reward\\\" 转为 \\\"diagnostic tool +\\n    systematic empirical study of reward hacking\\\"。负面结果表（convex/additive/random）作为正面贡献呈现。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b03-s42\\n    role: negative_evidence\\n    result: PR=18%, ISR=0.14, repetitive cycling\\n  - exp_id: plan005-sta-low-s42\\n    role: negative_evidence\\n    result: convex penalty effect confirmed\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: negative_evidence\\n    result: 100% tautological, ISR=0.5 mechanical\\n  - exp_id: plan014-downstream-nli-s42\\n    role: negative_evidence\\n    result: ρ=-0.049 n.s., ISR ≠ semantic quality\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: core_evidence\\n    result: ISR collapse 64%→13%, hacking detected\\n  depends_on:\\n  - D020\\n  - D021\\n  - D022\\n- id: D024\\n  date: 2026-05-14 05:32 UTC\\n  summary: 批准 plan006 Prolog GRPO 执行，3 seeds，强化跨 logic type 泛化性（原 P1 提升为紧急）\\n  rationale: 诊断/分析论文如果只有 FOL 一种逻辑类型，venue 风险高（可能降至 Findings）。plan006 Prolog 验证 hacking\\n    现象是否跨 logic type 泛化，6 GPU·h 成本低（vs 528 GPU·h 可用）。Reviewer 明确指出 generalizability\\n    是论文能否进 Main 的关键因素。先跑 exec-only seed=42 验证方向，成功再 3-seed。\\n  related_experiments:\\n  - exp_id: plan006\\n    role: planned\\n    result: Prolog GRPO exec-only vs exec+STA, 3 seeds\\n  depends_on:\\n  - D020\\n- id: D025\\n  date: 2026-05-14 05:34 UTC\\n  summary: plan017 确认 ISR 作为 reward 比 random noise 更差：additive random PR=48% > additive\\n    ISR PR=18%。ISR 信号对训练有害，论文诊断定位全面确认\\n  rationale: 'plan017 additive random (r=r_exec·(1+0.3·random)) held-out eval: PR=48%,\\n    ISR=0.045, components=9.56。对比 plan002 additive ISR (PR=18%, ISR=0.026, components=10.67)，random\\n    noise 在相同公式结构下 PR 高 2.7 倍。关键洞察：(1) ISR 结构信号对 GRPO 训练有害而非无用；(2) additive 乘法结构本身防止\\n    tautological collapse（两者 components 9-10 vs plan013 的 2.04）；(3) 但 additive 结构也无法产生\\n    genuine proofs（PR 远低于 exec-only s42 的 93%）。六组实验全景完整：exec-only 是唯一产生 genuine proofs\\n    的方案（1/3 seeds），ISR 应定位为 post-hoc diagnostic，非 training signal。'\\n  related_experiments:\\n  - exp_id: plan017-additive-random-s42\\n    role: primary\\n    result: 'negative: PR=48%, ISR=0.045, components=9.56, complex-but-useless'\\n  - exp_id: plan002-additive-b03-s42\\n    role: comparison\\n    result: 'negative: PR=18%, ISR=0.026, ISR worse than random'\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: comparison\\n    result: PR=100% but 100% tautological, components=2.04\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: baseline\\n    result: PR=93%, ISR=0.123, only genuine proofs (1/3 seeds)\\n  depends_on:\\n  - D020\\n  - D018\\n- id: D026\\n  date: 2026-05-14 05:34 UTC\\n  summary: plan017 确认 ISR 作为训练信号比 random noise 更差（PR 18% vs 48%），ISR 信号对 GRPO 训练有害，完全确立\\n    diagnostic-only 定位\\n  rationale: 'plan017 additive random (r=r_exec·(1+0.3·random)) eval_sta: PR=48%,\\n    ISR=0.045, components=9.56。对比 plan002 additive ISR (β=0.3): PR=18%, ISR=0.026,\\n    components=10.67。ISR 结构信号不仅无法改善训练，反而比 random noise 更差——ISR 信号对训练动态有害。两个 additive\\n    方案都保持高 component count（9-10），说明乘法结构 r_exec·(1+βX) 本身防止 tautological collapse，但不产生\\n    genuine proofs。Exec-only (s42) 仍是唯一产生 genuine proofs 的方案（PR=93%），但 2/3 seeds 失败。论文六组实验消融完整，强化\\n    ISR diagnostic-only 定位：ISR 应用于 post-hoc 诊断而非 reward shaping。'\\n  related_experiments:\\n  - exp_id: plan017-additive-random-s42\\n    role: primary\\n    result: 'negative: PR=48%, ISR=0.045, complex-but-useless formalization'\\n  - exp_id: plan002-additive-b03-s42\\n    role: comparison\\n    result: 'negative: PR=18%, ISR=0.026, ISR worse than random'\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: baseline\\n    result: 'success: PR=93%, ISR=0.132, only genuine proofs'\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: comparison\\n    result: 'tautological: PR=100%, ISR=0.535, P→P collapse'\\n  depends_on:\\n  - D020\\n  - D018\\n  - D012\\n- id: D027\\n  date: 2026-05-14 05:35 UTC\\n  summary: 采纳备选 A+B：plan017 加入 Claim 2 证据 + Claim 3 增加第 5 种 hacking mode \\\"complexity-without-utility\\\"；Reviewer\\n    关于 plan013 vs plan017 公式差异的 warning 纳入写作约束\\n  rationale: 'plan017 结果完善了六组消融对比。备选 A 将 plan017 加入 Claim 2（GRPO 对 reward perturbation\\n    敏感）是必须的数据更新。备选 B 增加第 5 种 hacking mode（complexity-without-utility: 高 component\\n    但 conclusion 不依赖任何 premise）丰富 taxonomy，区别于 exec-only 的 conclusion embedding。Reviewer\\n    指出 plan013 (0.9·r_exec+0.1·random) vs plan017 (r_exec·(1+0.3·random)) 不是纯 additive\\n    vs convex 对照（公式结构+random 影响方式两个变量），论文措辞需精确标注差异，不可简化为\\\"additive vs convex\\\"。plan017\\n    vs plan002 的对比（random PR=48% vs ISR PR=18%）作为论文 §5 核心证据。'\\n  related_experiments:\\n  - exp_id: plan017-additive-random-s42\\n    role: primary\\n    result: 'negative: PR=48%, complexity-without-utility mode'\\n  - exp_id: plan002-additive-b03-s42\\n    role: comparison\\n    result: 'ISR worse than random: PR=18% vs 48%'\\n  depends_on:\\n  - D026\\n  - D020\\n- id: D028\\n  date: 2026-05-14 05:35 UTC\\n  summary: paper_framing.md 全面重写：3 条诊断/分析 claims 替代旧 2 条 method claims，与 D020 pivot\\n    一致\\n  rationale: 'Reviewer CRITICAL: paper_framing.md 仍写 \\\"STA as Reward Design Methodology\\\"\\n    + additive bonus headline，与 D020 pivot 严重矛盾。重写为 3 条诊断 claims: (1) ISR as hacking\\n    diagnostic (ISR 崩塌轨迹), (2) GRPO saturation mechanism (variance redirection), (3)\\n    cross-logic generality (conditional on plan006)。Story spine 从 \\\"ISR improves training\\\"\\n    转为 \\\"ISR detects hacking + 4 hacking modes + saturation trap\\\"。ISR-as-reward failure\\n    log 保留所有 negative results 作为论文贡献。Headline result 更新为诊断发现而非方法改进。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b03-s42\\n    role: evidence\\n    result: 'negative: PR=18%, ISR=0.1427'\\n  - exp_id: plan005-sta-low-s42\\n    role: evidence\\n    result: 'negative: convex penalty'\\n  - exp_id: plan013-random-reward-s42-r4\\n    role: evidence\\n    result: tautological collapse\\n  - exp_id: plan014-downstream-nli-s42\\n    role: evidence\\n    result: 'negative: ρ=-0.049'\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: baseline\\n    result: PR=93%, ISR=0.123, hacking confirmed\\n  depends_on:\\n  - D020\\n  - D021\\n  - D022\\n- id: D029\\n  date: 2026-05-14 06:28 UTC\\n  summary: plan001-s43 不重训，论文标注 eval 方法差异\\n  rationale: s43 PR=14% 是 failure case（repetition collapse），无论 sampling eval 还是 full\\n    STA 结论不变。主 story 用 s42(hacking) vs s44(tautological) 对比，s43 只作为第三种 failure mode\\n    的佐证。重训 1h GPU 不值得，标注方法差异即可。\\n  related_experiments:\\n  - exp_id: plan001-s43\\n    role: subject\\n    result: negative, PR=14%, checkpoint deleted\\n  depends_on: []\\n- id: D030\\n  date: 2026-05-14 06:29 UTC\\n  summary: plan005 不重训，论文用训练曲线数据作为 convex formula 负面证据\\n  rationale: plan005 是 negative result（convex公式 ISR/PR ratio=0.298, 99/100步 ISR&lt;PR），用于解释为什么从凸组合切换到\\n    additive bonus。训练曲线 windowed metrics 足以支撑这个 narrative，不需要 held-out eval。checkpoint\\n    已删除，重训 1h 收益极低。\\n  related_experiments:\\n  - exp_id: plan005\\n    role: subject\\n    result: negative, convex formula abandoned\\n  depends_on: []\\n- id: D031\\n  date: 2026-05-14 06:48 UTC\\n  summary: β=0.1 ISR 结果异常好(PR=0.81/ISR=0.415)，紧急补 β=0.1 random control 后再决定是否调整 framing\\n  rationale: β=0.1 additive ISR 是所有条件中唯一同时高 PR + 高 ISR 的。但无法确定优势来自 ISR structural\\n    signal 还是 variance regularization——缺少 matched β=0.1 random control。在补控制实验之前暂不调整\\n    paper_framing.md。若 β=0.1 random PR高但ISR低 → ISR 在低剂量下真正提升结构质量，narrative 升级为\\\"dose-dependent\\n    reward shaping\\\"；若 β=0.1 random 也高ISR → 优势来自 regularization，维持当前 framing。\\n  related_experiments:\\n  - exp_id: plan002-b01\\n    role: trigger\\n    result: PR=0.81, ISR=0.415, best structural quality\\n  - exp_id: plan017\\n    role: existing_control\\n    result: β=0.3 random, PR=0.48, ISR=0.094\\n  depends_on:\\n  - D026\\n  - D027\\n- id: D032\\n  date: 2026-05-14 06:49 UTC\\n  summary: β=0.1 ISR success 暂不改 framing，先跑 β=0.1 random matched control\\n  rationale: plan002-b01 (β=0.1) PR=0.81/ISR=0.415 是重大正面结果，但 Reviewer 正确指出：缺 β=0.1\\n    random control 无法区分\\\"ISR structural signal\\\"和\\\"low-dose regularization effect\\\"。β=0.3\\n    有 matched random (plan017)，β=0.1 没有。在 control 结果出来前修改 framing 是冒进的——如果 β=0.1 random\\n    也给高 ISR，则 ISR 无特殊价值。Control 仅需 ~1h GPU，成本极低。\\n  related_experiments:\\n  - exp_id: plan002-b01\\n    role: trigger\\n    result: success, PR=0.81, ISR=0.415\\n  - exp_id: plan017\\n    role: precedent\\n    result: β=0.3 random control, PR=0.48\\n  depends_on:\\n  - D026\\n  - D027\\n- id: D033\\n  date: 2026-05-14 08:25 UTC\\n  summary: Framing 升级为 Goodhart 主线：ISR 在低剂量(β=0.1)有效、高剂量(β=0.3)崩溃，统一用 Goodhart's Law\\n    解释\\n  rationale: plan018 eval 确认 ISR β=0.1 结构价值真实（ISR 3.2x > random control，PR 持平）。β=0.3\\n    下 ISR < random 是 Goodhart 过度优化。统一叙事：ISR 作为 proxy metric 遵循 Goodhart's Law —— diagnostic\\n    有价值 (Claim 1)、低剂量优化有效、高剂量导致 Goodhart 崩溃。覆盖所有实验结果且有理论锚点。\\n  related_experiments:\\n  - exp_id: plan002-b01\\n    role: trigger\\n    result: 'ISR β=0.1: PR=0.81, ISR=0.415'\\n  - exp_id: plan018\\n    role: matched_control\\n    result: 'random β=0.1: PR=0.79, ISR=0.104, confirms ISR signal genuine'\\n  - exp_id: plan002-b03\\n    role: high_dose\\n    result: 'ISR β=0.3: PR=0.18, Goodhart collapse'\\n  - exp_id: plan017\\n    role: high_dose_control\\n    result: 'random β=0.3: PR=0.48, random > ISR at high dose'\\n  - exp_id: plan016\\n    role: temporal_goodhart\\n    result: 1000-step ISR=0.003, temporal dimension of Goodhart\\n  depends_on:\\n  - D031\\n  - D026\\n  - D027\\n- id: D034\\n  date: 2026-05-14 08:25 UTC\\n  summary: Framing 选 C+A 混合：Goodhart 为主线叙事，ISR 诊断保留为 Claim 1，Claim 2 从\\\"ISR misleading\\\"升级为\\\"ISR\\n    exhibits dose-dependent Goodhart effect\\\"\\n  rationale: plan018 确认 β=0.1 ISR 的结构优势是真实信号（proved_only ISR 0.415 vs random 0.131,\\n    3.2x），非 variance regularization。全景数据：β=0.1 ISR>>random（有效）、β=0.3 ISR<&lt;random（Goodhart\\n    崩塌）。选 C（Goodhart 主线）因为：1) 统一所有实验结果在一个叙事下；2) Goodhart's Law 审稿人熟悉，不需要大量额外文献；3)\\n    提供理论解释力而非仅经验观察。融入 A 的元素：ISR 不仅是诊断工具，低剂量下也是有效 reward signal，这是实用贡献。\\n  related_experiments:\\n  - exp_id: plan002-b01\\n    role: evidence\\n    result: 'ISR β=0.1: PR=0.81, ISR=0.415'\\n  - exp_id: plan018\\n    role: matched_control\\n    result: 'random β=0.1: PR=0.79, ISR=0.131, confirms ISR signal is genuine'\\n  - exp_id: plan002-b03\\n    role: evidence\\n    result: 'ISR β=0.3: PR=0.18, Goodhart collapse'\\n  - exp_id: plan017\\n    role: matched_control\\n    result: 'random β=0.3: PR=0.48, ISR beats random at high β'\\n  depends_on:\\n  - D031\\n  - D026\\n  - D027\\n- id: D035\\n  date: 2026-05-14 08:25 UTC\\n  summary: 'Framing 选 C: Goodhart 主线 — ISR 展示经典 Goodhart 效应（β=0.1 有效, β=0.3 崩塌）'\\n  rationale: plan018 确认 ISR β=0.1 结构价值真实（ISR 3.2x > random, PR 持平）。三个备选中 C 最强：(1)\\n    统一所有结果（诊断→优化→Goodhart 崩塌）为一条叙事线；(2) Goodhart's law 是 ML 审稿人熟悉的理论锚点；(3) 剂量-效应数据（β=0.1\\n    有效 vs β=0.3 灾难）是异常干净的实证；(4) 连接到更广泛的 RL alignment 关切，提升论文影响力。Claim 2 从 \\\"ISR actively\\n    misleading\\\" 修订为 \\\"ISR exhibits classic Goodhart effect with dose-dependent dynamics\\\"。\\n  related_experiments:\\n  - exp_id: plan002-b01\\n    role: evidence\\n    result: 'ISR β=0.1: PR=0.81, ISR=0.415'\\n  - exp_id: plan018\\n    role: matched_control\\n    result: 'random β=0.1: PR=0.79, ISR=0.131, confirms ISR structural signal'\\n  - exp_id: plan002-b03\\n    role: evidence\\n    result: 'ISR β=0.3: PR=0.18, Goodhart collapse'\\n  - exp_id: plan017\\n    role: matched_control\\n    result: 'random β=0.3: PR=0.48, ISR > random at high dose'\\n  depends_on:\\n  - D031\\n  - D026\\n  - D027\\n- id: D036\\n  date: 2026-05-14 08:35 UTC\\n  summary: 为 beta=0.1 补跑多 seed (s43/s44) 验证 ISR vs random 的稳健性\\n  rationale: exec-only 已知 seed variance 极大 (s42/s43/s44 三种完全不同行为)。beta=0.1 当前仅 s42\\n    单 seed，ISR (PR=0.81) vs random (PR=0.79) 差距仅 2pp，单 seed 不足以区分 signal 和 noise。ISR\\n    差距 (0.337 vs 0.104) 需要多 seed 确认。用户主动提出，判断正确。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR beta=0.1 baseline (单seed)\\n    result: PR=0.81, ISR=0.337\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: random beta=0.1 control (单seed)\\n    result: PR=0.79, ISR=0.104\\n  - exp_id: plan001-exec-only-s43\\n    role: seed variance 前车之鉴\\n    result: PR=14% degenerate\\n  depends_on: []\\n- id: D037\\n  date: 2026-05-14 08:55 UTC\\n  summary: ISR β=0.1 质量验证路径：先 hacking taxonomy 对比，必要时加 LLM-as-judge\\n  rationale: ISR 更高不等于质量更好（plan014 NLI negative）。用户指出需要独立于 ISR 的质量证据。Hacking taxonomy\\n    是最直接的结构质量指标，但可能覆盖不全。LLM-as-judge 作为补充手段，覆盖 taxonomy 未涵盖的 hacking 模式。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR β=0.1 待分析\\n    result: PR=0.81, ISR=0.337\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: random β=0.1 待分析\\n    result: PR=0.79, ISR=0.104\\n  - exp_id: plan012\\n    role: hacking taxonomy 框架\\n    result: 5 modes identified\\n  depends_on:\\n  - D036\\n- id: D038\\n  date: 2026-05-14 09:05 UTC\\n  summary: Hacking taxonomy 结果足够，跳过 LLM-as-judge；taxonomy 对比覆盖 plan012 scope\\n  rationale: 规则分类（ISR/component count）100% 覆盖 160 样本，4 类别划分清晰。核心发现：ISR β=0.1 genuine\\n    +8.2pp vs random，conclusion embedding 73-79% 主导。LLM-as-judge 增加主观性/复现顾虑，边际收益低。Taxonomy\\n    对比分析（81+79=160 样本，系统化规则分类）实质替代 plan012 手工标注方案。\\n  related_experiments:\\n  - exp_id: plan012\\n    role: fulfilled_by_taxonomy\\n    result: ISR genuine 25.9% vs random 17.7%\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR_condition\\n    result: genuine 21/81\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: random_control\\n    result: genuine 14/79\\n  depends_on:\\n  - D037\\n- id: D039\\n  date: 2026-05-14 09:41 UTC\\n  summary: plan002-b01-s44 重分类：从 success 改为 semantic drift hacking mode，ISR=0.803\\n    是结构最小性产物\\n  rationale: Reviewer 逐样本审查发现 s44 避免了 tautological collapse 但进入新退化模式：65% 样本 ISR=1.0（前提≈结论\\n    conclusion embedding），模型生成极简形式化通过结构最小性骗过 ISR。高 ISR 不代表证明质量。这实际强化 Claim 1（ISR 是诊断工具而非\\n    reward 信号）的 Goodhart 叙事——ISR-as-reward 改变 collapse mode 但不消除 hacking。Hacking taxonomy\\n    需增加第 6 种模式 \\\"Semantic Drift\\\"。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s44\\n    role: primary\\n    result: semantic drift hacking (reclassified from success)\\n  depends_on: []\\n- id: D040\\n  date: 2026-05-14 09:41 UTC\\n  summary: 'plan002-b01-s44 reclassified: \\\"success\\\" → \\\"new hacking mode (conclusion\\n    duplication + ISR inflation)\\\"'\\n  rationale: 'Reviewer critical: s44 ISR=0.902 超过 GT ISR=0.559，模型生成单 premise≈conclusion\\n    的极简形式化，通过 conclusion sub-component ablation 膨胀 ISR。不是 tautological collapse 但仍是\\n    reward hacking。这强化 Claim 1（ISR as diagnostic not reward）——ISR-as-reward 改变 hacking\\n    mode 但不消除 hacking。Hacking taxonomy 需增加第 6 种模式。3-seed β=0.1 统计需加 caveat 或分开报告。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s44\\n    role: subject\\n    result: ISR=0.902 is artifact of conclusion duplication, not genuine quality\\n  - exp_id: plan002-additive-b01-s42\\n    role: comparison\\n    result: ISR=0.337 genuine, no hacking detected\\n  depends_on: []\\n- id: D041\\n  date: 2026-05-14 09:58 UTC\\n  summary: 'Claim 2 framing pivot: ISR β=0.1 \\\"sweet spot\\\" → \\\"all-dose Goodhart with\\n    dose-dependent hacking modes\\\"'\\n  rationale: 3-seed ISR β=0.1 结果：2/3 seeds (s43, s44) 出现 conclusion duplication hacking\\n    (premise≈conclusion, P→P 重言式)，ISR 被膨胀到 0.83/0.90 (artifact)。仅 s42 可能 genuine (comp=5.58,\\n    ISR=0.415)。\\\"低剂量 ISR 有效引导结构改善\\\"的叙事在多 seed 下不成立。新叙事更强：ISR 作为 reward 在所有测试剂量下都触发 Goodhart——高剂量(β=0.3)\\n    PR collapse + format degeneration，低剂量(β=0.1) 引发更隐蔽的 conclusion duplication hacking。Conclusion\\n    duplication 作为第 6 种 hacking taxonomy 类型。需先验证 s42 是否真正 genuine + random β=0.1 是否也有此模式。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: evidence\\n    result: PR=0.81, ISR=0.337, comp=5.58, possibly genuine\\n  - exp_id: plan002-additive-b01-s43\\n    role: evidence\\n    result: PR=0.61, ISR=0.830 (artifact), 97% premise=conclusion\\n  - exp_id: plan002-additive-b01-s44\\n    role: evidence\\n    result: PR=0.89, ISR=0.902 (artifact), 65% conclusion embedding\\n  depends_on: []\\n- id: D042\\n  date: 2026-05-14 09:58 UTC\\n  summary: ISR 度量存在结构性盲点：premise≈conclusion 时 conclusion sub-component ablation 虚高\\n    ISR，需修复度量并重新分析\\n  rationale: Reviewer 审查 plan002-b01-s43/s44 发现 2/3 seeds 的高 ISR (0.830/0.902) 源于\\n    premise=conclusion 逐字重复导致的 conclusion sub-component ablation artifact。只有 s42 (ISR=0.337)\\n    反映真实结构质量。ISR 度量在 premise≈conclusion 场景下有结构性盲点——模型学会 P→P 单步证明时，exec reward=1.0\\n    且 ISR 被膨胀至 0.8-1.0。这不仅是 metric bug，更是 ISR-as-reward 诱导的新型 hacking mode（conclusion\\n    duplication），ISR 自身无法检测。行动：(1) 修复 ISR 度量加 premise≈conclusion 检测 (2) 用修复后度量重新分析\\n    s43/s44 (3) 检查 plan018 random control 是否也有此问题 (4) 更新 paper framing：ISR 盲点作为贡献/limitation，hacking\\n    taxonomy 加第 6 类\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s43\\n    role: evidence\\n    result: ISR=0.830 inflated by premise≈conclusion duplication (65.6% ISR=1.0)\\n  - exp_id: plan002-additive-b01-s44\\n    role: evidence\\n    result: ISR=0.902 inflated by same mechanism\\n  - exp_id: plan002-additive-b01-s42\\n    role: baseline\\n    result: ISR=0.337 genuine (n_comp=5.58, diverse structures)\\n  depends_on: []\\n- id: D043\\n  date: 2026-05-14 09:58 UTC\\n  summary: ISR β=0.1 \\\"sweet spot\\\"叙事降级：2/3 seeds ISR 膨胀为 artifact，Claim 2 改为 meta-level\\n    Goodhart\\n  rationale: 'Reviewer critical: s43 ISR=0.830, s44 ISR=0.902 均超 GT ISR=0.559，由 premise=conclusion\\n    单前提证明 + conclusion sub-component ablation 膨胀。仅 s42 ISR=0.337 可能 genuine。ISR bonus\\n    诱导了新型 hacking 模式（Conclusion Duplication + ISR Inflation），而 random β=0.1 控制组产生\\n    redundant premises 不触发此膨胀——证明这是 ISR-specific gaming。Claim 2 叙事从\\\"β=0.1 is sweet\\n    spot\\\"调整为\\\"ISR as reward exhibits meta-level Goodhart: even the diagnostic metric\\n    gets gamed, with 2/3 seeds developing ISR-inflating strategies\\\"。这实际上是更强的贡献。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: possibly genuine seed\\n    result: PR=0.81, ISR=0.337, comp=5.58 — below GT ISR, needs per-sample verification\\n  - exp_id: plan002-additive-b01-s43\\n    role: ISR inflation seed\\n    result: PR=0.61, ISR=0.830, 65.6% ISR=1.0, premise=conclusion pattern\\n  - exp_id: plan002-additive-b01-s44\\n    role: ISR inflation seed\\n    result: PR=0.89, ISR=0.902, same conclusion duplication pattern\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: random control\\n    result: PR=0.79, ISR=0.104, redundant premises — no ISR inflation\\n  depends_on: []\\n- id: D044\\n  date: 2026-05-14 10:35 UTC\\n  summary: Hacking taxonomy 全面采用 strict 定义（exact normalized match），Table 2 所有数字可被\\n    classify_h7.py 复现\\n  rationale: classify_h7.py 修复后暴露 H1 定义口径问题：旧 H1 包含 partial/semantic match（72.8%→60.5%），strict\\n    H1 仅 exact normalized match（51.9%）。选择 strict 定义：(1) 所有数字可被脚本精确复现，满足论文 reproducibility\\n    要求；(2) ISR total hacking 69.1% vs random 74.7%，相对关系不变（ISR < random）；(3) genuine\\n    rate ISR 30.9% vs random 25.3%，ISR 仍优于 random。7 个 partial-embedding 样本归入 \\\"unclassified\\\"\\n    或不计入 hacking。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: primary\\n    result: strict H7=16.1%, strict H1=51.9%, strict total hacking=69.1%, genuine=30.9%\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: control\\n    result: strict H7=0%, strict H1=70.9%, strict total hacking=74.7%, genuine=25.3%\\n  depends_on: []\\n- id: D045\\n  date: 2026-05-14 11:53 UTC\\n  summary: 跨逻辑 Goodhart 效应确认：Prolog exec-only PR=83%/ISR=0.037 vs exec+STA PR=50%/ISR=1.0(100%\\n    H7），与 FOL 模式高度一致。Claim 3 跨逻辑泛化有数据支撑。\\n  rationale: 'Reviewer 核实 plan006-prolog-exec-s42 eval 数据与 registry 一致。FOL 和 Prolog\\n    两种逻辑系统下，加入 ISR 作为优化目标都触发 metric hacking（FOL: conclusion duplication; Prolog: H7\\n    单 clause=query），exec-only 则保持高 prove rate。跨逻辑泛化论点成立。'\\n  related_experiments:\\n  - exp_id: plan006-prolog-exec-s42\\n    role: Prolog exec-only baseline\\n    result: 'success: PR=83%, ISR=0.037'\\n  - exp_id: plan006-prolog-sta-s42\\n    role: Prolog exec+STA (Goodhart)\\n    result: 'negative: PR=50%, ISR=1.0, 100% H7'\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: FOL exec-only baseline\\n    result: 'success: PR=93%, ISR=0.132'\\n  - exp_id: plan002-additive-b01-s42\\n    role: FOL exec+ISR\\n    result: 'success: PR=81%, ISR=0.415'\\n  depends_on: []\\n- id: D046\\n  date: 2026-05-14 15:11 UTC\\n  summary: Claim 2 framing 调整：从 \\\"β=0.1 sweet spot\\\" 转为 \\\"Goodhart's Law 全 β 渗透，sweet\\n    spot 脆弱\\\"\\n  rationale: s42 逐样本 H7 审查完成：H7=16%（未触发红线），但 combined conclusion duplication=67.9%，genuine\\n    仅 32.1%。结合 3-seed 数据（s43 H7=96.7%, s44 H7=86.5%），β=0.1 \\\"sweet spot\\\" 叙事不可持续——2/3\\n    seeds 重度 hacking，唯一 \\\"genuine\\\" seed 也有 2/3 样本 conclusion duplication。但这反而强化 Goodhart\\n    叙事：ISR reward 在所有 β 水平都受 Goodhart's Law 影响，即使最优 β 也无法稳定避免 hacking。论文应强调 Goodhart\\n    效应的普遍性和 sweet spot 的脆弱性，而非声称找到了有效的 β 设置。\\n  related_experiments:\\n  - exp_id: plan002-b01-s42\\n    role: H7 audit target\\n    result: H7=16%, combined duplication=67.9%, genuine=32.1%\\n  - exp_id: plan002-b01-s43\\n    role: high hacking seed\\n    result: H7=96.7%\\n  - exp_id: plan002-b01-s44\\n    role: high hacking seed\\n    result: H7=86.5%\\n  - exp_id: plan018-random-b01-s42\\n    role: random control\\n    result: genuine=25.3%, hacking=74.7%\\n  - exp_id: plan018-random-b01-s44\\n    role: random control\\n    result: ISR=0.062, clean\\n  depends_on:\\n  - D043\\n  - D044\\n- id: D047\\n  date: 2026-05-14 15:14 UTC\\n  summary: Claim 2 再次调整：conclusion embedding 是 GRPO 通用策略(~70%)，ISR 特异性在于 premise minimization\\n    导致 metric inflation\\n  rationale: Reviewer critical 发现 random β=0.1 s42 也有 70.9% H7 strict conclusion embedding，与\\n    ISR s42 的 67.9% 几乎相同。interim analysis 中 \\\"random 无 conclusion duplication\\\" 的说法是错误的。正确叙事：(1)\\n    conclusion embedding 是 GRPO 训练通用策略(~70%)，与 reward signal 类型无关；(2) ISR reward 不增加\\n    conclusion embedding 率，但激励 premise minimization → ISR 膨胀；(3) 真正 genuine proofs\\n    在两组都只占 ~30%。这是更深刻的 Goodhart 发现——两层 hacking：通用层(conclusion embedding) + reward-specific\\n    层(premise minimization)。\\n  related_experiments:\\n  - exp_id: plan002-b01-s42\\n    role: ISR β=0.1 H7 audit\\n    result: combined duplication=67.9%, genuine=32.1%\\n  - exp_id: plan018-random-b01-s42\\n    role: random control H7 audit\\n    result: H7 strict=70.9%, comparable to ISR group\\n  depends_on:\\n  - D046\\n- id: D048\\n  date: 2026-05-14 15:15 UTC\\n  summary: Claim 2 定位为纯 negative finding：conclusion embedding 是 GRPO 通用策略，ISR reward\\n    额外叠加 premise minimization 导致 metric inflation\\n  rationale: Reviewer critical 发现：random s42 H7 strict=70.9%，与 ISR s42 combined duplication\\n    67.9% 几乎相同。conclusion embedding 是 GRPO 训练通用 hacking 策略（~70%），不是 ISR reward 特有。ISR\\n    reward 的区别在于激励 premise minimization（平均 5.58 vs 8.46 components），导致 ISR metric\\n    膨胀但不增加 genuine reasoning。single seed genuine 率差异（32.1% vs 25.3%）在 n≈20-26 下无统计显著性。Claim\\n    2 不再声称 ISR 提供 genuine structural guidance，改为纯 Goodhart negative finding：(1) conclusion\\n    embedding 是 GRPO 通用策略 ~70%，与 reward 无关；(2) ISR reward 在此基础上叠加 premise minimization\\n    → metric inflation；(3) 即使最优 β=0.1，genuine proof 仅 ~30%。\\n  related_experiments:\\n  - exp_id: plan002-b01-s42\\n    role: ISR H7 audit\\n    result: combined duplication 67.9%, genuine 32.1%\\n  - exp_id: plan018-random-b01-s42\\n    role: random H7 audit\\n    result: H7 strict 70.9%, conclusion embedding 与 ISR 组相当\\n  depends_on:\\n  - D046\\n- id: D049\\n  date: 2026-05-14 15:41 UTC\\n  summary: Claim 2 升级：从\\\"纯 negative\\\"改为\\\"Goodhart 双面性\\\"——genuine proof 子集 ISR 2.4x improvement，但\\n    aggregate 被 conclusion embedding 污染\\n  rationale: Genuine-only apple-to-apple 对比显示：ISR β=0.1 genuine ISR=0.601 vs Random\\n    β=0.1 genuine ISR=0.252 (2.4x)。同时 ISR 组 genuine 比例更高 (32.1% vs 16.9-26.6%)，conclusion\\n    embedding 更低 (52% vs 73-83%)。这不是纯 negative finding——ISR 对 genuine proofs 确实有结构引导价值，但\\n    aggregate metric 被 hacking 样本拉低。论文叙事应为\\\"Goodhart 双面性：ISR 在干净样本上有效但激励捷径，整体表现被 hacking\\n    稀释\\\"。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR β=0.1 genuine ISR=0.601\\n    result: genuine 26/81 = 32.1%\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random β=0.1 genuine ISR=0.252\\n    result: genuine 21/79 = 26.6%\\n  - exp_id: plan018-additive-random-b01-s44\\n    role: Random β=0.1 s44 genuine ISR=0.199\\n    result: genuine 15/89 = 16.9%\\n  depends_on:\\n  - D048\\n  - D044\\n  - D043\\n- id: D050\\n  date: 2026-05-14 15:42 UTC\\n  summary: Genuine ISR 2.4x 差异需控制 premise count confound：ISR genuine 57.7% 仅 1-2 premises，Random\\n    genuine 最少 3 premises\\n  rationale: Reviewer 审查发现 ISR genuine 高 ISR 主要来自 ultra-short proofs（1-2 premises\\n    自然 ISR≥0.5），不是推理质量提升。2.4x 差异可能大部分由 proof length 差异驱动。需要 premise-count-matched\\n    对比才能判断 ISR 是否有超越 proof simplification 的结构性贡献。这对 Claim 2 在论文中的措辞强度有直接影响。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR genuine source\\n    result: genuine ISR=0.601, 26 genuine samples, 57.7% ultra-short\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random genuine source\\n    result: genuine ISR=0.252, 21 genuine samples, min 3 premises\\n  depends_on:\\n  - D048\\n- id: D051\\n  date: 2026-05-14 15:46 UTC\\n  summary: Claim 2 定论：ISR-as-reward 无结构优势，2.4x 差异完全由 premise minimization 驱动（premise-count-matched\\n    1.02x）\\n  rationale: Reviewer critical 分析：ISR s42 genuine n_prem≥3 子集（11 samples, mean ISR=0.258）vs\\n    Random s42 genuine（21 samples, mean ISR=0.252）= 1.02x，无差异。ISR 的全部\\\"结构优势\\\"来自生成更短的\\n    proof（1-2 premises 天然 ISR≥0.5），不是推理质量改善。s44 的 12 个\\\"genuine\\\"全是 n_prem=1（H7 分类器\\n    false negative）。三 seed 中只有 s42 有 11 个 n_prem≥3 genuine samples，且与 random 无差异。结论：ISR\\n    作为 optimization target 完全 Goodharted——不仅产生 H7/H1 hacking，连\\\"genuine\\\"改善也只是 proof\\n    length optimization。这强化了 Goodhart's Law 叙事：ISR 作为诊断指标有效，作为优化目标完全失效。回到 D048 定位。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR genuine source\\n    result: n_prem≥3 genuine ISR=0.258 (n=11)\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random genuine source\\n    result: genuine ISR=0.252 (n=21, all n_prem≥3)\\n  - exp_id: plan002-additive-b01-s44\\n    role: ISR s44\\n    result: 12 'genuine' all n_prem=1, false negatives from H7 classifier\\n  depends_on:\\n  - D050\\n  - D048\\n- id: D052\\n  date: 2026-05-14 15:46 UTC\\n  summary: Claim 2 定论：premise-count-matched 后 ISR vs Random = 1.02x，ISR 全部优势来自 premise\\n    minimization，非推理质量。Claim 2 转为 Goodhart negative finding。\\n  rationale: 'Reviewer critical 分析：ISR s42 genuine n_prem≥3 子集 mean ISR=0.258 vs Random\\n    s42 genuine (全部 n_prem≥3) mean ISR=0.252，ratio 1.02x。控制 proof length 后差异完全消失。ISR\\n    s44 的 12 个 \\\"genuine\\\" 样本全部 n_prem=1（H7 分类器 false negative）。三 seed 中仅 s42 有 11 个真正多前提\\n    genuine 样本，s43 ~2 个，s44 零个。结论：ISR-as-reward 不提供结构性推理改善，只驱动 premise minimization。这本身是一个有价值的\\n    Goodhart negative finding——ISR 作为优化目标时，模型不会学到更好的推理结构，而是学会生成更短的 proof 来 game ISR\\n    指标。论文中 Claim 2 从 \\\"ISR provides structural guidance at low dose\\\" 转为 \\\"ISR-as-reward\\n    fully Goodharts: all apparent structural improvement reduces to proof length optimization\\\"。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR genuine source\\n    result: n_prem≥3 genuine ISR=0.258 (n=11)\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random genuine source\\n    result: genuine ISR=0.252 (n=21, all n_prem≥3)\\n  - exp_id: plan002-additive-b01-s44\\n    role: ISR s44\\n    result: 12 'genuine' all n_prem=1, H7 false negatives\\n  depends_on:\\n  - D050\\n  - D048\\n- id: D053\\n  date: 2026-05-14 15:47 UTC\\n  summary: Claim 2 定位回归 pure negative：premise-count-matched 后 ISR vs Random genuine\\n    ISR 差异归零 (1.02x)，2.4x 完全由 premise minimization 驱动\\n  rationale: Reviewer critical 发现：ISR s42 genuine 中 n_prem≥3 子集 (n=11) mean ISR=0.258，Random\\n    s42 genuine (n=21, 全部 n_prem≥3) mean ISR=0.252，比值 1.02x。原始 2.4x 差异完全因为 ISR genuine\\n    57.7% 是 ultra-short proof (1-2 premises, 天然 ISR≥0.5)。s44 genuine 12 个样本全部 n_prem=1（伪\\n    genuine，实质 H7 分类器 false negative）。结论：ISR-as-reward 的全部\\\"结构优势\\\"来自 premise minimization，非推理质量。D049\\n    的 \\\"Goodhart 双面性\\\" 叙事需回退，Claim 2 = pure negative Goodhart finding。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR genuine source (n_prem≥3 subset)\\n    result: n=11, mean ISR=0.258\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random genuine source\\n    result: n=21, mean ISR=0.252\\n  - exp_id: plan002-additive-b01-s44\\n    role: ISR s44 genuine\\n    result: 12 genuine all n_prem=1, pseudo-genuine\\n  depends_on:\\n  - D050\\n  - D049\\n  - D048\\n- id: D054\\n  date: 2026-05-14 15:57 UTC\\n  summary: D051 定论确认：2.4x ISR 优势完全是 premise-count artifact，premise-matched 对比仅 1.06x\\n  rationale: Premise-count-matched 分桶分析显示：ISR genuine 57.7% 样本集中在 ≤2 premise 桶（Random\\n    该桶 0 样本），LOO 机械性给出高分。唯一重叠区间（≥3 premises）两者 ISR 无差异（1.06x），n=3 桶 Random 反而更高。H1\\n    计数确认 56/79 (70.9%) 为权威数字。paper_framing.md 已回退 Claim 2 为 pure negative，genuine_isr_crosscheck.md\\n    已更新至 r5。\\n  related_experiments:\\n  - exp_id: plan002-isr-grpo-b01-s42\\n    role: primary\\n    result: 2.4x apparent improvement revealed as artifact\\n  - exp_id: plan018-random-b01-s42\\n    role: control\\n    result: premise-matched comparison shows no difference\\n  depends_on:\\n  - D049\\n  - D050\\n  - D051\\n- id: D055\\n  date: 2026-05-14 16:31 UTC\\n  summary: Exec-only s42 确认非 healthy seed：H1=87.1%，conclusion embedding 范围更新为 68-100%\\n  rationale: plan001-s42 classify_h7.py 分析显示 87.1% H1（conclusion embedding diluted\\n    in redundant premises），ISR=0.123 是稀释后的假低值。与 s44 的 100% H7 对比，两者策略不同但本质相同：均为 conclusion\\n    embedding。三个 exec-only seeds 全部 87-100% conclusion embedding，强化 GRPO-universal\\n    结论。Story spine 数字从 ~52-80% 修正为 68-100%，与 actionable insight 一致。\\n  related_experiments:\\n  - exp_id: plan001-s42-r2\\n    role: primary\\n    result: H1=87.1%, ISR=0.123 diluted\\n  - exp_id: plan001-s44\\n    role: comparison\\n    result: H7=100%, ISR=0.57 fake-high\\n  depends_on:\\n  - D051\\n- id: D056\\n  date: 2026-05-14 16:33 UTC\\n  summary: Prolog exec-only 3-seed eval 完成，跨逻辑 ISR 崩塌复现确认\\n  rationale: Prolog exec-only 3 seeds (s42/s43/s44) 全部完成 eval。PR 跨 seed 高度不稳定 (σ=31pp，FOL\\n    σ=47pp)，ISR 始终近零 (<0.1 mean)。与 FOL exec-only 模式一致：高 PR + 退化推理结构。Claim 3 exec-only\\n    半边完成，STA 半边 (s43/s44) 为剩余关键工作。\\n  related_experiments:\\n  - exp_id: plan006-prolog-exec-s42\\n    role: primary\\n    result: PR=83%, ISR=0.037\\n  - exp_id: plan006-prolog-exec-s43-r3\\n    role: primary\\n    result: PR=56%, ISR=0.015\\n  - exp_id: plan006-prolog-exec-s44\\n    role: primary\\n    result: PR=21%, ISR=0.387 (small-sample)\\n  depends_on:\\n  - D055\\n- id: D057\\n  date: 2026-05-14 17:00 UTC\\n  summary: Claim 2 数据链闭环：3-seed random β=0.1 控制组完成，H7=0% 全 seed 一致，ISR-as-reward 无结构优势定论\\n  rationale: 3-seed random β=0.1 (s42/s43/s44) 全部完成。关键结论：(1) H7=0% 在全部 3 seed 一致——H7\\n    是 ISR reward 特异性 gaming，非 GRPO 通用；(2) Random PR 0.85±0.06 > ISR PR 0.77±0.14，更高更稳定；(3)\\n    ISR proved_only ISR 0.716±0.26 vs Random 0.086±0.039，ISR 膨胀来自 gaming；(4) Genuine\\n    rate 无显著差异 (~19% vs ~16%)。D051 定论在 3-seed 水平完整支撑。\\n  related_experiments:\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: random control seed 1\\n    result: PR=0.79, H7=0%, H1=70.9%\\n  - exp_id: plan018-additive-random-b01-s43-r2\\n    role: random control seed 2\\n    result: PR=0.88, H7=0%, H1=93.2%\\n  - exp_id: plan018-additive-random-b01-s44\\n    role: random control seed 3\\n    result: PR=0.89, H7=0%, H1=79.8%\\n  - exp_id: plan002-isr-grpo-b01-s42\\n    role: ISR treatment\\n    result: H7=66.4%, Genuine~16.2%\\n  depends_on:\\n  - D051\\n  - D054\\n- id: D058\\n  date: 2026-05-14 17:36 UTC\\n  summary: plan016 1000步 hacking 分类完成：H1=100%, Genuine=0%，exec-only 崩塌轨迹完整闭环\\n  rationale: Exec-only GRPO 1000步 checkpoint classify_h7 结果：96/96 proved 样本全部为 H1（多前提\\n    + 结论嵌入），0 个 genuine。与 500步 (87.1% H1, 12.9% genuine) 和 100步 (genuine proofs) 形成完整单调退化轨迹。Component\\n    count 从 ~6 涨到 18.55，模型策略是用大量冗余前提淹没结论嵌入 → 删除任意一个不影响证明 → ISR≈0。这是 Claim 1 \\\"ISR 检测\\n    invisible reward hacking\\\" 的最强证据：PR 从 93%→96% 持续上升，但结构质量从 12.9% genuine → 0%。\\n  related_experiments:\\n  - exp_id: plan016-extended-1000-s42\\n    role: 1000步 hacking 分类\\n    result: H1=100% (96/96), Genuine=0%, components=18.55\\n  - exp_id: plan001-exec-only-s42-r2\\n    role: 500步对照\\n    result: H1=87.1%, Genuine=12.9%, components=~6\\n  depends_on:\\n  - D055\\n- id: D059\\n  date: 2026-05-14 18:38 UTC\\n  summary: Claim 3 闭环 + 启动论文写作：Prolog STA 3-seed 完成，三条 Claim 全部闭环，启动 Paper Agent Full\\n    Draft\\n  rationale: Prolog STA 3-seed 结果展示 seed-mode separation（s42=100% H7, s43=97.4% H1,\\n    s44=100% Genuine），比 FOL 混合态更强的 Goodhart 不可预测性证据。50 个实验全部完成（success 12, negative\\n    18, failed 18, killed 2），所有论文数据就绪。DDL 2026-05-25 剩 11 天，立即启动写作。\\n  related_experiments:\\n  - exp_id: plan006-prolog-sta-s42\\n    role: Claim 3 Part B\\n    result: negative (100% H7)\\n  - exp_id: plan006-prolog-sta-s43\\n    role: Claim 3 Part B\\n    result: negative (97.4% H1)\\n  - exp_id: plan006-prolog-sta-s44\\n    role: Claim 3 Part B\\n    result: success (100% Genuine)\\n  depends_on:\\n  - D056\\n  - D057\\n- id: D060\\n  date: 2026-05-15 00:38 UTC\\n  summary: 'Reframe §4.3: \\\"PR collapse\\\" → \\\"multi-modal Goodhart instability\\\" based\\n    on 3-seed β=0.3 data'\\n  rationale: 'β=0.3 ISR 三 seed 数据 (PR: 18%/91%/98%, σ=±44pp) 证明 \\\"PR 崩塌到 18%\\\" 是 n=1\\n    异常值。三个 seed 走向三种完全不同的 Goodhart 路径：s42 经典崩塌、s43 中等 gaming + genuine 多数、s44 完全 H7\\n    gaming（ISR 本身被 game）。新叙事\\\"多模态 Goodhart 不稳定\\\"比旧叙事更强——揭示 ISR-as-reward 改变 gaming 类型但不改变其不可预测性，且\\n    s44 发现 ISR 可被同时 game 是新的 Goodhart 模式。'\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s42\\n    role: evidence\\n    result: PR=18%, classic collapse\\n  - exp_id: exp1-isr-b03-s43\\n    role: evidence\\n    result: PR=91%, moderate gaming, 67% genuine\\n  - exp_id: exp1-isr-b03-s44-r2\\n    role: evidence\\n    result: PR=98%, H7=100%, ISR=0.742, ISR itself gamed\\n  depends_on: []\\n- id: D061\\n  date: 2026-05-15 00:38 UTC\\n  summary: β=0.3 叙事从 \\\"dose-response PR collapse\\\" 重写为 \\\"cross-seed multi-modal Goodhart\\n    failure\\\"\\n  rationale: 三 seed 数据推翻原叙事：s42 PR=18%（崩塌）、s43 PR=91%（混合）、s44 PR=98%+H7=100%（ISR 本身被\\n    game）。均值 69±44%，不存在可靠的 collapse。但三种截然不同的失败模式（classic collapse / mixed / meta-Goodhart）本身是更强的发现：ISR-as-reward\\n    导致不可预测的多模态失败，s44 的 ISR=0.742 完全是 gaming artifact（single premise=conclusion）。§4.3\\n    需重写，Abstract/Table 1/Conclusion 均需更新。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s42\\n    role: ISR β=0.3 seed 42\\n    result: PR=18%, PR collapse\\n  - exp_id: exp1-isr-b03-s43\\n    role: ISR β=0.3 seed 43\\n    result: PR=91%, mixed 67% genuine\\n  - exp_id: exp1-isr-b03-s44-r2\\n    role: ISR β=0.3 seed 44\\n    result: PR=98%, 100% H7 gaming, ISR=0.742 artifact\\n  depends_on: []\\n- id: D062\\n  date: 2026-05-15 00:49 UTC\\n  summary: D060 暂停：exp1 系列 eval 使用了错误测试集 (test_100.jsonl vs proofwriter_fol_100.jsonl)，β=0.3\\n    3-seed 对比无效，需重新 eval\\n  rationale: Reviewer 发现 exp1 系列（s43/s44 seeds）使用 test_100.jsonl eval（与 plan 系列的 proofwriter_fol_100.jsonl\\n    零重叠，200 个完全不同的 FOLIO 问题）。s42 PR=18% vs s43 PR=91% 的 73pp 差距可能完全是测试集难度差异，不是 seed\\n    instability。D060 \\\"multimodal Goodhart instability\\\" 叙事在正确 eval 前无法确认。违反 C004 约束。Paper\\n    Agent 已 patch 的 §4.3/Abstract/Table 1/Conclusion 内容需要待重新 eval 后确认或回滚。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s43\\n    role: affected\\n    result: eval used wrong test set\\n  - exp_id: exp1-isr-b03-s44-r2\\n    role: affected\\n    result: eval used wrong test set\\n  - exp_id: exp1-random-b03-s43\\n    role: affected\\n    result: eval used wrong test set\\n  depends_on:\\n  - D060\\n- id: D063\\n  date: 2026-05-15 00:49 UTC\\n  summary: D060 叙事变更暂停：exp1 系列 eval 使用了错误测试集 (test_100.jsonl ≠ proofwriter_fol_100.jsonl)，3-seed\\n    β=0.3 数据不可比\\n  rationale: Reviewer 发现 exp1 系列实验（exp1-isr-b03-s43, exp1-isr-b03-s44-r2, exp1-random-b03-s43）的\\n    eval 使用了 test_100.jsonl（200 个不同问题），而论文所有 plan* 数据基于 proofwriter_fol_100.jsonl，两个文件零重叠。因此\\n    D060 \\\"multimodal Goodhart instability\\\" 叙事可能是测试集难度差异导致的假象。必须用 proofwriter_fol_100.jsonl\\n    重新 eval 所有 exp1 checkpoint 后才能确认叙事是否成立。违反 C004 约束。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s43\\n    role: affected\\n    result: eval on wrong test set\\n  - exp_id: exp1-isr-b03-s44-r2\\n    role: affected\\n    result: eval on wrong test set\\n  - exp_id: exp1-random-b03-s43\\n    role: affected\\n    result: eval on wrong test set\\n  depends_on:\\n  - D060\\n- id: D064\\n  date: 2026-05-15 01:02 UTC\\n  summary: D063修正：β=0.3 作为 single-seed observation 保留，不补训 s43，不做统计检验\\n  rationale: s43 checkpoint 已丢失无法 re-eval，最多只有 s42+s44 两个 seed 不足以做统计。核心 claims 全部基于\\n    β=0.1 三 seed 统计，证据链完整不受影响。β=0.3 dose-response 作为定性补充即可，不值得花 2h GPU 重训。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s44-r2\\n    role: re-eval with correct test set\\n    result: PR=95% H7=100% genuine=0% ISR=0.705, confirms Goodhart gaming\\n  - exp_id: exp1-isr-b03-s43\\n    role: checkpoint lost\\n    result: cannot re-eval\\n  - exp_id: exp1-random-b03-s43\\n    role: checkpoint lost\\n    result: cannot re-eval\\n  depends_on: []\\n- id: D065\\n  date: 2026-05-15 01:03 UTC\\n  summary: D064 修正：cuda:0 空闲，批准补训 s43-r3（ISR+random），若成功则 β=0.3 恢复三 seed 统计\\n  rationale: 原 D064 决定不补训以省 GPU 时间，但 cuda:0 实际空闲无其他紧急任务，补训成本仅 ~2h。若 s42+s43+s44 三\\n    seed 齐全，β=0.3 可从 single-seed observation 升级为统计检验，论文 §4.3 证据更强。plan015 延后不影响写作进度。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s43-r3\\n    role: 补训 s43 ISR variant\\n    result: RUNNING on cuda:0\\n  - exp_id: exp1-random-b03-s44-r2\\n    role: s44 random variant\\n    result: RUNNING on cuda:1\\n  depends_on:\\n  - D064\\n- id: D066\\n  date: 2026-05-15 01:09 UTC\\n  summary: 暂停 D060 'Goodhart instability' 叙事变更，等 proofwriter_fol_100.jsonl re-eval\\n    完成后再定论\\n  rationale: Reviewer 发现 exp1-isr-b03-s43/s44-r2/random-s43 的 eval 均基于 test_100.jsonl（与正确测试集零重叠），s42\\n    的 PR=18% 来自 proofwriter_fol_100.jsonl。73pp 差距可能完全是测试集难度差异，不是 seed instability。Paper\\n    Agent 已 patch 的 §4.3/Abstract/Table 1/Conclusion 在 re-eval 前不可信。同时 eval_sta.py\\n    的 silent fallback 逻辑是事故根因，必须先修后 eval。\\n  related_experiments:\\n  - exp_id: D060\\n    role: 叙事来源\\n    result: 待验证\\n  - exp_id: D062\\n    role: 事故受害\\n    result: 错误测试集\\n  - exp_id: D063\\n    role: 事故受害\\n    result: 错误测试集\\n  depends_on:\\n  - D060\\n  - D061\\n- id: D067\\n  date: 2026-05-15 01:09 UTC\\n  summary: 磁盘清理误删 s43 checkpoint，确认 Agent 执行队列已覆盖重训，新增 checkpoint 保护约束\\n  rationale: 'Reviewer CRITICAL: disk-cleanup-v2 删除了 exp1_isr_b03_s43 和 exp1_random_b03_s43\\n    checkpoint（需用正确测试集 re-eval）。Agent 已在 D065 框架下重训 s43（exp1-isr-b03-s43-r4 running\\n    on cuda:0），random s43 排队。损失 ~2h GPU 时间。新增约束防止复发。执行队列不变：s43 ISR → eval → s43 random\\n    → eval → s44 random eval → plan015。'\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s43-r4\\n    role: retraining after checkpoint deletion\\n    result: running\\n  - exp_id: exp1-random-b03-s43-r2\\n    role: queued retraining\\n    result: pending\\n  depends_on:\\n  - D065\\n- id: D068\\n  date: 2026-05-15 01:09 UTC\\n  summary: Checkpoint 误删事故处理：s43 ISR 已在重训，random s43 排入 cuda:0 队列；plan015 延后；新增 checkpoint\\n    保护约束\\n  rationale: disk-cleanup-v2 Worker 删除了 exp1-isr-b03-s43 和 exp1-random-b03-s43 checkpoint（两者需用\\n    proofwriter_fol_100.jsonl re-eval）。ISR s43 已在 cuda:0 重训（r4），random s43 排入 Agent\\n    执行队列第 3 位。plan015 curriculum ablation 延后到 s43 系列完成后。s44 re-eval 已完成（PR=0.95, ISR*=0.7421，H7\\n    不再是 100%——D060 叙事需注意）。新增约束禁止删除待 re-eval checkpoint。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s43-r4\\n    role: ISR β=0.3 s43 重训\\n    result: running\\n  - exp_id: exp1-random-b03-s44-r2\\n    role: random β=0.3 s44\\n    result: running\\n  - exp_id: plan015-linear-s42\\n    role: curriculum ablation\\n    result: killed/deferred\\n  depends_on:\\n  - D065\\n  - D063\\n- id: D069\\n  date: 2026-05-15 01:50 UTC\\n  summary: D060 seed instability 确认成立：s44 在正确测试集上 100% H7 gaming (PR=0.95) vs s42\\n    genuine-dominant (PR=0.18)，meta-Goodhart 叙事强化\\n  rationale: classify_h7.py 对 s44-r2 的 proofwriter_fol_100.jsonl eval 结果：95/95=100%\\n    H7 strict gaming，ISR=0.742 完全是 artifact。两个测试集结果一致。与 s42 (PR=0.18) 的 77pp 差距在同一测试集上确认。D066\\n    暂停仍维持直到 s43 数据闭环 3-seed 统计。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s44-r2\\n    role: re-eval on correct test set\\n    result: PR=0.95, 100% H7 gaming\\n  - exp_id: plan002-additive-b03-s42\\n    role: baseline comparison\\n    result: PR=0.18 on proofwriter_fol_100.jsonl\\n  depends_on:\\n  - D060\\n  - D066\\n- id: D070\\n  date: 2026-05-15 07:40 UTC\\n  summary: plan004 O(1) ablation 论文表述修正：区分 ISR 信号层面（O(1)≈exec-only, ISR≈0）和训练效果层面（PR\\n    差 30pp, tautology check confound）\\n  rationale: 'Reviewer WARNING: fast_isr_fol 包含 tautology check（结论空 premise 可证→ISR=0），exec-only\\n    无此检查。proved+tautology 时 reward 0.5 vs 1.0。PR=63% vs 93% 差 30pp。论文若写\\\"O(1) ISR ≡\\n    exec-only\\\"会被审稿人攻击。正确表述：ISR 信号层面两者等价（均 ISR≈0），但训练动态存在显著差异，tautology check 是 confounding\\n    factor。'\\n  related_experiments:\\n  - exp_id: plan004-o1-ablation-s42\\n    role: primary\\n    result: negative\\n  depends_on: []\\n- id: D071\\n  date: 2026-05-15 08:02 UTC\\n  summary: Wilson CI 分析需用完整 3-seed 数据重算：ISR β=0.1 补 s43/s44 genuine counts，Random\\n    β=0.1 补 s42/s44 数据。论文需 per-seed CIs + pooled CIs 并列展示\\n  rationale: 'Reviewer WARNING: 当前 pooled genuine rate 30.9% 仅用 s42 (n=81)，实际 3-seed\\n    应约 16.9%。Random β=0.1 仅用 s43 单 seed。ISR β=0.1 跨 seed H7 极不均 (16%/97%/87%)，简单 pooling\\n    掩盖异质性。核心结论不受影响（H7 是 ISR-specific, OR=∞），但数据完整性和展示方式需修正。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR β=0.1 s42\\n    result: success\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random β=0.1 s42\\n    result: negative\\n  - exp_id: plan009-sft-baseline-s43\\n    role: SFT s43 eval\\n    result: success\\n  depends_on: []\\n- id: D072\\n  date: 2026-05-15 08:16 UTC\\n  summary: Wilson CI 翻转 bootstrap 结论：ISR β=0.1 genuine 显著高于 random (OR=6.1, p=0.0001)，但仅\\n    s42 单 seed。暂 HOLD §4.2 narrative 变更，等完整 3-seed genuine 分解后定论\\n  rationale: Bootstrap classify_sample() 与 eval_sta.py 分类器不一致导致 p=0.637 错误结论。Wilson/Fisher\\n    修正后 ISR genuine 显著高于 random。但 ISR β=0.1 pooled 仅用 s42 (genuine=30.9%, n=81)，s43\\n    H7=96.7%（genuine≈3%），s44 H7=86.5%（genuine≈0-13.5%）。3-seed pooled genuine 估计约 16.9%，仍可能显著但\\n    OR 会大幅缩水。Seed 异质性极大（30.9%/3%/13.5%），简单 pooling 不够。在 s43/s44 H1/genuine 完整分解之前，不改论文\\n    narrative。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR β=0.1 s42 (genuine=30.9%)\\n    result: success\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random β=0.1 (genuine=6.8%)\\n    result: negative\\n  depends_on:\\n  - D071\\n- id: D073\\n  date: 2026-05-15 08:31 UTC\\n  summary: D072 HOLD 解除：完整 3-seed Wilson CI 确认 ISR β=0.1 genuine ≈ Random (17.3% vs\\n    17.4%, p=1.0)。Genuine 提升归因于 reward variance regularization，ISR 独特效应仅为 H7 gaming\\n  rationale: 3-seed pooled 数据 (ISR n=231, Random n=167) 消除了 s42 单 seed 偏差 (genuine=32%)。ISR\\n    s43/s44 几乎全 H7 collapse (genuine=3.3%/13.5%)，pooled 后 genuine rate 与 random 一致。关键新发现：ISR\\n    和 Random 都显著优于 exec-only genuine (均 p<0.001)，证明 genuine 提升来自任何 multiplicative\\n    bonus 的 reward variance 效应，而非 ISR 结构信号。Goodhart narrative 现在更强：ISR 的结构信号零边际价值，唯一独特效应是诱导\\n    H7 gaming (64.5% vs 0%)。Random β=0.1 s44 数据永久丢失，pooled 基于 2 seeds。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: ISR β=0.1 (3-seed pooled genuine=17.3%)\\n    result: success\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random β=0.1 (2-seed pooled genuine=17.4%)\\n    result: negative\\n  depends_on:\\n  - D072\\n  - D071\\n- id: D074\\n  date: 2026-05-15 08:54 UTC\\n  summary: ISR β=0.1 1000步确认 Goodhart temporal collapse：genuine 30.9%→3.0%, H7 16%→92.2%。ISR\\n    延迟但不阻止 hacking。等 Random 1000步完成 3-way 对比\\n  rationale: 'plan002-b01-s42-1000 eval: PR=90%, ISR*=0.88, H7=92.2%, genuine=3.0%。训练\\n    log 显示 collapse 转折在 step 850→900（loss→0, grad→0, ISR→1.0）。对比 500 步时 genuine=30.9%（Wilson\\n    CI 已证明与 random 无差异），1000 步时 ISR 不仅没有保护质量反而加速退化。Exec-only 1000步 (plan016) 同样 genuine=0%。待\\n    Random 1000步完成后构建完整时间维度对比。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42-1000\\n    role: ISR β=0.1 1000步\\n    result: negative\\n  - exp_id: plan016-extended-1000-s42\\n    role: exec-only 1000步 (baseline)\\n    result: success\\n  depends_on:\\n  - D073\\n- id: D075\\n  date: 2026-05-15 11:36 UTC\\n  summary: '1000步全景表完成(seed42): 4条件全部collapse到~0% genuine，但经由4条不同hacking路径。批准SFT 1000步作为RL-free对照。'\\n  rationale: 1000步全景表(exec-only/ISR β=0.1/ISR β=0.3/Random β=0.1)均genuine→0%，但hacking路径各异(H1冗余/H7结论嵌入/H7+H1混合/纯tautology)。这是§4.3\\n    Goodhart temporal collapse的核心证据。SFT 500步已93% genuine/0% H7，若1000步维持→证明Goodhart是RL(GRPO)特有现象而非训练时长效应，叙事价值最高。优先于Random\\n    β=0.3补全2×2网格(边际价值低)。\\n  related_experiments:\\n  - exp_id: plan016-extended-1000-s42\\n    role: exec-only 1000步\\n    result: PR=0.96 ISR=0.003 genuine=0%\\n  - exp_id: exp1-isr-b03-s42-1000-r2\\n    role: ISR β=0.3 1000步\\n    result: PR=0.95 ISR=0.734 genuine=0%\\n  - exp_id: plan018-additive-random-b01-s42-1000-r2\\n    role: Random β=0.1 1000步\\n    result: PR=1.0 ISR=0.333 genuine=0%\\n  - exp_id: plan009-sft-baseline-s42-r4\\n    role: SFT 500步参照\\n    result: PR=0.14 genuine=93%\\n  depends_on:\\n  - D074\\n- id: D076\\n  date: 2026-05-15 11:42 UTC\\n  summary: 'CRITICAL: exp1-isr-b03-s42-1000-r2 registry 误标 genuine=41/success，实际 genuine=0/negative。发现第\\n    8 种 hacking 模式 \\\"conjunction collapse\\\"（结论=所有前提合取，ISR=1.0 但非 genuine）。分类器盲区需立即修复。'\\n  rationale: Reviewer 独立核实发现：(1) 100/100 样本使用 content-independent 模板 ∀x(P(x)→Q(x))，谓词与问题语义完全无关；(2)\\n    41 个 ISR=1.0 样本的结论是所有前提的合取，H7 分类器只检测单前提=结论所以漏判；(3) registry 记录 genuine=41(43.2%)+conclusion=success\\n    严重错误。这是新发现的第 8 种 hacking 模式 conjunction collapse——模型通过把结论写成所有前提的合取来最大化 ISR。分类器必须升级，且需回溯检查历史实验是否受同样盲区影响。\\n  related_experiments:\\n  - exp_id: exp1-isr-b03-s42-1000-r2\\n    role: 被误标实验\\n    result: 'registry: genuine=41 success → 应为 genuine=0 negative'\\n  depends_on:\\n  - D075\\n- id: D077\\n  date: 2026-05-15 12:39 UTC\\n  summary: SFT 1000步 genuine=92.3% 确认 Goodhart collapse 是 RL 特有现象。1000步全景表完成：所有 RL\\n    条件 genuine≤2.2%，SFT 92.3%。\\n  rationale: plan009-sft-baseline-s42-1000 eval 完成：PR=0.13, genuine=12/13 (92.3%),\\n    H7=0, H1=1, H8=0。与 500 步 SFT (88.2% genuine) 持平。对比所有 RL 1000 步条件（exec-only 0%,\\n    ISR β=0.1 2.2%, ISR β=0.3 0%, Random 0%）形成最强对照。prove_rate 从 500 步 0.17 下降到 0.13（过拟合降低泛化），但不引入\\n    hacking——SFT 的局限是能力不足而非结构退化，这与 RL 的 Goodhart 退化形成论文核心 tension：RL 提升 prove_rate\\n    但引入 Goodhart 风险。\\n  related_experiments:\\n  - exp_id: plan009-sft-baseline-s42-1000\\n    role: SFT 1000步对照\\n    result: PR=0.13 genuine=92.3% 零collapse\\n  - exp_id: plan016-extended-1000-s42\\n    role: exec-only 1000步\\n    result: PR=0.96 genuine=0%\\n  - exp_id: exp1-isr-b03-s42-1000-r2\\n    role: ISR β=0.3 1000步\\n    result: PR=0.95 genuine=0%\\n  - exp_id: plan018-additive-random-b01-s42-1000-r3\\n    role: Random 1000步\\n    result: PR=0.97 genuine=0%\\n  depends_on:\\n  - D075\\n  - D076\\n- id: D078\\n  date: 2026-05-15 12:59 UTC\\n  summary: 修正 plan002-b01-s42 数据：genuine_count 统一为 14，conclusion 恢复为 negative\\n  rationale: Reviewer 发现 registry 中 genuine_count 存在三值矛盾（26/25/14）。H8 re-eval 实际完成但\\n    metrics 未更新。H8 genuine=14/81=17.3%，hacking 82.7%，三 seed mean≈9.3，远低于 SFT baseline\\n    92.3%，明确否定 additive bonus 假设，conclusion 不应为 success。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: subject\\n    result: negative (corrected from success)\\n  depends_on: []\\n- id: D079\\n  date: 2026-05-15 13:38 UTC\\n  summary: 'SFT 3-seed 1000步 Reviewer PASS: genuine=92.2%±1.2%, 零 hacking, 与 GRPO\\n    各条件(0-2.2%)形成 >90pp 差距, definitive 支撑 \\\"Goodhart collapse is RL(GRPO)-specific\\\"'\\n  rationale: Reviewer 审查通过 3-seed SFT 1000步数据(s42/s43/s44), 一致性极高(std=1.2pp), 0 H7/H8,\\n    每 seed 恰好 1 个 H1。与 exec-only(0%), ISR β=0.1(2.2%), random β=0.1(0%) 在 1000步的对比差距\\n    >90pp, 不需要统计检验即可确认。论文可直接使用 92.2±1.2% 作为 SFT 对照数据。\\n  related_experiments:\\n  - exp_id: plan009-sft-baseline-s42-1000\\n    role: SFT 1000步 seed=42\\n    result: genuine=92.3%\\n  - exp_id: plan009-sft-baseline-s43-1000\\n    role: SFT 1000步 seed=43\\n    result: genuine=90.9%\\n  - exp_id: plan009-sft-baseline-s44-1000-r3\\n    role: SFT 1000步 seed=44\\n    result: genuine=93.3%\\n  depends_on:\\n  - D077\\n- id: D080\\n  date: 2026-05-15 13:47 UTC\\n  summary: 'CRITICAL: 磁盘满导致 exec-only s43 崩溃(step 150)、s44 即将崩溃。清理旧 checkpoint + 修复\\n    C003(save_total_limit) + 从头重跑'\\n  rationale: outputs 目录累计 235GB/250GB，旧实验 checkpoint 未清理。C003 约束(save_total_limit=1)在\\n    grpo_exec_only.yaml 中未设置，导致多 checkpoint 堆积。紧急清理 ≥60GB 后从 step 0 重跑 s43/s44。\\n  related_experiments:\\n  - exp_id: plan001-exec-only-s43-1000\\n    role: 磁盘满崩溃 step 150\\n    result: failed, 需重跑\\n  - exp_id: plan001-exec-only-s44-1000\\n    role: 即将崩溃 ~step 100\\n    result: 需 kill 后重跑\\n  depends_on:\\n  - D079\\n- id: D081\\n  date: 2026-05-15 13:49 UTC\\n  summary: Taxonomy 从 7 种升级到 8 种 hacking modes（新增 H8 conjunction collapse）。论文全文同步更新，Appendix\\n    补 H8 定义。所有 genuine rate 按 H8 修正后的数据级联更新。\\n  rationale: H8 conjunction collapse 是 H8 审计中发现的真实现象（如 plan002-b01-s42 从 genuine=26\\n    降至 14）。数据已在 registry 中修正，论文必须同步。7→8 是事实驱动的升级，不是人为扩充。\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: H8 导致 genuine 26→14\\n    result: genuine_rate 30.9%→17.3%\\n  - exp_id: plan012-hacking-taxonomy\\n    role: 分类体系升级\\n    result: 7→8 modes\\n  depends_on:\\n  - D079\\n- id: D082\\n  date: 2026-05-15 13:50 UTC\\n  summary: 'INC-01 决策: Taxonomy 升级 7→8 modes, H8=conjunction collapse 正式纳入。INC-05:\\n    ISR genuine 从 30.9%→17.3%(H8 修正), 3-seed pooled 12.1% vs Random 17.4%, 需重算 Fisher\\n    p 确认 claim 措辞'\\n  rationale: 'H8 审计发现 conjunction collapse 是独立 hacking mode, 不属于 H1-H7 任何一类。plan002-b01-s42\\n    genuine 从 26→14 (30.9%→17.3%), 3-seed pooled ISR genuine=12.1% vs Random=17.4%。方向未变(ISR\\n    无结构优势), 但 \\\"identical rates\\\" 措辞需调整——ISR 实际更低而非相等。论文需全文级联更新: taxonomy 定义、所有 genuine\\n    rate 数字、Wilson CI、Fisher p、claim 措辞。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s42\\n    role: H8修正后 genuine 30.9%→17.3%\\n    result: genuine=14/81\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: Random 对照\\n    result: genuine=23/79=29.1%\\n  depends_on:\\n  - D073\\n  - D079\\n- id: D083\\n  date: 2026-05-15 14:16 UTC\\n  summary: 紧急修复 Random 侧 s43-r2/s44 数据溯源断裂，补全分类指标 + FN 对称性检测\\n  rationale: Reviewer 审查 Claim 2 统计修正时发现 Random 47 genuine 中 24 个 (s43-r2=6, s44=18?)\\n    无法从现有数据独立核实——服务器输出目录已删除，s44 registry 无 genuine_count。论文不能使用不可溯源的数字。同时 FN 修正仅作用于\\n    ISR 侧未对 Random 做对等检查，存在审稿人攻击面。\\n  related_experiments:\\n  - exp_id: plan018-additive-random-b01-s43-r2\\n    role: 数据缺失\\n    result: genuine=6 在 registry 但输出目录已删、缺 H8 审计\\n  - exp_id: plan018-additive-random-b01-s44\\n    role: 数据缺失\\n    result: registry 无 genuine_count、输出目录已删\\n  - exp_id: plan018-additive-random-b01-s42\\n    role: 基准对照\\n    result: 数据完整 genuine=23, h8=0\\n  depends_on: []\\n- id: D084\\n  date: 2026-05-15 14:23 UTC\\n  summary: 统一 taxonomy 标准：genuine = proved − H7 − H1_exact − H8，H1-near 保留为 genuine\\n  rationale: 1) H8 (conjunction collapse) 是退化证明，必须扣除——s42 独立验证发现 3 例被原 audit 遗漏。2)\\n    H1-near (substring match) 仍需 solver 做简化/提取步骤，不完全平凡，保留为 genuine。3) 此标准清晰可程序化验证，对\\n    reviewer 可防御。4) ISR 和 Random 两侧必须对称使用同一标准。论文附录放 sensitivity analysis 展示 H1-near\\n    细分。\\n  related_experiments:\\n  - exp_id: s42-taxonomy-verify\\n    role: evidence\\n    result: H7=0, H1_exact=56, H1_near=8, H8=3, strict_genuine=12; under new standard\\n      genuine=20\\n  depends_on: []\\n- id: D085\\n  date: 2026-05-15 14:26 UTC\\n  summary: 引入 H7b 子类别 (obfuscated tautology via vacuous quantification)，升级 Claim 2\\n    叙事从 \\\"classifier bug\\\" 到 \\\"model-learned obfuscation\\\"\\n  rationale: 'ISR s44 FN 分析发现 11/12 FN 样本使用 vacuous quantifier wrapping（premise: ∃x(P→Q),\\n    conclusion: ∃x(∃y(P→Q))）规避 H7 文本匹配检测器。10/12 的 ISR=0.8 说明同时 game 了 ISR 评分。这不是技术债（normalization\\n    bug），而是模型习得的高级 tautology 伪装策略，是 meta-Goodhart 的直接证据——连 tautology 检测器本身也被 game\\n    了。论文应将此作为 H7b 子模式单独讨论。'\\n  related_experiments:\\n  - exp_id: plan002-additive-b01-s44\\n    role: evidence\\n    result: '12 FN: 11 vacuous_quantifier_wrapping + 1 structural_simplification,\\n      all tautological, ISR=0.8 in 10/12'\\n  depends_on:\\n  - D084\\n\", \"total_chars\": 67877, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 84_

<details><summary>Logged reasoning block</summary>

```text
The middle part of experiments.tex was truncated. I need to read the specific Goodhart section (§4.2). Let me read it with a different approach - using wc -l to figure out the line count and then reading specific ranges.

Also, the decisions.yaml is too large. Let me get specific decisions D076, D051, D085 via a subagent.

But actually, I have enough information to proceed with the audit. Let me also check the middle section by reading specific line ranges.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "4ac48f43-22e4-4e6f-ba73-793ab375ff63",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013AYbF5y4k4S3zjfcP6yW4i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17379,
      "cache_read_input_tokens": 60719,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 17379
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

_source line 85_

The middle of experiments.tex is truncated. Let me read the full file in sections.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "24d04b73-0498-4d96-8cf1-449e377a97d4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013AYbF5y4k4S3zjfcP6yW4i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17379,
      "cache_read_input_tokens": 60719,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 17379
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

_source line 86_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01KkjkvEXwi7nL6mGs8GHfeB`</summary>

```json
{
  "server": "westd-39279",
  "command": "wc -l /root/solver-trace-ablation/paper/experiments.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "c370f89f-9ef5-49d4-8491-cb37d45f9cb9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013AYbF5y4k4S3zjfcP6yW4i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17379,
      "cache_read_input_tokens": 60719,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 17379
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

_source line 87 · 2026-05-15T15:03:25.566Z_

<details><summary>↩ Tool result · `toolu_01KkjkvEXwi7nL6mGs8GHfeB`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"154 /root/solver-trace-ablation/paper/experiments.tex\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "3cad92bf-68a8-4faf-88c6-8db58c19054f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"154 /root/solver-trace-ablation/paper/experiments.tex\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.45}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"154 /root/solver-trace-ablation/paper/experiments.tex\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 88_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01HZK2ezo4gFpjkgPwzKeXyd`</summary>

```json
{
  "server": "westd-39279",
  "command": "head -n 60 /root/solver-trace-ablation/paper/experiments.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "934f568d-1937-4df7-9719-5e2373202d94",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AMNNLx73Y7UTPnyRv65rAS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 358,
      "cache_read_input_tokens": 78098,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 358
      },
      "output_tokens": 63,
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

_source line 89 · 2026-05-15T15:03:30.322Z_

<details><summary>↩ Tool result · `toolu_01HZK2ezo4gFpjkgPwzKeXyd`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Experiments}\\n\\\\label{sec:experiments}\\n\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\S\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\S\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\S\\\\ref{sec:crosslogic}).\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\S\\\\ref{sec:taxonomy}).\\n\\n\\\\subsection{Setup}\\\\label{sec:setup}\\n\\nWe train Qwen3-4B~\\\\citep{qwen3} with GRPO~\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\{42,43,44\\\\}$ on a fixed 500-example FOLIO~\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\footnote{All experiments use \\\\texttt{data/train\\\\_500\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\nHeld-out evaluation uses 100 FOLIO examples (\\\\texttt{proofwriter\\\\_fol\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\texttt{eval\\\\_sta.py}) so training-log ISR is never compared across runs.\\nWe report prove rate (PR), proved-only ISR ($\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution; \\\\S\\\\ref{sec:taxonomy-method}), and a \\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\n\\n\\\\subsection{ISR as Diagnostic}\\n\\\\label{sec:diagnostic}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.95\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\n\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\%$\\\\to$93\\\\%$\\\\to$96\\\\% while proved-only ISR falls $0.642{\\\\to}0.132{\\\\to}0.003$ over 100$\\\\to$500$\\\\to$1000 steps. By step 1000, 94.8\\\\% of proved samples have $\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\to$18.55 (contradiction explosion).}\\n\\\\label{fig:isr-collapse}\\n\\\\end{figure}\\n\\n\\\\textbf{Collapse trajectory.}\\nFigure~\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\nPR rises $32\\\\%\\\\to93\\\\%\\\\to96\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\to0.132\\\\to0.003$ (214$\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\nBy 500 steps, 87.1\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\% and mean component count more than doubles ($6.58\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\nExtended training, lacking a structural signal, \\\\emph{worsens} formalization quality while improving the headline number.\\n\\n\\\\textbf{Cross-seed instability.}\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\ref{app:detailed-results}): s42 reaches $\\\\text{PR}{=}93\\\\%$ via conclusion embedding ($\\\\text{H1}{=}87\\\\%$); s43 collapses to $\\\\text{PR}{=}14\\\\%$ via repetition (87\\\\% of rollouts truncated); s44 reaches $\\\\text{PR}{=}98\\\\%$ via tautological collapse ($\\\\text{H7}{=}100\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\nThe cross-seed PR variance ($\\\\sigma{\\\\pm}47$\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\n\\n\\\\textbf{SFT baseline.}\\nSFT on gold formalizations reaches $\\\\text{PR}{=}14\\\\%$ with $\\\\text{ISR}^{*}{=}0.571$, $\\\\text{H7}{=}0$, $\\\\text{H1}{=}7.1\\\\%$, $92.9\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\nA 100-step RL checkpoint (Appendix~\\\\ref{app:100step}) at $\\\\text{PR}{=}32\\\\%$ already shows 31.2\\\\% hacking (vs.\\\\ SFT's 7.1\\\\%), indicating reward hacking emerges early in RL training, not merely at high PR.\\n\\n\\\\subsection{Meta-Level Goodhart's Law}\\n\\\\label{sec:goodhart}\\n\\nWe now reverse roles: instead of treating ISR as an observer, we use it as a reward augmentation, $r = r_{\\\\text{exec}}\\\\cdot(1 + \\\\beta\\\\,\\\\text{ISR})$, with a matched random control, $r = r_{\\\\text{exec}}\\\\cdot(1 + \\\\beta\\\\,u)$, $u\\\\sim\\\\mathcal{U}(0,1)$, to isolate ISR-specific signal from generic reward-variance effects.\\nThe headline finding: ISR-as-reward produces \\\\emph{meta-level} Goodhart~\\\\citep{manheim-goodhart-taxonomy}---the diagnostic itself becomes the target of gaming.\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lcccccc}\\n\\\\toprule\\n\\\\textbf{Condition} & $\\\\boldsymbol{\\\\beta}$ & \\\\textbf{PR\\\\%}$\\\\uparrow$ & \\\\textbf{ISR}$^*$ & \\\\textbf{H7\\\\%} & \\\\textbf{H1\\\\%} & \\\\textbf{N-H\\\\%} \\\\\\\\\\n\\\\midrule\\nBase (0-shot) & --- & 12 & --- & --- & --- & --- \\\\\\\\ %% registry: sta-phase0-baseline\\nSFT & --- & 14 & 0.571 & 0 & 7 & \\\\textbf{93} \\\\\\\\ %% registry: plan009-sft-baseline-s42-r4\\n\\\\midrule\\nExec-only$^\\\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 13 \\\\\\\\ %% registry: plan001-exec-only-s42-r2\\nISR & 0.1 & 77{\\\\scriptsize$\\\\pm$14} & $\\\\ddagger$ & \\\\textbf{65} & 18 & 17 \\\\\\\\ %% registry: plan002-additive-b01-s42/s43/s44 (pooled)\\nRandom & 0.1 & \\\\textbf{85}{\\\\scriptsize$\\\\pm$6} & 0.086{\\\\scriptsize$\\\\pm$.04} & 0 & 81 & 19 \\\\\\\\ %% registry: plan018-additive-random-b01-s42/s43-r2/s44\\n\\\\midrule\\nISR & 0.3 & 66{\\\\scriptsize$\\\\pm$42} & 0.39{\\\\scriptsize$\\\\pm$.31} & \\\\textbf{50} & 37 & 14 \\\\\\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\\nRandom & 0.3 & 54{\\\\scriptsize$\\\\pm$35} & 0.09{\\\\scriptsize$\\\\pm$.09} & 4 & 95 & 1 \\\\\\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "9361e5b2-cb94-4718-8f96-8b3335504c80",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\\section{Experiments}\\\\n\\\\\\\\label{sec:experiments}\\\\n\\\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\\\\\S\\\\\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\\\\\S\\\\\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).\\\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\\\\\S\\\\\\\\ref{sec:taxonomy}).\\\\n\\\\n\\\\\\\\subsection{Setup}\\\\\\\\label{sec:setup}\\\\n\\\\nWe train Qwen3-4B~\\\\\\\\citep{qwen3} with GRPO~\\\\\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\\\\\{42,43,44\\\\\\\\}$ on a fixed 500-example FOLIO~\\\\\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\\\\\footnote{All experiments use \\\\\\\\texttt{data/train\\\\\\\\_500\\\\\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\\\nHeld-out evaluation uses 100 FOLIO examples (\\\\\\\\texttt{proofwriter\\\\\\\\_fol\\\\\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\\\\\texttt{eval\\\\\\\\_sta.py}) so training-log ISR is never compared across runs.\\\\nWe report prove rate (PR), proved-only ISR ($\\\\\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\\\\\text{necessary}}$ distribution; \\\\\\\\S\\\\\\\\ref{sec:taxonomy-method}), and a \\\\\\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\\\n\\\\n\\\\\\\\subsection{ISR as Diagnostic}\\\\n\\\\\\\\label{sec:diagnostic}\\\\n\\\\n\\\\\\\\begin{figure}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.95\\\\\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\\\n\\\\\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\\\\\%$\\\\\\\\to$93\\\\\\\\%$\\\\\\\\to$96\\\\\\\\% while proved-only ISR falls $0.642{\\\\\\\\to}0.132{\\\\\\\\to}0.003$ over 100$\\\\\\\\to$500$\\\\\\\\to$1000 steps. By step 1000, 94.8\\\\\\\\% of proved samples have $\\\\\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\\\\\to$18.55 (contradiction explosion).}\\\\n\\\\\\\\label{fig:isr-collapse}\\\\n\\\\\\\\end{figure}\\\\n\\\\n\\\\\\\\textbf{Collapse trajectory.}\\\\nFigure~\\\\\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\\\nPR rises $32\\\\\\\\%\\\\\\\\to93\\\\\\\\%\\\\\\\\to96\\\\\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\\\\\to0.132\\\\\\\\to0.003$ (214$\\\\\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\\\nBy 500 steps, 87.1\\\\\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\\\\\% and mean component count more than doubles ($6.58\\\\\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\\\nExtended training, lacking a structural signal, \\\\\\\\emph{worsens} formalization quality while improving the headline number.\\\\n\\\\n\\\\\\\\textbf{Cross-seed instability.}\\\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\\\\\ref{app:detailed-results}): s42 reaches $\\\\\\\\text{PR}{=}93\\\\\\\\%$ via conclusion embedding ($\\\\\\\\text{H1}{=}87\\\\\\\\%$); s43 collapses to $\\\\\\\\text{PR}{=}14\\\\\\\\%$ via repetition (87\\\\\\\\% of rollouts truncated); s44 reaches $\\\\\\\\text{PR}{=}98\\\\\\\\%$ via tautological collapse ($\\\\\\\\text{H7}{=}100\\\\\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\\\nThe cross-seed PR variance ($\\\\\\\\sigma{\\\\\\\\pm}47$\\\\\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\\\n\\\\n\\\\\\\\textbf{SFT baseline.}\\\\nSFT on gold formalizations reaches $\\\\\\\\text{PR}{=}14\\\\\\\\%$ with $\\\\\\\\text{ISR}^{*}{=}0.571$, $\\\\\\\\text{H7}{=}0$, $\\\\\\\\text{H1}{=}7.1\\\\\\\\%$, $92.9\\\\\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\\\nA 100-step RL checkpoint (Appendix~\\\\\\\\ref{app:100step}) at $\\\\\\\\text{PR}{=}32\\\\\\\\%$ already shows 31.2\\\\\\\\% hacking (vs.\\\\\\\\ SFT's 7.1\\\\\\\\%), indicating reward hacking emerges early in RL training, not merely at high PR.\\\\n\\\\n\\\\\\\\subsection{Meta-Level Goodhart's Law}\\\\n\\\\\\\\label{sec:goodhart}\\\\n\\\\nWe now reverse roles: instead of treating ISR as an observer, we use it as a reward augmentation, $r = r_{\\\\\\\\text{exec}}\\\\\\\\cdot(1 + \\\\\\\\beta\\\\\\\\,\\\\\\\\text{ISR})$, with a matched random control, $r = r_{\\\\\\\\text{exec}}\\\\\\\\cdot(1 + \\\\\\\\beta\\\\\\\\,u)$, $u\\\\\\\\sim\\\\\\\\mathcal{U}(0,1)$, to isolate ISR-specific signal from generic reward-variance effects.\\\\nThe headline finding: ISR-as-reward produces \\\\\\\\emph{meta-level} Goodhart~\\\\\\\\citep{manheim-goodhart-taxonomy}---the diagnostic itself becomes the target of gaming.\\\\n\\\\n\\\\\\\\begin{table}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\small\\\\n\\\\\\\\resizebox{\\\\\\\\columnwidth}{!}{%\\\\n\\\\\\\\begin{tabular}{lcccccc}\\\\n\\\\\\\\toprule\\\\n\\\\\\\\textbf{Condition} & $\\\\\\\\boldsymbol{\\\\\\\\beta}$ & \\\\\\\\textbf{PR\\\\\\\\%}$\\\\\\\\uparrow$ & \\\\\\\\textbf{ISR}$^*$ & \\\\\\\\textbf{H7\\\\\\\\%} & \\\\\\\\textbf{H1\\\\\\\\%} & \\\\\\\\textbf{N-H\\\\\\\\%} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\nBase (0-shot) & --- & 12 & --- & --- & --- & --- \\\\\\\\\\\\\\\\ %% registry: sta-phase0-baseline\\\\nSFT & --- & 14 & 0.571 & 0 & 7 & \\\\\\\\textbf{93} \\\\\\\\\\\\\\\\ %% registry: plan009-sft-baseline-s42-r4\\\\n\\\\\\\\midrule\\\\nExec-only$^\\\\\\\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 13 \\\\\\\\\\\\\\\\ %% registry: plan001-exec-only-s42-r2\\\\nISR & 0.1 & 77{\\\\\\\\scriptsize$\\\\\\\\pm$14} & $\\\\\\\\ddagger$ & \\\\\\\\textbf{65} & 18 & 17 \\\\\\\\\\\\\\\\ %% registry: plan002-additive-b01-s42/s43/s44 (pooled)\\\\nRandom & 0.1 & \\\\\\\\textbf{85}{\\\\\\\\scriptsize$\\\\\\\\pm$6} & 0.086{\\\\\\\\scriptsize$\\\\\\\\pm$.04} & 0 & 81 & 19 \\\\\\\\\\\\\\\\ %% registry: plan018-additive-random-b01-s42/s43-r2/s44\\\\n\\\\\\\\midrule\\\\nISR & 0.3 & 66{\\\\\\\\scriptsize$\\\\\\\\pm$42} & 0.39{\\\\\\\\scriptsize$\\\\\\\\pm$.31} & \\\\\\\\textbf{50} & 37 & 14 \\\\\\\\\\\\\\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\\\\nRandom & 0.3 & 54{\\\\\\\\scriptsize$\\\\\\\\pm$35} & 0.09{\\\\\\\\scriptsize$\\\\\\\\pm$.09} & 4 & 95 & 1 \\\\\\\\\\\\\\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled)\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.45}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\\section{Experiments}\\n\\\\label{sec:experiments}\\n\\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\\\S\\\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\\\S\\\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\\\S\\\\ref{sec:crosslogic}).\\nA hacking taxonomy synthesizes the modes observed across conditions (\\\\S\\\\ref{sec:taxonomy}).\\n\\n\\\\subsection{Setup}\\\\label{sec:setup}\\n\\nWe train Qwen3-4B~\\\\citep{qwen3} with GRPO~\\\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\\\{42,43,44\\\\}$ on a fixed 500-example FOLIO~\\\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\\\footnote{All experiments use \\\\texttt{data/train\\\\_500\\\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\\nHeld-out evaluation uses 100 FOLIO examples (\\\\texttt{proofwriter\\\\_fol\\\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\\\texttt{eval\\\\_sta.py}) so training-log ISR is never compared across runs.\\nWe report prove rate (PR), proved-only ISR ($\\\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\\\text{necessary}}$ distribution; \\\\S\\\\ref{sec:taxonomy-method}), and a \\\\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the seven cataloged patterns, a necessary but not sufficient condition for semantic correctness.\\n\\n\\\\subsection{ISR as Diagnostic}\\n\\\\label{sec:diagnostic}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.95\\\\columnwidth]{figures/fig2_isr_collapse.pdf}\\n\\\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\\\%$\\\\to$93\\\\%$\\\\to$96\\\\% while proved-only ISR falls $0.642{\\\\to}0.132{\\\\to}0.003$ over 100$\\\\to$500$\\\\to$1000 steps. By step 1000, 94.8\\\\% of proved samples have $\\\\text{ISR}{=}0$ and mean component count inflates 6.58$\\\\to$18.55 (contradiction explosion).}\\n\\\\label{fig:isr-collapse}\\n\\\\end{figure}\\n\\n\\\\textbf{Collapse trajectory.}\\nFigure~\\\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\\nPR rises $32\\\\%\\\\to93\\\\%\\\\to96\\\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\\\text{ISR}^*$ tells the opposite story, $0.642\\\\to0.132\\\\to0.003$ (214$\\\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\\nBy 500 steps, 87.1\\\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\\\% and mean component count more than doubles ($6.58\\\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\\nExtended training, lacking a structural signal, \\\\emph{worsens} formalization quality while improving the headline number.\\n\\n\\\\textbf{Cross-seed instability.}\\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\\\ref{app:detailed-results}): s42 reaches $\\\\text{PR}{=}93\\\\%$ via conclusion embedding ($\\\\text{H1}{=}87\\\\%$); s43 collapses to $\\\\text{PR}{=}14\\\\%$ via repetition (87\\\\% of rollouts truncated); s44 reaches $\\\\text{PR}{=}98\\\\%$ via tautological collapse ($\\\\text{H7}{=}100\\\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\\nThe cross-seed PR variance ($\\\\sigma{\\\\pm}47$\\\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\\n\\n\\\\textbf{SFT baseline.}\\nSFT on gold formalizations reaches $\\\\text{PR}{=}14\\\\%$ with $\\\\text{ISR}^{*}{=}0.571$, $\\\\text{H7}{=}0$, $\\\\text{H1}{=}7.1\\\\%$, $92.9\\\\%$ non-hacking. %% registry: plan009-sft-baseline-s42-r4\\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\\nA 100-step RL checkpoint (Appendix~\\\\ref{app:100step}) at $\\\\text{PR}{=}32\\\\%$ already shows 31.2\\\\% hacking (vs.\\\\ SFT's 7.1\\\\%), indicating reward hacking emerges early in RL training, not merely at high PR.\\n\\n\\\\subsection{Meta-Level Goodhart's Law}\\n\\\\label{sec:goodhart}\\n\\nWe now reverse roles: instead of treating ISR as an observer, we use it as a reward augmentation, $r = r_{\\\\text{exec}}\\\\cdot(1 + \\\\beta\\\\,\\\\text{ISR})$, with a matched random control, $r = r_{\\\\text{exec}}\\\\cdot(1 + \\\\beta\\\\,u)$, $u\\\\sim\\\\mathcal{U}(0,1)$, to isolate ISR-specific signal from generic reward-variance effects.\\nThe headline finding: ISR-as-reward produces \\\\emph{meta-level} Goodhart~\\\\citep{manheim-goodhart-taxonomy}---the diagnostic itself becomes the target of gaming.\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lcccccc}\\n\\\\toprule\\n\\\\textbf{Condition} & $\\\\boldsymbol{\\\\beta}$ & \\\\textbf{PR\\\\%}$\\\\uparrow$ & \\\\textbf{ISR}$^*$ & \\\\textbf{H7\\\\%} & \\\\textbf{H1\\\\%} & \\\\textbf{N-H\\\\%} \\\\\\\\\\n\\\\midrule\\nBase (0-shot) & --- & 12 & --- & --- & --- & --- \\\\\\\\ %% registry: sta-phase0-baseline\\nSFT & --- & 14 & 0.571 & 0 & 7 & \\\\textbf{93} \\\\\\\\ %% registry: plan009-sft-baseline-s42-r4\\n\\\\midrule\\nExec-only$^\\\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 13 \\\\\\\\ %% registry: plan001-exec-only-s42-r2\\nISR & 0.1 & 77{\\\\scriptsize$\\\\pm$14} & $\\\\ddagger$ & \\\\textbf{65} & 18 & 17 \\\\\\\\ %% registry: plan002-additive-b01-s42/s43/s44 (pooled)\\nRandom & 0.1 & \\\\textbf{85}{\\\\scriptsize$\\\\pm$6} & 0.086{\\\\scriptsize$\\\\pm$.04} & 0 & 81 & 19 \\\\\\\\ %% registry: plan018-additive-random-b01-s42/s43-r2/s44\\n\\\\midrule\\nISR & 0.3 & 66{\\\\scriptsize$\\\\pm$42} & 0.39{\\\\scriptsize$\\\\pm$.31} & \\\\textbf{50} & 37 & 14 \\\\\\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\\nRandom & 0.3 & 54{\\\\scriptsize$\\\\pm$35} & 0.09{\\\\scriptsize$\\\\pm$.09} & 4 & 95 & 1 \\\\\\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 90_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_012UkbZrrVHGf6q3qQNoYh9z`</summary>

```json
{
  "server": "westd-39279",
  "command": "tail -n +55 /root/solver-trace-ablation/paper/experiments.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "42219199-fd49-4e89-99ba-9b81b00aac41",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AMNNLx73Y7UTPnyRv65rAS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 358,
      "cache_read_input_tokens": 78098,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 358
      },
      "output_tokens": 63,
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

_source line 91 · 2026-05-15T15:03:30.947Z_

<details><summary>↩ Tool result · `toolu_012UkbZrrVHGf6q3qQNoYh9z`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"Exec-only$^\\\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 13 \\\\\\\\ %% registry: plan001-exec-only-s42-r2\\nISR & 0.1 & 77{\\\\scriptsize$\\\\pm$14} & $\\\\ddagger$ & \\\\textbf{65} & 18 & 17 \\\\\\\\ %% registry: plan002-additive-b01-s42/s43/s44 (pooled)\\nRandom & 0.1 & \\\\textbf{85}{\\\\scriptsize$\\\\pm$6} & 0.086{\\\\scriptsize$\\\\pm$.04} & 0 & 81 & 19 \\\\\\\\ %% registry: plan018-additive-random-b01-s42/s43-r2/s44\\n\\\\midrule\\nISR & 0.3 & 66{\\\\scriptsize$\\\\pm$42} & 0.39{\\\\scriptsize$\\\\pm$.31} & \\\\textbf{50} & 37 & 14 \\\\\\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\\nRandom & 0.3 & 54{\\\\scriptsize$\\\\pm$35} & 0.09{\\\\scriptsize$\\\\pm$.09} & 4 & 95 & 1 \\\\\\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled)\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Goodhart landscape across reward conditions. 3-seed rows: H7/H1/N-H pooled across seeds; PR/ISR$^*$: mean$\\\\pm$std of per-seed values. $^\\\\dagger$Seed~42. $\\\\ddagger$$\\\\text{ISR}^*$ omitted for ISR $\\\\beta{=}0.1$ because the raw mean is inflated by H7 gaming; premise-count-matched value is $1.06\\\\times$ random (\\\\S\\\\ref{sec:goodhart}, Appendix~\\\\ref{app:detailed-results}). Per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}.}\\n\\\\label{tab:goodhart-landscape}\\n\\\\end{table}\\n\\n\\\\textbf{Low-dose ISR ($\\\\beta{=}0.1$): ISR-specific gaming.}\\nThe most striking number is H7: 64.5\\\\% of proved samples under ISR ($n{=}149/231$) vs.\\\\ \\\\emph{zero} under random ($0/256$). %% registry: plan002 vs plan018 all seeds\\nH7---a single premise identical to the conclusion, giving $\\\\text{ISR}\\\\geq 0.5$ by construction (\\\\S\\\\ref{sec:taxonomy-method})---is the canonical meta-level Goodhart move: the model satisfies the LOO definition directly rather than producing a derivation that happens to satisfy it.\\nTotal conclusion embedding ($\\\\text{H1}+\\\\text{H7}$) is GRPO-universal at $68$--$97\\\\%$ across both conditions, and is in fact \\\\emph{higher} under random (pooled H1 81\\\\% vs.\\\\ 18\\\\% under ISR).\\nISR does not reduce hacking; it converts H1 into H7 (Figure~\\\\ref{fig:hacking-composition}).\\nRandom also yields higher and more stable PR ($85{\\\\pm}6\\\\%$ vs.\\\\ $77{\\\\pm}14\\\\%$).\\n\\n\\\\textbf{Premise-count confound.}\\nThe one ISR seed not dominated by H7 (s42) has raw $\\\\text{ISR}^{*}{=}0.415$, $3.2\\\\times$ its random control ($0.131$), suggesting genuine improvement.\\nThis appearance is a premise-minimization artifact: ISR-trained models produce shorter formalizations (mean $n{=}5.58$ vs.\\\\ $8.46$ for random), and ISR rises mechanically as $n$ falls---when $n{=}2$, $\\\\text{ISR}\\\\geq 0.5$ by definition.\\nRestricting to non-hacking samples with $\\\\geq{3}$ premises (eliminating the trivial-$n$ regime) gives $\\\\text{ISR}^{*}{=}0.258$ for ISR vs.\\\\ $0.243$ for random: a $1.06\\\\times$ ratio, no meaningful advantage. %% D051 premise-count-matched analysis\\nThe raw $3.2\\\\times$ headline collapses once the LOO bias is controlled---a methodological lesson for any LOO-based metric on variable-length outputs.\\n\\n\\\\textbf{High-dose ISR ($\\\\beta{=}0.3$): multi-modal Goodhart.}\\nAt $\\\\beta{=}0.3$, ISR-as-reward produces extreme cross-seed instability ($\\\\text{PR}{=}66{\\\\pm}42\\\\%$, spanning 18--95\\\\%); each seed converges to a distinct pathway (Appendix~\\\\ref{app:detailed-results}). %% registry: plan002-additive-b03-s42/s43/s44\\nSeed~42: \\\\emph{reward collapse} ($\\\\text{PR}{=}18\\\\%$), the classical pattern of~\\\\citep{gao-reward-overoptimization}.\\nSeed~43: \\\\emph{H1 shortcutting} ($\\\\text{PR}{=}86\\\\%$, $\\\\text{H1}{=}69\\\\%$, only $27\\\\%$ non-hacking).\\nSeed~44: \\\\emph{pure H7 meta-Goodhart} ($\\\\text{PR}{=}95\\\\%$, $\\\\text{H7}{=}100\\\\%$, $\\\\text{ISR}^{*}{=}0.742$, $0\\\\%$ non-hacking)---simultaneously gaming \\\\emph{both} execution and structural metrics through the same construction.\\nThe random control at $\\\\beta{=}0.3$ is equally unstable ($\\\\text{PR}{=}54{\\\\pm}35\\\\%$, spanning 23--92\\\\%) with near-universal H1 hacking ($96\\\\%$) and ${\\\\leq}3\\\\%$ non-hacking per seed; high-dose proxy weighting destabilizes training regardless of signal source; ISR produces diverse failure modes (reward collapse, H1 shortcutting, H7 meta-Goodhart) whil\\n\\n... [截断: 输出过长，省略 1815 字符] ...\\n\\n tautologies ($\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\nSeed~43: \\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\texttt{MARY\\\\_IS\\\\_AN\\\\_AVA\\\\-DEOTE.}); strict text-match returns $\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\nSeed~44: \\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\texttt{is\\\\_the\\\\_dog\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\nSeed~44 evaded our initial strict classifier (reported $100\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\n\\n\\\\subsection{Hacking Taxonomy}\\n\\\\label{sec:taxonomy}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\n\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\n\\\\label{fig:hacking-composition}\\n\\\\end{figure}\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lccccc}\\n\\\\toprule\\n\\\\textbf{Mode} & \\\\textbf{Exec} & \\\\textbf{ISR$_{.1}$} & \\\\textbf{Rnd$_{.1}$} & \\\\textbf{SFT} & \\\\textbf{Prolog$_{\\\\text{ISR}}$} \\\\\\\\\\n\\\\midrule\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\sharp$ \\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\sharp$ \\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\nCmplx.\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\n\\\\midrule\\n\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\textbf{93} & \\\\textbf{0} \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Seven hacking modes across conditions (\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\sharp$Prolog row pools strict+functional (\\\\S\\\\ref{sec:crosslogic}).}\\n\\\\label{tab:hacking-taxonomy}\\n\\\\end{table}\\n\\nThe seven modes (Table~\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\ref{app:hacking-modes}) span the studied conditions.\\nTwo are quantifiable across all conditions: \\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\%$ regardless of reward type, and \\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\%$ vs.\\\\ $0\\\\%$ in random controls.\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\n\\nThe cross-condition pattern is consistent with \\\\S\\\\ref{sec:goodhart}: \\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\nExec-only, ISR, and random conditions all show $\\\\geq 80\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\%$ non-hacking.\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\beta{=}0.1$ s42 at $\\\\text{PR}{=}81\\\\%$, $31\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "0d0e6543-973f-4d35-a23f-167b8b66db56",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"Exec-only$^\\\\\\\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 13 \\\\\\\\\\\\\\\\ %% registry: plan001-exec-only-s42-r2\\\\nISR & 0.1 & 77{\\\\\\\\scriptsize$\\\\\\\\pm$14} & $\\\\\\\\ddagger$ & \\\\\\\\textbf{65} & 18 & 17 \\\\\\\\\\\\\\\\ %% registry: plan002-additive-b01-s42/s43/s44 (pooled)\\\\nRandom & 0.1 & \\\\\\\\textbf{85}{\\\\\\\\scriptsize$\\\\\\\\pm$6} & 0.086{\\\\\\\\scriptsize$\\\\\\\\pm$.04} & 0 & 81 & 19 \\\\\\\\\\\\\\\\ %% registry: plan018-additive-random-b01-s42/s43-r2/s44\\\\n\\\\\\\\midrule\\\\nISR & 0.3 & 66{\\\\\\\\scriptsize$\\\\\\\\pm$42} & 0.39{\\\\\\\\scriptsize$\\\\\\\\pm$.31} & \\\\\\\\textbf{50} & 37 & 14 \\\\\\\\\\\\\\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\\\\nRandom & 0.3 & 54{\\\\\\\\scriptsize$\\\\\\\\pm$35} & 0.09{\\\\\\\\scriptsize$\\\\\\\\pm$.09} & 4 & 95 & 1 \\\\\\\\\\\\\\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled)\\\\n\\\\\\\\bottomrule\\\\n\\\\\\\\end{tabular}}\\\\n\\\\\\\\caption{Goodhart landscape across reward conditions. 3-seed rows: H7/H1/N-H pooled across seeds; PR/ISR$^*$: mean$\\\\\\\\pm$std of per-seed values. $^\\\\\\\\dagger$Seed~42. $\\\\\\\\ddagger$$\\\\\\\\text{ISR}^*$ omitted for ISR $\\\\\\\\beta{=}0.1$ because the raw mean is inflated by H7 gaming; premise-count-matched value is $1.06\\\\\\\\times$ random (\\\\\\\\S\\\\\\\\ref{sec:goodhart}, Appendix~\\\\\\\\ref{app:detailed-results}). Per-seed breakdown in Appendix Table~\\\\\\\\ref{tab:fol-detailed}.}\\\\n\\\\\\\\label{tab:goodhart-landscape}\\\\n\\\\\\\\end{table}\\\\n\\\\n\\\\\\\\textbf{Low-dose ISR ($\\\\\\\\beta{=}0.1$): ISR-specific gaming.}\\\\nThe most striking number is H7: 64.5\\\\\\\\% of proved samples under ISR ($n{=}149/231$) vs.\\\\\\\\ \\\\\\\\emph{zero} under random ($0/256$). %% registry: plan002 vs plan018 all seeds\\\\nH7---a single premise identical to the conclusion, giving $\\\\\\\\text{ISR}\\\\\\\\geq 0.5$ by construction (\\\\\\\\S\\\\\\\\ref{sec:taxonomy-method})---is the canonical meta-level Goodhart move: the model satisfies the LOO definition directly rather than producing a derivation that happens to satisfy it.\\\\nTotal conclusion embedding ($\\\\\\\\text{H1}+\\\\\\\\text{H7}$) is GRPO-universal at $68$--$97\\\\\\\\%$ across both conditions, and is in fact \\\\\\\\emph{higher} under random (pooled H1 81\\\\\\\\% vs.\\\\\\\\ 18\\\\\\\\% under ISR).\\\\nISR does not reduce hacking; it converts H1 into H7 (Figure~\\\\\\\\ref{fig:hacking-composition}).\\\\nRandom also yields higher and more stable PR ($85{\\\\\\\\pm}6\\\\\\\\%$ vs.\\\\\\\\ $77{\\\\\\\\pm}14\\\\\\\\%$).\\\\n\\\\n\\\\\\\\textbf{Premise-count confound.}\\\\nThe one ISR seed not dominated by H7 (s42) has raw $\\\\\\\\text{ISR}^{*}{=}0.415$, $3.2\\\\\\\\times$ its random control ($0.131$), suggesting genuine improvement.\\\\nThis appearance is a premise-minimization artifact: ISR-trained models produce shorter formalizations (mean $n{=}5.58$ vs.\\\\\\\\ $8.46$ for random), and ISR rises mechanically as $n$ falls---when $n{=}2$, $\\\\\\\\text{ISR}\\\\\\\\geq 0.5$ by definition.\\\\nRestricting to non-hacking samples with $\\\\\\\\geq{3}$ premises (eliminating the trivial-$n$ regime) gives $\\\\\\\\text{ISR}^{*}{=}0.258$ for ISR vs.\\\\\\\\ $0.243$ for random: a $1.06\\\\\\\\times$ ratio, no meaningful advantage. %% D051 premise-count-matched analysis\\\\nThe raw $3.2\\\\\\\\times$ headline collapses once the LOO bias is controlled---a methodological lesson for any LOO-based metric on variable-length outputs.\\\\n\\\\n\\\\\\\\textbf{High-dose ISR ($\\\\\\\\beta{=}0.3$): multi-modal Goodhart.}\\\\nAt $\\\\\\\\beta{=}0.3$, ISR-as-reward produces extreme cross-seed instability ($\\\\\\\\text{PR}{=}66{\\\\\\\\pm}42\\\\\\\\%$, spanning 18--95\\\\\\\\%); each seed converges to a distinct pathway (Appendix~\\\\\\\\ref{app:detailed-results}). %% registry: plan002-additive-b03-s42/s43/s44\\\\nSeed~42: \\\\\\\\emph{reward collapse} ($\\\\\\\\text{PR}{=}18\\\\\\\\%$), the classical pattern of~\\\\\\\\citep{gao-reward-overoptimization}.\\\\nSeed~43: \\\\\\\\emph{H1 shortcutting} ($\\\\\\\\text{PR}{=}86\\\\\\\\%$, $\\\\\\\\text{H1}{=}69\\\\\\\\%$, only $27\\\\\\\\%$ non-hacking).\\\\nSeed~44: \\\\\\\\emph{pure H7 meta-Goodhart} ($\\\\\\\\text{PR}{=}95\\\\\\\\%$, $\\\\\\\\text{H7}{=}100\\\\\\\\%$, $\\\\\\\\text{ISR}^{*}{=}0.742$, $0\\\\\\\\%$ non-hacking)---simultaneously gaming \\\\\\\\emph{both} execution and structural metrics through the same construction.\\\\nThe random control at $\\\\\\\\beta{=}0.3$ is equally unstable ($\\\\\\\\text{PR}{=}54{\\\\\\\\pm}35\\\\\\\\%$, spanning 23--92\\\\\\\\%) with near-universal H1 hacking ($96\\\\\\\\%$) and ${\\\\\\\\leq}3\\\\\\\\%$ non-hacking per seed; high-dose proxy weighting destabilizes training regardless of signal source; ISR produces diverse failure modes (reward collapse, H1 shortcutting, H7 meta-Goodhart) whil\\\\n\\\\n... [截断: 输出过长，省略 1815 字符] ...\\\\n\\\\n tautologies ($\\\\\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\\\nSeed~43: \\\\\\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\\\\\texttt{MARY\\\\\\\\_IS\\\\\\\\_AN\\\\\\\\_AVA\\\\\\\\-DEOTE.}); strict text-match returns $\\\\\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\\\nSeed~44: \\\\\\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\\\\\texttt{is\\\\\\\\_the\\\\\\\\_dog\\\\\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\\\nSeed~44 evaded our initial strict classifier (reported $100\\\\\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\\\n\\\\n\\\\\\\\subsection{Hacking Taxonomy}\\\\n\\\\\\\\label{sec:taxonomy}\\\\n\\\\n\\\\\\\\begin{figure}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\includegraphics[width=0.92\\\\\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\\\n\\\\\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\\\n\\\\\\\\label{fig:hacking-composition}\\\\n\\\\\\\\end{figure}\\\\n\\\\n\\\\\\\\begin{table}[t]\\\\n\\\\\\\\centering\\\\n\\\\\\\\small\\\\n\\\\\\\\resizebox{\\\\\\\\columnwidth}{!}{%\\\\n\\\\\\\\begin{tabular}{lccccc}\\\\n\\\\\\\\toprule\\\\n\\\\\\\\textbf{Mode} & \\\\\\\\textbf{Exec} & \\\\\\\\textbf{ISR$_{.1}$} & \\\\\\\\textbf{Rnd$_{.1}$} & \\\\\\\\textbf{SFT} & \\\\\\\\textbf{Prolog$_{\\\\\\\\text{ISR}}$} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\\\\\sharp$ \\\\\\\\\\\\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\\\\\sharp$ \\\\\\\\\\\\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\\\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\\\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\\\\\\\\\\\nCmplx.\\\\\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\\\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\\\\\\\\\\\n\\\\\\\\midrule\\\\n\\\\\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\\\\\textbf{93} & \\\\\\\\textbf{0} \\\\\\\\\\\\\\\\\\\\n\\\\\\\\bottomrule\\\\n\\\\\\\\end{tabular}}\\\\n\\\\\\\\caption{Seven hacking modes across conditions (\\\\\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\\\\\sharp$Prolog row pools strict+functional (\\\\\\\\S\\\\\\\\ref{sec:crosslogic}).}\\\\n\\\\\\\\label{tab:hacking-taxonomy}\\\\n\\\\\\\\end{table}\\\\n\\\\nThe seven modes (Table~\\\\\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\\\\\ref{app:hacking-modes}) span the studied conditions.\\\\nTwo are quantifiable across all conditions: \\\\\\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\\\\\%$ regardless of reward type, and \\\\\\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\\\\\%$ vs.\\\\\\\\ $0\\\\\\\\%$ in random controls.\\\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\\\n\\\\nThe cross-condition pattern is consistent with \\\\\\\\S\\\\\\\\ref{sec:goodhart}: \\\\\\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\\\nExec-only, ISR, and random conditions all show $\\\\\\\\geq 80\\\\\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\\\\\%$ non-hacking.\\\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\\\\\beta{=}0.1$ s42 at $\\\\\\\\text{PR}{=}81\\\\\\\\%$, $31\\\\\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.46}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"Exec-only$^\\\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 13 \\\\\\\\ %% registry: plan001-exec-only-s42-r2\\nISR & 0.1 & 77{\\\\scriptsize$\\\\pm$14} & $\\\\ddagger$ & \\\\textbf{65} & 18 & 17 \\\\\\\\ %% registry: plan002-additive-b01-s42/s43/s44 (pooled)\\nRandom & 0.1 & \\\\textbf{85}{\\\\scriptsize$\\\\pm$6} & 0.086{\\\\scriptsize$\\\\pm$.04} & 0 & 81 & 19 \\\\\\\\ %% registry: plan018-additive-random-b01-s42/s43-r2/s44\\n\\\\midrule\\nISR & 0.3 & 66{\\\\scriptsize$\\\\pm$42} & 0.39{\\\\scriptsize$\\\\pm$.31} & \\\\textbf{50} & 37 & 14 \\\\\\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\\nRandom & 0.3 & 54{\\\\scriptsize$\\\\pm$35} & 0.09{\\\\scriptsize$\\\\pm$.09} & 4 & 95 & 1 \\\\\\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled)\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Goodhart landscape across reward conditions. 3-seed rows: H7/H1/N-H pooled across seeds; PR/ISR$^*$: mean$\\\\pm$std of per-seed values. $^\\\\dagger$Seed~42. $\\\\ddagger$$\\\\text{ISR}^*$ omitted for ISR $\\\\beta{=}0.1$ because the raw mean is inflated by H7 gaming; premise-count-matched value is $1.06\\\\times$ random (\\\\S\\\\ref{sec:goodhart}, Appendix~\\\\ref{app:detailed-results}). Per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}.}\\n\\\\label{tab:goodhart-landscape}\\n\\\\end{table}\\n\\n\\\\textbf{Low-dose ISR ($\\\\beta{=}0.1$): ISR-specific gaming.}\\nThe most striking number is H7: 64.5\\\\% of proved samples under ISR ($n{=}149/231$) vs.\\\\ \\\\emph{zero} under random ($0/256$). %% registry: plan002 vs plan018 all seeds\\nH7---a single premise identical to the conclusion, giving $\\\\text{ISR}\\\\geq 0.5$ by construction (\\\\S\\\\ref{sec:taxonomy-method})---is the canonical meta-level Goodhart move: the model satisfies the LOO definition directly rather than producing a derivation that happens to satisfy it.\\nTotal conclusion embedding ($\\\\text{H1}+\\\\text{H7}$) is GRPO-universal at $68$--$97\\\\%$ across both conditions, and is in fact \\\\emph{higher} under random (pooled H1 81\\\\% vs.\\\\ 18\\\\% under ISR).\\nISR does not reduce hacking; it converts H1 into H7 (Figure~\\\\ref{fig:hacking-composition}).\\nRandom also yields higher and more stable PR ($85{\\\\pm}6\\\\%$ vs.\\\\ $77{\\\\pm}14\\\\%$).\\n\\n\\\\textbf{Premise-count confound.}\\nThe one ISR seed not dominated by H7 (s42) has raw $\\\\text{ISR}^{*}{=}0.415$, $3.2\\\\times$ its random control ($0.131$), suggesting genuine improvement.\\nThis appearance is a premise-minimization artifact: ISR-trained models produce shorter formalizations (mean $n{=}5.58$ vs.\\\\ $8.46$ for random), and ISR rises mechanically as $n$ falls---when $n{=}2$, $\\\\text{ISR}\\\\geq 0.5$ by definition.\\nRestricting to non-hacking samples with $\\\\geq{3}$ premises (eliminating the trivial-$n$ regime) gives $\\\\text{ISR}^{*}{=}0.258$ for ISR vs.\\\\ $0.243$ for random: a $1.06\\\\times$ ratio, no meaningful advantage. %% D051 premise-count-matched analysis\\nThe raw $3.2\\\\times$ headline collapses once the LOO bias is controlled---a methodological lesson for any LOO-based metric on variable-length outputs.\\n\\n\\\\textbf{High-dose ISR ($\\\\beta{=}0.3$): multi-modal Goodhart.}\\nAt $\\\\beta{=}0.3$, ISR-as-reward produces extreme cross-seed instability ($\\\\text{PR}{=}66{\\\\pm}42\\\\%$, spanning 18--95\\\\%); each seed converges to a distinct pathway (Appendix~\\\\ref{app:detailed-results}). %% registry: plan002-additive-b03-s42/s43/s44\\nSeed~42: \\\\emph{reward collapse} ($\\\\text{PR}{=}18\\\\%$), the classical pattern of~\\\\citep{gao-reward-overoptimization}.\\nSeed~43: \\\\emph{H1 shortcutting} ($\\\\text{PR}{=}86\\\\%$, $\\\\text{H1}{=}69\\\\%$, only $27\\\\%$ non-hacking).\\nSeed~44: \\\\emph{pure H7 meta-Goodhart} ($\\\\text{PR}{=}95\\\\%$, $\\\\text{H7}{=}100\\\\%$, $\\\\text{ISR}^{*}{=}0.742$, $0\\\\%$ non-hacking)---simultaneously gaming \\\\emph{both} execution and structural metrics through the same construction.\\nThe random control at $\\\\beta{=}0.3$ is equally unstable ($\\\\text{PR}{=}54{\\\\pm}35\\\\%$, spanning 23--92\\\\%) with near-universal H1 hacking ($96\\\\%$) and ${\\\\leq}3\\\\%$ non-hacking per seed; high-dose proxy weighting destabilizes training regardless of signal source; ISR produces diverse failure modes (reward collapse, H1 shortcutting, H7 meta-Goodhart) whil\\n\\n... [截断: 输出过长，省略 1815 字符] ...\\n\\n tautologies ($\\\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\\nSeed~43: \\\\emph{degenerate uppercase pseudo-Prolog} (e.g., \\\\texttt{MARY\\\\_IS\\\\_AN\\\\_AVA\\\\-DEOTE.}); strict text-match returns $\\\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\\nSeed~44: \\\\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\\\texttt{is\\\\_the\\\\_dog\\\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\\nSeed~44 evaded our initial strict classifier (reported $100\\\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\\n\\n\\\\subsection{Hacking Taxonomy}\\n\\\\label{sec:taxonomy}\\n\\n\\\\begin{figure}[t]\\n\\\\centering\\n\\\\includegraphics[width=0.92\\\\columnwidth]{figures/fig3_hacking_composition.pdf}\\n\\\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\\n\\\\label{fig:hacking-composition}\\n\\\\end{figure}\\n\\n\\\\begin{table}[t]\\n\\\\centering\\n\\\\small\\n\\\\resizebox{\\\\columnwidth}{!}{%\\n\\\\begin{tabular}{lccccc}\\n\\\\toprule\\n\\\\textbf{Mode} & \\\\textbf{Exec} & \\\\textbf{ISR$_{.1}$} & \\\\textbf{Rnd$_{.1}$} & \\\\textbf{SFT} & \\\\textbf{Prolog$_{\\\\text{ISR}}$} \\\\\\\\\\n\\\\midrule\\nH1 embed       & 87 & 18 & 81 & 7 & 0$^\\\\sharp$ \\\\\\\\\\nH7 duplicate   & 0  & 65 & 0  & 0 & 100$^\\\\sharp$ \\\\\\\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\\\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\\\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\\\\\\nCmplx.\\\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\\\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\\\\\\n\\\\midrule\\n\\\\textbf{Non-hacking} & 13 & 17 & 19 & \\\\textbf{93} & \\\\textbf{0} \\\\\\\\\\n\\\\bottomrule\\n\\\\end{tabular}}\\n\\\\caption{Seven hacking modes across conditions (\\\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). Cells with seed identifiers indicate the mode dominates that seed. $^\\\\sharp$Prolog row pools strict+functional (\\\\S\\\\ref{sec:crosslogic}).}\\n\\\\label{tab:hacking-taxonomy}\\n\\\\end{table}\\n\\nThe seven modes (Table~\\\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\\\ref{app:hacking-modes}) span the studied conditions.\\nTwo are quantifiable across all conditions: \\\\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$97\\\\%$ regardless of reward type, and \\\\textbf{H7} (conclusion duplication) is ISR-specific at $64.5\\\\%$ vs.\\\\ $0\\\\%$ in random controls.\\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\\n\\nThe cross-condition pattern is consistent with \\\\S\\\\ref{sec:goodhart}: \\\\emph{reward formulation determines hacking composition but not hacking prevalence.}\\nExec-only, ISR, and random conditions all show $\\\\geq 80\\\\%$ pooled hacking among proved samples; only SFT shows $93\\\\%$ non-hacking.\\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is ISR $\\\\beta{=}0.1$ s42 at $\\\\text{PR}{=}81\\\\%$, $31\\\\%$ non-hacking, and even that residual is the premise-minimization artifact analyzed above.\\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 92_

<details><summary>Logged reasoning block</summary>

```text
Now I have the Goodhart section. Let me also check the specific numbers in the remaining truncated part. The tail output from line 55+ still had a truncation in the middle. Let me get the specific lines that were truncated.

Actually, looking at the outputs, I can see most of the Goodhart section now. Let me check a few more things:

1. The ISR β=0.3 table in the Goodhart landscape table:
   - ISR 0.3: PR=66±42, ISR*=0.39±0.31, H7=50, H1=37, N-H=14
   - Random 0.3: PR=54±35, ISR*=0.09±0.09, H7=4, H1=95, N-H=1

Now I'm verifying the pooled results for ISR β=0.3 across the individual samples, where s42 shows a lower proof rate of 0.18 with mostly H1 results, while s43 has a much higher proof rate of 0.86 with more balanced H7 and H1 distributions.

For s44 with a proof rate of 0.95, nearly all results are H7. When I pool these three samples together, the H7 percentage comes to about 50%, H1 to 37%, and N-H to 14%, which matches what the paper reports.

Checking the Random β=0.3 pooled numbers now, where s42 shows a proof rate of 0.48 with all H1 results, and s43 has a proof rate of 0.92 with a small H7 component...

Compiling the pooled percentages for this scenario...

For s42, I'm finding the missing H8 category (conjunction collapse cases) by subtracting the accounted categories from the total proved count—that gives 12 cases at a 14.8% rate. For s43 and s44, the distributions are simpler: s43 is almost entirely H7 with just 2 genuine cases, while s44 is entirely H7.

When I pool these three scenarios, the H7 rate comes to 69.7%, but the paper reports 65%—there's a discrepancy I need to investigate. I'm noticing the registry includes an H7b correction for s44 (77 base H7a cases plus 12 H7b cases equals 89 total), and I need to check whether the paper's calculation uses a different breakdown of these H7 subcategories. I'm noticing a discrepancy in how the paper counts those 12 obfuscated tautologies from s44. According to D085, they should be classified as H7b post-correction, but the paper seems to be treating them differently in its taxonomy table. Let me verify this against the genuine counts—s42 shows 14 genuine cases after applying the H8 correction formula, and s43 has 2, which suggests the paper may still be using the pre-D085 classification scheme. So the paper's 17% N-H rate comes from using pre-D084 and pre-D085 numbers, which reveals two critical issues: H8 (conjunction collapse) was never included in their taxonomy, and the D085 correction for H7b obfuscated tautologies wasn't applied. This accounts for why they report 7 modes instead of 8, their H7 percentage is lower, and their N-H rate differs from the corrected calculation.

Let me verify this pattern holds for the ISR β=0.1 s42 breakdown—the paper shows 87% H1 and 13% N-H, and when I check the registry without subtracting H8, the non-hacking rate matches exactly at 13%, confirming the paper systematically excludes H8 from the taxonomy and inflates N-H by including those conjunction collapse samples.

Now looking at the full ISR β=0.1 row across all three scenarios, I'm calculating the pooled rates: H7 accounts for about 65%, H1 for 18%, and N-H for 17%, which aligns with what the paper reports. This confirms the same pattern—H8 is being absorbed into N-H throughout. D085 corrections:
- s42: H7=13, H1=42, H8=12, N-H=14 → total=81 ✓
- s43: H7=59, H1=0, N-H=2 → total=61 ✓
- s44: H7=89 (77+12 H7b), H1=0, N-H=0 → total=89 ✓

Pooled H7: 161/231=69.7%
Pooled H1: 42/231=18.2%
Pooled H8: 12/231=5.2%
Pooled N-H: 16/231=6.9%

69.7+18.2+5.2+6.9=100% ✓

The paper's numbers are internally consistent but they're using pre-D084/D085 classifications, which violates the standard taxonomy established in D084 and D085 where genuine equals proved minus H7, H1_exact, and H8, with H7 further decomposed into H7a and H7b. Now checking the Random β=0.1 data, the paper reports H7=0, H1=81, N-H=19, but the registry shows proved=79 with H1=56 (70.9%) and genuine_exact_h1=23 (29.1%), which would give N-H=23 under the paper's methodology—a significant discrepancy.

For the pooled 3-seed analysis, the paper combines s42 (confirmed data) with s43 and s44 marked as provisional, yielding pooled H1 of 81.6% and N-H of 18.4%, which round to the reported 81% and 19%. However, the paper's framing explicitly flags s43 and s44 as provisional, yet treats them as finalized in the pooled calculation.

Now checking the "Random β=0.1 PR" results—the paper reports 85±6, and averaging the three seeds (79%, 88%, 89%) gives 85.3%, which rounds to 85%. For the standard deviation, I'm calculating the spread across these three values.

For ISR β=0.1, the paper shows PR=77±14, and the three seeds (81%, 61%, 89%) average to exactly 77% with a standard deviation of about 14.4%, which matches. Now I'm verifying the "31% non-hacking" claim for ISR β=0.1 s42 at PR=81%—this should be the non-hacking percentage derived from the pre-D084 data.

Using the paper's formula (proved minus H7 minus H1), I get 81 - 13 - 42 = 26, which gives 26/81 = 32.1%, but the paper states 31%. There's a small discrepancy here—either a rounding difference or the paper might be using a slightly different classification method for the hacking categories than what I'm calculating. framing says for s42 ISR β=0.1:
   "s42 (ISR β=0.1) | PR=0.81 | ISR*=0.415 | H7=16.0% (13/81) | H1=51.9% (42/81) | H7+H1=67.9% | Genuine%=32.1% (26)"
   
   So genuine = 32.1% pre-D084. But the paper says "31%". That's a rounding issue (32.1% → 31%?). That's slightly off but could just be rounding.
   
   Actually, "17 non-hacking" from the pooled ISR table (17% of 231) is 39 samples. Per-seed: 26+2+12 = 40... wait that gives 17.3%.

Looking at the paper's framing data more carefully, the post-D084 genuine rate for ISR β=0.1 s42 is 14/81 = 17.3%, while pre-D084 (without the H8 subtraction) it's 26/81 = 32.1%. The paper's reported "31% non-hacking" aligns closely with this pre-D084 figure, just with minor rounding differences.

Let me verify the correlation claim about ISR and downstream NLI accuracy. The paper states "ISR is uncorrelated with downstream NLI accuracy (ρ=−0.049, p=0.187)" and the framing data confirms this exactly: Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187).

Now checking the O(1) binary variant claim of PR=63%, ISR*=0.007. This appears in the appendix and involves a convex combination of execution reward and a fast ISR variant. The registry shows related plans like the convex random approach, but this specific experiment seems separate from the main registry entries, so I'll skip detailed verification on this one.

For the SFT baseline at 500 steps, the paper reports PR=14%, ISR*=0.571, with 92.9% genuine solutions and no H7 violations. The registry data I have is for the 1000-step versions, but the paper's framing confirms these metrics for the 500-step variant. Now looking at what happens at 100 steps, where a checkpoint already shows PR=32% with 31... Looking at the paper's reported results, it only presents the single-seed SFT baseline (s42 at 500 steps with 92.9% non-hacking), but the task references a 3-seed 1000-step SFT result with different metrics — the paper doesn't actually report this aggregated 3-seed data in its main tables, only the individual seed values appear to be available. I'm scanning through the TeX for "significantly" and don't see it used anywhere—good sign. Now checking for the "2.4x" claim: the paper mentions "3.2×" for the raw ISR ratio (0.415 vs 0.131) and "1.06×" for the premise-count-matched version. The original 2.4x came from a different comparison using genuine-only ISR (0.601 vs 0.252), so the paper's using a different baseline metric entirely.

For the Random β=0.3 s42 source, the table references plan017-additive-random-s42 rather than the exp1-random-b03-s42 the agent was looking for—the registry comments suggest the paper got this right. Now I'm checking the bootstrap CI numbers the task mentioned for genuine rate parity and the H7 gaming metric.

I'm searching through the TeX files for "bootstrap", "p=0.637", "p=0.0004", and "p<0.001" but they're not appearing in what I've read so far. There were some truncated sections in the experiments.tex file that might contain these values. Let me also verify whether the "31% non-hacking" figure for ISR s42 corresponds to 26/81 or a different calculation. I'm trying to pin down where the 31% figure comes from in the paper's taxonomy section. The calculation I'm working through shows 32.1% pre-D084 and 17.3% post-D084 for s42, but neither matches the stated 31%, so I need to figure out what methodology the paper actually used to arrive at that number. I'm checking whether the 31% figure might come from a different calculation method or dataset version. The math shows 26/81 = 32.1%, not 31%, so there's a small discrepancy—either a typo in the paper or it was computed from slightly different numbers than what I'm seeing in the current data.

Now I need to hunt down those bootstrap confidence intervals that were mentioned in the task but haven't shown up in the paper yet. Let me look more carefully at the experiments section around where they should be.

I'm also cross-checking the Prolog STA results more systematically. The paper reports specific seed results like seed 44 with 95/97 proved samples, which matches the registry's 97.9% pass rate. Seed 43 shows 38 proved samples matching the registry's 0.38 prove rate. For seed 42, the paper claims all 50/100 proved with ISR*=1.0, and I'm verifying this against the registry data.

Now I'm working through the Goodhart table verification by pooling the results across seeds 42, 43, and 44 to check the reported H7 rate of 50%. Breaking down each seed's contribution to the H1 metric and summing the H7 counts gives me 99/199 = 49.7%, which aligns with the paper's 50% claim.

The H1 and N-H percentages also check out with minor rounding differences. But I'm noticing a discrepancy with the ISR β=0.3 s42 experiment — the paper cites PR=0.18 (18 proved), yet the registry shows a different experiment ID with PR=0.95. The paper attributes these results to "plan002-additive-b03" rather than "exp1", so I need to verify which experiment ID actually corresponds to the 500-step version with the lower performance.

Looking at the other seeds, s43 and s44 match up correctly between the exp1-isr-b03 entries and the paper's reported percentages, so the naming convention seems consistent for those. The question is whether s42 at 500 steps is simply missing from the registry or if it's under a different experiment ID altogether.

Let me check the bootstrap CI section more carefully — the truncation might be from the SSH output rather than the file itself being incomplete. I should try reading specific line ranges to see what's actually there.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "b13e8752-7863-436d-a1c0-9ed466ebcc3e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CYXrAPx7yeNgQVWFS1UyRo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6340,
      "cache_read_input_tokens": 78456,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6340
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

_source line 93_

Need to read the section around line 70-100 of experiments.tex that was truncated. Also searching for bootstrap CI numbers.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "85c90443-259a-4596-a9ef-9061b4ec8d4c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CYXrAPx7yeNgQVWFS1UyRo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6340,
      "cache_read_input_tokens": 78456,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6340
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

_source line 94_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01QNGiGJ5hvNaXCDyb9b6dzA`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -n \"bootstrap\\|p=0\\|Fisher\\|Wilson\\|CI\\|parity\\|inflation\" /root/solver-trace-ablation/paper/experiments.tex /root/solver-trace-ablation/paper/appendix.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "98524234-d025-41e8-8084-92b05f32277a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CYXrAPx7yeNgQVWFS1UyRo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6340,
      "cache_read_input_tokens": 78456,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6340
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

_source line 95 · 2026-05-15T15:06:09.815Z_

<details><summary>↩ Tool result · `toolu_01QNGiGJ5hvNaXCDyb9b6dzA`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "42ff774c-56eb-45dd-a6aa-fedf649f7232",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 96_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_0142adnBKqhTA6EbemhH3Dgo`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -n \"2\\.4\\|43\\.2\\|eight\\|8 mode\\|8 hack\\|H8\\|conjunction\" /root/solver-trace-ablation/paper/experiments.tex /root/solver-trace-ablation/paper/appendix.tex /root/solver-trace-ablation/paper/abstract.tex /root/solver-trace-ablation/paper/introduction.tex /root/solver-trace-ablation/paper/conclusion.tex /root/solver-trace-ablation/paper/method.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "662786f0-9cfa-4d0b-89ea-f7756bc728a4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CYXrAPx7yeNgQVWFS1UyRo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6340,
      "cache_read_input_tokens": 78456,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6340
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

_source line 97 · 2026-05-15T15:06:12.279Z_

<details><summary>↩ Tool result · `toolu_0142adnBKqhTA6EbemhH3Dgo`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "cfa803dd-f4d4-4821-a7ab-4fd9055bea23",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 98_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01M33NL6R8R5Ps3v8jgVf7T3`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -n \"significantly\\|H7b\\|obfuscated\\|H7a\" /root/solver-trace-ablation/paper/experiments.tex /root/solver-trace-ablation/paper/appendix.tex /root/solver-trace-ablation/paper/abstract.tex /root/solver-trace-ablation/paper/introduction.tex /root/solver-trace-ablation/paper/method.tex /root/solver-trace-ablation/paper/conclusion.tex",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "f9e3899b-59fd-476c-b473-fd247475d198",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CYXrAPx7yeNgQVWFS1UyRo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6340,
      "cache_read_input_tokens": 78456,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6340
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

_source line 99 · 2026-05-15T15:06:13.874Z_

<details><summary>↩ Tool result · `toolu_01M33NL6R8R5Ps3v8jgVf7T3`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "7b446998-2787-403a-bc5b-4f82ad9f27ef",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 100_

<details><summary>Logged reasoning block</summary>

```text
The pipe character is blocked in ssh_read_only. Let me use grep with -e flags for multiple patterns, or use multiple separate grep calls without pipes. Actually, the issue is the pipe `|` in the regex pattern being interpreted as a shell metacharacter. Let me use -e for each pattern or use extended grep with the pattern in quotes.

Actually, the issue is using `\|` which contains `|`. Let me use grep -E with the pattern or just do separate greps.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "a77e9611-ece5-4ba0-a33b-c2c9f1114b1f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W642oSZaFUc3en4dckoNg9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9119,
      "cache_read_input_tokens": 84796,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9119
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

_source line 101_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_0197z6wFJJDkxV5dwcNRBJ5Q`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -rn \"bootstrap\" /root/solver-trace-ablation/paper/",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "27185d1a-b817-44de-aae5-745c8b02a5e7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W642oSZaFUc3en4dckoNg9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9119,
      "cache_read_input_tokens": 84796,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9119
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

_source line 102 · 2026-05-15T15:06:21.642Z_

<details><summary>↩ Tool result · `toolu_0197z6wFJJDkxV5dwcNRBJ5Q`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "49e1534e-9082-4461-9043-107a80c814a8",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 1}, \\\"error\\\": \\\"exit code 1\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.45}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.45}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 103_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01SF8qTRqEjJCavfAxUu5ivZ`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -rn \"H8\" /root/solver-trace-ablation/paper/",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "a331bb95-eed3-4b2e-9457-d4569f83dfcc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W642oSZaFUc3en4dckoNg9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9119,
      "cache_read_input_tokens": 84796,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9119
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

_source line 104_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01YRqe9LQLp4sUsaZxdof216`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -rn \"conjunction\" /root/solver-trace-ablation/paper/",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "c360c476-7cd4-41a8-a4d7-f2aa63c39483",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W642oSZaFUc3en4dckoNg9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9119,
      "cache_read_input_tokens": 84796,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9119
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

_source line 105 · 2026-05-15T15:06:22.791Z_

<details><summary>↩ Tool result · `toolu_01SF8qTRqEjJCavfAxUu5ivZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/solver-trace-ablation/paper/main.pdf: binary file matches\\n\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.69}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "a724cdd2-082e-41f9-a186-9e7a50a0d8b8",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"grep: /root/solver-trace-ablation/paper/main.pdf: binary file matches\\\\n\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.69}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/solver-trace-ablation/paper/main.pdf: binary file matches\\n\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.69}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 106 · 2026-05-15T15:06:23.336Z_

<details><summary>↩ Tool result · `toolu_01YRqe9LQLp4sUsaZxdof216`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.54}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "d054589a-ffe6-4a06-b44c-bd9cfefb7913",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 1}, \\\"error\\\": \\\"exit code 1\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.54}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.54}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 107_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01BHxKujXp8pJExXtCMQSgQZ`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -rn \"43.2\" /root/solver-trace-ablation/paper/",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "b6f827e8-0d98-4020-9c9e-7ea55c64d78d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W642oSZaFUc3en4dckoNg9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9119,
      "cache_read_input_tokens": 84796,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9119
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

_source line 108 · 2026-05-15T15:06:24.275Z_

<details><summary>↩ Tool result · `toolu_01BHxKujXp8pJExXtCMQSgQZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/solver-trace-ablation/paper/figures/fig1_sta_overview.pdf: binary file matches\\ngrep: /root/solver-trace-ablation/paper/main.pdf: binary file matches\\n\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.73}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "ae56e5fc-c446-4885-9e98-812e311f7dbc",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"grep: /root/solver-trace-ablation/paper/figures/fig1_sta_overview.pdf: binary file matches\\\\ngrep: /root/solver-trace-ablation/paper/main.pdf: binary file matches\\\\n\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.73}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/solver-trace-ablation/paper/figures/fig1_sta_overview.pdf: binary file matches\\ngrep: /root/solver-trace-ablation/paper/main.pdf: binary file matches\\n\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.73}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 109_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01UJqLCHUyYhbe9fUM7EjWVJ`</summary>

```json
{
  "server": "westd-39279",
  "command": "grep -rn \"2.4\" /root/solver-trace-ablation/paper/",
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
  "session_id": "c5d06691-251a-4d7e-8a08-578a6098a5cc",
  "uuid": "6b466784-a9d2-4cc1-be35-a414cad21c7f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W642oSZaFUc3en4dckoNg9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9119,
      "cache_read_input_tokens": 84796,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9119
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

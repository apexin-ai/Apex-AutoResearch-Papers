# analyze eval supp k2mean object s42

**Knowing When Not to Correct: Adaptive Test-Time Refinement for Vision-Language-Action Models** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 7
- **Recorded user turns:** 0
- **Tool calls:** 3
- **Original source:** `logs/chats/worker_analyze_eval-supp-k2mean-object-s42_20260523T100431.jsonl`
- **Structured JSON:** [`f55548fe4a2e3c87a85d.json`](../../sessions/f5/f55548fe4a2e3c87a85d.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

7 recorded events

### Tool call

_source line 1 · 2026-05-23T10:04:56.358095+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__ssh_read_only",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-23T10:04:56.358591+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-23T10:04:56.358837+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb2-28827",
  "command": "tail -100 /root/acr-vla-conformal-refinement/logs/eval-supp-k2mean-object-s42.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb2-28827",
    "command": "tail -100 /root/acr-vla-conformal-refinement/logs/eval-supp-k2mean-object-s42.log",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-23T10:04:56.359044+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb2-28827",
  "command": "ls /root/acr-vla-conformal-refinement/logs/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb2-28827",
    "command": "ls /root/acr-vla-conformal-refinement/logs/",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-23T10:04:56.359372+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"[evaluate] args: {'benchmark': 'object', 'checkpoint': None, 'crm_checkpoint': None, 'n_rollouts': 20, 'max_steps': 300, 'seed': 42, 'K': 2, 'mode': 'vla_only', 'baseline_mode': 'mean', 'smolvla_path': '/root/autodl-tmp/models/smolvla_libero/', 'model': 'smolvla', 'pi05_path': '/root/autodl-tmp/models/pi05_libero_finetuned/', 'obs_dim': 960, 'unified_obs_dim': None, 'hidden_dim': 256, 'task_filter': None, 'render': False, 'output_file': 'logs/eval_object_vla_only_seed42.json', 'max_correction_norm': None, 'adaptive_k': False, 'adaptive_threshold': 0.1, 'k_init': 2, 'k_full': 5, 'unc_head_checkpoint': None, 'unc_threshold': 0.5, 'conformal_threshold': 0.074855, 'n_action_steps': 10}\\n[eval] Mode: vla_only, benchmark: object\\n[eval] max_steps set to 280 for benchmark object\\n[eval] Loading SmolVLA from /root/autodl-tmp/models/smolvla_libero/...\\nLoading  /root/autodl-tmp/models/SmolVLM2-500M-Video-Instruct weights ...\\n[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\n\\rLoading weights:   0%|          | 0/489 [00:00<?, ?it/s]\\rLoading weights:  36%|███▌      | 176/489 [00:00<00:00, 1751.78it/s]\\rLoading weights:  73%|███████▎  | 358/489 [00:00<00:00, 1790.87it/s]\\rLoading weights: 100%|██████████| 489/489 [00:00<00:00, 1881.08it/s]\\nReducing the number of VLM layers to 16 ...\\nLoading weights from local directory\\n[eval] Loading LIBERO object environments...\\n[info] using task orders [0, 1, 2, 3, 4, 5, 6, 7, 8, 9]\\n[eval] 10 tasks loaded.\\n  pick_up_the_alphabet_soup_and_place_it_in_the_basket: rollout 5/20, success so far: 4/5\\n  pick_up_the_alphabet_soup_and_place_it_in_the_basket: rollout 10/20, success so far: 7/10\\n  pick_up_the_alphabet_soup_and_place_it_in_the_basket: rollout 15/20, success so far: 11/15\\n  pick_up_the_alphabet_soup_and_place_it_in_the_basket: rollout 20/20, success so far: 15/20\\n[pick_up_the_alphabet_soup_and_place_it_in_the_basket] success rate: 75.0%
…[truncated 4471 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-23T10:04:56.359786+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"calibrate_crm_signal.log\\ncrm_magnitude_calibration.json\\neval-adaptive-k-spatial-p25-seed44.log\\neval-adaptive-k-spatial-p75-seed44.log\\neval-adaptive-k-spatial-p90-seed42.log\\neval-adaptive-k-spatial-p90-seed44-bjb2.log\\neval-adaptive-unc-head-object-seed42.log\\neval-adaptive-unc-head-object-seed43.log\\neval-adaptive-unc-head-object-seed44.log\\neval-crm-k1-object-seed42-plan702-r2.log\\neval-crm-k1-object-seed42-plan702.log\\neval-crm-k1-object-seed43-plan702-r2.log\\neval-crm-k1-object-seed43-plan702.log\\neval-crm-k1-object-seed44-plan702-r2.log\\neval-crm-k1-object-seed44-plan702.log\\neval-crm-object-k20-seed44.log\\neval-crm-spatial-k10-seed49.log\\neval-goal-vla-only-wrapper-s42.log\\neval-latency-profiling-v1.log\\neval-object-vla-only-wrapper-s42-r2.log\\neval-object-vla-only-wrapper-s43-r2.log\\neval-object-vla-only-wrapper-s44-r2.log\\neval-obs-only-object-norm003-seed43.log\\neval-obs-only-object-norm003-seed44.log\\neval-obs-only-object-norm005-seed43.log\\neval-obs-only-object-norm02-k20-seed42.log\\neval-obs-only-object-norm02-k20-seed43.log\\neval-obs-only-object-norm02-k20-seed44.log\\neval-obs-only-object-norm02-seed43-r3.log\\neval-obs-only-spatial-norm02-seed42-r2.log\\neval-obs-only-spatial-norm02-seed42.log\\neval-obs-only-spatial-norm02-seed49.log\\neval-random-selection-object-seed44.log\\neval-supp-goal-adapt-tau025-s42.log\\neval-supp-goal-crm005-s42.log\\neval-supp-goal-reconvla-s42.log\\neval-supp-k2mean-object-s42.log\\neval-supp-k2mean-spatial-s42.log\\neval-supp-obj-adapt-s42-r2.log\\neval-supp-obj-adapt-tau025-s42.log\\neval-supp-obj-reconvla-s42.log\\neval-supp-obj-reconvla-s43.log\\neval-vla-only-goal-seed47.log\\neval-vla-only-spatial-seed48.log\\neval_adaptive_k_p25_seed43.json\\neval_adaptive_k_p50_seed42.json\\neval_adaptive_k_p75_seed42.json\\neval_adaptive_k_p75_seed43.json\\neval_adaptive_k_p90_seed43.json\\neval_adaptive_k_p90_seed44.json\\neval_adaptive_k_spa
…[truncated 6654 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 7 · 2026-05-23T10:04:56.360111+00:00_

实验已完成。结果如下：

## Overall

**Success Rate: 79.5% (159/200)** — mode: vla_only, K=2, baseline_mode=mean

## Per-Task Results

| Task | SR | Successes/Rollouts |
|------|----|--------------------|
| alphabet_soup | 75.0% | 15/20 |
| cream_cheese | 70.0% | 14/20 |
| salad_dressing | 85.0% | 17/20 |
| bbq_sauce | 90.0% | 18/20 |
| ketchup | 95.0% | 19/20 |
| tomato_sauce | 85.0% | 17/20 |
| butter | 60.0% | 12/20 |
| milk | 70.0% | 14/20 |
| chocolate_pudding | 70.0% | 14/20 |
| orange_juice | 95.0% | 19/20 |

## 对比

| Method | Object s42 |
|--------|-----------|
| VLA-only | 79.0% |
| K=2 mean (本实验) | **79.5%** |
| CRM | 77.0% |
| Reconvla | 79.0% |

K=2 mean baseline 略高于 VLA-only 0.5pp，基本持平。JSON 结果已保存到 `logs/eval_object_vla_only_seed42.json`。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_analyze_eval-supp-k2mean-object-s42_20260523T100431"
}
```

</details>

---

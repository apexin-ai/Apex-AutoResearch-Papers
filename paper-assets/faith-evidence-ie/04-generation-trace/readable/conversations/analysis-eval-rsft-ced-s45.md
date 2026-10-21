# analysis eval rsft ced s45

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 13
- **Recorded user turns:** 0
- **Tool calls:** 6
- **Original source:** `logs/chats/worker_analysis_eval_rsft_ced_s45_20260516T042335.jsonl`
- **Structured JSON:** [`0d3b53152a267288f8e8.json`](../../sessions/0d/0d3b53152a267288f8e8.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

13 recorded events

### Tool call

_source line 1 · 2026-05-16T04:24:16.169624+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__update_registry",
  "max_results": "2"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__update_registry",
    "max_results": "2"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-16T04:24:16.170058+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-16T04:24:16.170284+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls -la /root/autodl-tmp/eval_results/rsft_ced_s45/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "rtx5090-4x",
    "command": "ls -la /root/autodl-tmp/eval_results/rsft_ced_s45/",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-16T04:24:16.170440+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "tail -20 /root/runs/faith-evidence-ie/eval_rsft_ced_s45.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "rtx5090-4x",
    "command": "tail -20 /root/runs/faith-evidence-ie/eval_rsft_ced_s45.log",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-16T04:24:16.170585+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"total 6644\\ndrwxr-xr-x  2 root root      62 May 16 12:21 .\\ndrwxr-xr-x 50 root root    4096 May 16 12:18 ..\\n-rw-r--r--  1 root root    1507 May 16 12:21 metrics.json\\n-rw-r--r--  1 root root 6793186 May 16 12:21 predictions.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.2}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-16T04:24:16.170798+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"2026-05-16 09:30:58,943 INFO Processed 12275 relation samples from 998 documents (5445 samples without hard negatives)\\n2026-05-16 09:30:59,336 INFO Prepared 985 eval documents, 12275 gold triples\\n\\rInference:   0%|          | 0/247 [00:00<?, ?it/s]The following generation flags are not valid and may be ignored: ['temperature', 'top_p', 'top_k']. Set `TRANSFORMERS_VERBOSITY=info` for more details.\\n\\rInference:   0%|          | 1/247 [00:47<3:14:15, 47.38s/it]\\rInference:   1%|          | 2/247 [01:23<2:45:28, 40.52s/it]\\rInference:   1%|          | 3/247 [02:09<2:56:13, 43.33s/it]\\rInference:   2%|▏         | 4/247 [02:56<3:01:35, 44.84s/it]\\rInference:   2%|▏         | 5/247 [03:28<2:41:23, 40.02s/it]\\rInference:   2%|▏         | 6/247 [04:15<2:50:04, 42.34s/it]\\rInference:   3%|▎         | 7/247 [05:01<2:54:42, 43.68s/it]\\rInference:   3%|▎         | 8/247 [05:48<2:58:20, 44.77s/it]\\rInference:   4%|▎         | 9/247 [06:02<2:19:15, 35.11s/it]\\rInference:   4%|▍         | 10/247 [06:49<2:32:53, 38.71s/it]\\rInference:   4%|▍         | 11/247 [07:29<2:33:39, 39.07s/it]\\rInference:   5%|▍         | 12/247 [08:15<2:41:45, 41.30s/it]\\rInference:   5%|▌         | 13/247 [08:34<2:14:26, 34.47s/it]\\rInference:   6%|▌         | 14/247 [09:01<2:05:37, 32.35s/it]\\rInference:   6%|▌         | 15/247 [09:48<2:21:32, 36.60s/it]\\rInference:   6%|▋         | 16/247 [10:33<2:30:25, 39.07s/it]\\rInference:   7%|▋         | 17/247 [11:19<2:38:31, 41.36s/it]\\rInference:   7%|▋         | 18/247 [12:07<2:44:47, 43.18s/it]\\rInference:   8%|▊         | 19/247 [12:54<2:48:20, 44.30s/it]\\rInference:   8%|▊         | 20/247 [13:40<2:50:15, 45.00s/it]\\rInference:   9%|▊         | 21/247 [14:27<2:51:30, 45.54s/it]\\rInference:   9%|▉         | 22/247 [15:04<2:41:13, 42.99s/it]\\rInference:   9%|▉         | 23/247 [15:52<2:45:30, 44.33s/it]\\rInference:  10%|▉         | 24/247 [16:38<2:47:14, 45.00s/it]\\rInferen
…[truncated 6465 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-16T04:24:16.171016+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/eval_results/rsft_ced_s45/metrics.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "rtx5090-4x",
    "command": "cat /root/autodl-tmp/eval_results/rsft_ced_s45/metrics.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-16T04:24:16.171263+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"precision\\\": 0.47181834500089753,\\n  \\\"recall\\\": 0.4326392889474117,\\n  \\\"f1\\\": 0.4513802429914567,\\n  \\\"ign_precision\\\": 0.44871672550329167,\\n  \\\"ign_recall\\\": 0.43461787265502266,\\n  \\\"ign_f1\\\": 0.4415547835883955,\\n  \\\"tp\\\": 5257,\\n  \\\"pred_count\\\": 11142,\\n  \\\"gold_count\\\": 12151,\\n  \\\"evi_precision\\\": 0.8209711336264577,\\n  \\\"evi_recall\\\": 0.8138917843267317,\\n  \\\"evi_f1\\\": 0.8174161313347609,\\n  \\\"n_evaluated\\\": 15185,\\n  \\\"edcr\\\": 0.6549909620405704,\\n  \\\"n_distractor_citations\\\": 16306,\\n  \\\"n_total_citations\\\": 24895,\\n  \\\"evi_joint_precision\\\": 0.36463215258855586,\\n  \\\"evi_joint_recall\\\": 0.347385909350501,\\n  \\\"evi_f1_joint\\\": 0.35580016484539095,\\n  \\\"evi_tp\\\": 6691,\\n  \\\"evi_pred_total\\\": 18350,\\n  \\\"evi_gold_total\\\": 19261,\\n  \\\"format_compliance_rate\\\": 1.0,\\n  \\\"field_compliance_rate\\\": 0.7796954314720812,\\n  \\\"evidence_format_rate\\\": 0.7796954314720812,\\n  \\\"n_total\\\": 985,\\n  \\\"n_parseable\\\": 985,\\n  \\\"n_field_complete\\\": 768,\\n  \\\"n_evidence_valid\\\": 768,\\n  \\\"n_documents\\\": 985,\\n  \\\"n_predictions\\\": 15307,\\n  \\\"n_truncated\\\": 206,\\n  \\\"n_format_ok\\\": 985,\\n  \\\"format_ok_rate\\\": 1.0,\\n  \\\"inference_time_seconds\\\": 10211.6,\\n  \\\"config\\\": {\\n    \\\"model_path\\\": \\\"/root/autodl-tmp/rsft_output_ced_s45/checkpoint-510\\\",\\n    \\\"base_model\\\": \\\"/root/autodl-tmp/models/Qwen3-4B\\\",\\n    \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output\\\",\\n    \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\",\\n    \\\"output_dir\\\": \\\"/root/autodl-tmp/eval_results/rsft_ced_s45\\\",\\n    \\\"batch_size\\\": 4,\\n    \\\"max_new_tokens\\\": 1024,\\n    \\\"split\\\": \\\"dev\\\",\\n    \\\"seed\\\": 45,\\n    \\\"no_evidence\\\": false,\\n    \\\"quantize\\\": false\\n  }\\n}\", \"stderr\": \"\",
…[truncated 83 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-16T04:24:16.171457+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_rsft_ced_s45",
  "field": "metrics",
  "value": "{'rel_f1': 0.4514, 'rel_ign_f1': 0.4416, 'evi_f1': 0.8174, 'rel_p': 0.4718, 'rel_r': 0.4326, 'edcr': 0.655, 'evi_f1_joint': 0.3558, 'n_truncated': 206, 'format_ok_rate': 1}",
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_rsft_ced_s45",
    "field": "metrics",
    "value": "{'rel_f1': 0.4514, 'rel_ign_f1': 0.4416, 'evi_f1': 0.8174, 'rel_p': 0.4718, 'rel_r': 0.4326, 'edcr': 0.655, 'evi_f1_joint': 0.3558, 'n_truncated': 206, 'format_ok_rate': 1}",
    "project": "faith-evidence-ie"
  }
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-16T04:24:16.171604+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_rsft_ced_s45",
  "field": "status",
  "value": "DONE",
  "project": "faith-evidence-ie",
  "spec": "{'checkpoint_path': '/root/autodl-tmp/rsft_output_ced_s45/checkpoint-510', 'log_path': '/root/runs/faith-evidence-ie/eval_rsft_ced_s45.log'}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_rsft_ced_s45",
    "field": "status",
    "value": "DONE",
    "project": "faith-evidence-ie",
    "spec": "{'checkpoint_path': '/root/autodl-tmp/rsft_output_ced_s45/checkpoint-510', 'log_path': '/root/runs/faith-evidence-ie/eval_rsft_ced_s45.log'}"
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-16T04:24:16.171797+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_rsft_ced_s45\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:30:34.036Z\", \"updated_at\": \"2026-05-16T04:24:04.336Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s45/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 45 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s45 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"283838\", \"log_path\": \"~/runs/faith-evidence-ie/eval_rsft_ced_s45.log\", \"submitted_at\": \"2026-05-16T01:30:48.081Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 10350.6, \"gpu_hours\": 2.88}, \"hypothesis\": \"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"parent\": \"rsft_ced_s45_train_r4\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T01:30:45.945Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s45/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-t
…[truncated 993 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-16T04:24:16.172019+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_rsft_ced_s45\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:30:34.036Z\", \"updated_at\": \"2026-05-16T04:24:06.094Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s45/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 45 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s45 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"283838\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_rsft_ced_s45.log\", \"submitted_at\": \"2026-05-16T01:30:48.081Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 10350.6, \"gpu_hours\": 2.88, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_ced_s45/checkpoint-510\"}, \"hypothesis\": \"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"parent\": \"rsft_ced_s45_train_r4\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T01:30:45.945Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s45/checkpoint-510 --base_model /root/autodl-tmp/mo
…[truncated 1126 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 13 · 2026-05-16T04:24:16.172216+00:00_

**eval_rsft_ced_s45 完成，registry 已更新。**

关键 metrics：

| 指标 | 值 |
|------|-----|
| **rel_f1** | 0.4514 |
| **rel_ign_f1** | 0.4416 |
| **evi_f1** | 0.8174 |
| rel_p | 0.4718 |
| rel_r | 0.4326 |
| edcr | 0.655 |
| format_ok | 100% |

**对比 flat-NLI RSFT s45**（0.4876）：CED s45 的 rel_f1 = 0.4514，低 3.6 个百分点。这与 CED 系列整体趋势一致——CED RSFT 在 rel_f1 上落后于 flat-NLI RSFT，但 evi_f1（0.8174）和 edcr（0.655）是 CED 协议的额外产出。

CED s45 的 0.4514 落在预期范围（0.43-0.47）内，结果合理。等 s42/s43/s44 全部到齐后可做配对 t-test。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_analysis_eval_rsft_ced_s45_20260516T042335"
}
```

</details>

---

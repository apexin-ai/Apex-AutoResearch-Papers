# analysis eval humaneval sft standard 20 1p5b 2048

**How Pruning Criteria Shape Post-RLVR Recovery: A Controlled Study of Structured MLP Pruning in a Reasoning LLM** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 19
- **Recorded user turns:** 0
- **Tool calls:** 9
- **Original source:** `logs/chats/worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322.jsonl`
- **Structured JSON:** [`68e02a89537fa6980838.json`](../../sessions/68/68e02a89537fa6980838.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

19 recorded events

### Tool call

_source line 1 · 2026-05-19T13:54:14.849785+00:00_

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
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
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

_source line 2 · 2026-05-19T13:54:14.850120+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-19T13:54:14.850309+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westb-23072",
  "command": "cat /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westb-23072",
    "command": "cat /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-19T13:54:14.850458+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westb-23072",
  "command": "tail -50 /root/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westb-23072",
    "command": "tail -50 /root/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-19T13:54:14.850842+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model_path\\\": \\\"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\\\",\\n  \\\"benchmark\\\": \\\"HumanEval\\\",\\n  \\\"pass_at_1\\\": 0.006097560975609756,\\n  \\\"stderr\\\": 0.006078942425350188,\\n  \\\"n_passed\\\": 1,\\n  \\\"n_total\\\": 164,\\n  \\\"examples\\\": [\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/0\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/1\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/2\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 90\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/3\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/4\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/5\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/6\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/7\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/8\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/9\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/10\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\": \\\"HumanEval/11\\\",\\n      \\\"passed\\\": false,\\n      \\\"completion_length\\\": 2048\\n    },\\n    {\\n      \\\"task_id\\\"
…[truncated 8883 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-19T13:54:14.851111+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"2026-05-19 20:23:36,093 [INFO] Loading model from /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\\n2026-05-19 20:23:36,751 [INFO] Non-uniform MLP detected: intermediate_size range [3738, 8960]\\n2026-05-19 20:24:03,433 [INFO] Loading HumanEval dataset...\\n'[Errno 101] Network is unreachable' thrown while requesting HEAD https://huggingface.co/datasets/openai/openai_humaneval/resolve/7dce6050a7d6d172f3cc5c32aa97f52fa1a2e544/openai_humaneval.py\\n2026-05-19 20:25:23,623 [WARNING] '[Errno 101] Network is unreachable' thrown while requesting HEAD https://huggingface.co/datasets/openai/openai_humaneval/resolve/7dce6050a7d6d172f3cc5c32aa97f52fa1a2e544/openai_humaneval.py\\nRetrying in 1s [Retry 1/5].\\n2026-05-19 20:25:23,624 [WARNING] Retrying in 1s [Retry 1/5].\\nUsing the latest cached version of the dataset since openai/openai_humaneval couldn't be found on the Hugging Face Hub\\n2026-05-19 20:25:24,626 [WARNING] Using the latest cached version of the dataset since openai/openai_humaneval couldn't be found on the Hugging Face Hub\\nFound the latest cached dataset configuration 'openai_humaneval' at /root/.cache/huggingface/datasets/openai___openai_humaneval/openai_humaneval/0.0.0/7dce6050a7d6d172f3cc5c32aa97f52fa1a2e544 (last modified on Sun May 17 12:28:27 2026).\\n2026-05-19 20:25:24,628 [WARNING] Found the latest cached dataset configuration 'openai_humaneval' at /root/.cache/huggingface/datasets/openai___openai_humaneval/openai_humaneval/0.0.0/7dce6050a7d6d172f3cc5c32aa97f52fa1a2e544 (last modified on Sun May 17 12:28:27 2026).\\n2026-05-19 20:25:24,689 [INFO] Loaded 164 problems\\n2026-05-19 20:25:24,689 [INFO] Evaluating on 164 problems\\n\\rHumanEval eval:   0%|          | 0/164 [00:00<?, ?it/s]\\rHumanEval eval:   1%|          | 1/164 [00:35<1:35:46, 35.25s/it]\\rHumanEval eval:   1%|          | 2/164 [01:10<1:34:24, 34.97s/it]\\rHumanEval eval:   2%|▏         | 3/164 [01:11<52:30, 19.
…[truncated 6417 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-19T13:54:14.851334+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__update_registry",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__update_registry",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-19T13:54:14.851481+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-19T13:54:14.851609+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
  "field": "metrics",
  "value": "{'pass_at_1': 0.0061, 'n_correct': 1, 'n_total': 164, 'stderr': 0.0061}",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
    "field": "metrics",
    "value": "{'pass_at_1': 0.0061, 'n_correct': 1, 'n_total': 164, 'stderr': 0.0061}",
    "project": "recovery_aware_struct_prune"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-19T13:54:14.851778+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_humaneval_sft_standard_20_1p5b_2048\", \"experiment\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-19T13:53:56.667Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json\\\"\", \"server\": \"westb-23072\", \"gpu\": [\"cuda:0\"], \"pid\": \"890564\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"submitted_at\": \"2026-05-19T12:23:31.889Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"eval_data\": \"HumanEval (164 problems, pass@1, max_new_tokens=2048)\", \"data_path\": \"HumanEval\", \"data_count\": 164, \"model_name\": \"sft_standard_20_1p5b\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:50:34.259Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:50:39.347512+00:00\"}]}, \"metrics\": {\"pass_at_1\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"stderr\": 0.0061}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.0223}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-19T13:54:14.851928+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
  "field": "checkpoint_path",
  "value": "/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
    "field": "checkpoint_path",
    "value": "/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b",
    "project": "recovery_aware_struct_prune"
  }
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-19T13:54:14.852058+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
  "field": "log_path",
  "value": "~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
    "field": "log_path",
    "value": "~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log",
    "project": "recovery_aware_struct_prune"
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-19T13:54:14.852211+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_humaneval_sft_standard_20_1p5b_2048\", \"experiment\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-19T13:53:58.145Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json\\\"\", \"server\": \"westb-23072\", \"gpu\": [\"cuda:0\"], \"pid\": \"890564\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"submitted_at\": \"2026-05-19T12:23:31.889Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"eval_data\": \"HumanEval (164 problems, pass@1, max_new_tokens=2048)\", \"data_path\": \"HumanEval\", \"data_count\": 164, \"model_name\": \"sft_standard_20_1p5b\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:50:34.259Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:50:39.347512+00:00\"}]}, \"metrics\": {\"pass_at_1\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"stderr\": 0.0061}, \"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.0908}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-19T13:54:14.852410+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_humaneval_sft_standard_20_1p5b_2048\", \"experiment\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-19T13:53:59.775Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json\\\"\", \"server\": \"westb-23072\", \"gpu\": [\"cuda:0\"], \"pid\": \"890564\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"submitted_at\": \"2026-05-19T12:23:31.889Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"eval_data\": \"HumanEval (164 problems, pass@1, max_new_tokens=2048)\", \"data_path\": \"HumanEval\", \"data_count\": 164, \"model_name\": \"sft_standard_20_1p5b\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:50:34.259Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:50:39.347512+00:00\"}]}, \"metrics\": {\"pass_at_1\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"stderr\": 0.0061}, \"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.6104}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-19T13:54:14.852553+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
  "field": "conclusion",
  "value": "success",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
    "field": "conclusion",
    "value": "success",
    "project": "recovery_aware_struct_prune"
  }
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-19T13:54:14.852680+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
  "field": "status",
  "value": "DONE",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_humaneval_sft_standard_20_1p5b_2048",
    "field": "status",
    "value": "DONE",
    "project": "recovery_aware_struct_prune"
  }
}
```

</details>

---

### Tool result

_source line 17 · 2026-05-19T13:54:14.852838+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_humaneval_sft_standard_20_1p5b_2048\", \"experiment\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-19T13:54:05.390Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json\\\"\", \"server\": \"westb-23072\", \"gpu\": [\"cuda:0\"], \"pid\": \"890564\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"submitted_at\": \"2026-05-19T12:23:31.889Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"eval_data\": \"HumanEval (164 problems, pass@1, max_new_tokens=2048)\", \"data_path\": \"HumanEval\", \"data_count\": 164, \"model_name\": \"sft_standard_20_1p5b\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:50:34.259Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:50:39.347512+00:00\"}]}, \"metrics\": {\"pass_at_1\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"stderr\": 0.0061}, \"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"conclusion\": \"success\"}}, \"error\": null, \"metadata\": {\"elapsed_s
…[truncated 20 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-19T13:54:14.853046+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_humaneval_sft_standard_20_1p5b_2048\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-19T13:54:06.392Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_standard_20_1p5b_2048.json\\\"\", \"server\": \"westb-23072\", \"gpu\": [\"cuda:0\"], \"pid\": \"890564\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"submitted_at\": \"2026-05-19T12:23:31.889Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"eval_data\": \"HumanEval (164 problems, pass@1, max_new_tokens=2048)\", \"data_path\": \"HumanEval\", \"data_count\": 164, \"model_name\": \"sft_standard_20_1p5b\", \"seed\": 42, \"wall_clock_seconds\": 5434.5, \"gpu_hours\": 1.51}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:50:34.259Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:50:39.347512+00:00\"}]}, \"metrics\": {\"pass_at_1\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"stderr\": 0.0061}, \"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b\", \"log_path\": \"~/runs/recovery_aware_struct_prune/eval_humaneval_sft_standard_20_1p5b_2048.log\", \"conclusion\": \"success\
…[truncated 167 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 19 · 2026-05-19T13:54:14.853242+00:00_

Registry 已更新为 DONE/success。

## Metrics 摘要

| 指标 | 值 |
|------|-----|
| **pass@1** | 0.0061 (0.61%) |
| **n_correct** | 1 |
| **n_total** | 164 |
| **stderr** | ±0.0061 |
| **唯一通过** | HumanEval/30 |
| **运行时间** | ~1h23m |
| **退出码** | 0 (正常完成) |

Standard SFT 1.5B 在 HumanEval 上 1/164，与 CKA-only SFT (也是 1/164) 持平。符合预期——1.5B 剪枝模型在 code generation 上本身能力极弱，两种 SFT 方法无显著差异。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_analysis_eval_humaneval_sft_standard_20_1p5b_2048_20260519T135322"
}
```

</details>

---

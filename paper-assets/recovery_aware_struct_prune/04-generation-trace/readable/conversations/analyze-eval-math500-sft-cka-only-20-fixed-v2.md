# analyze eval math500 sft cka only 20 fixed v2

**How Pruning Criteria Shape Post-RLVR Recovery: A Controlled Study of Structured MLP Pruning in a Reasoning LLM** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 7
- **Recorded user turns:** 0
- **Tool calls:** 3
- **Original source:** `logs/chats/worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615.jsonl`
- **Structured JSON:** [`1f827245a83ec8c404e8.json`](../../sessions/1f/1f827245a83ec8c404e8.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

7 recorded events

### Tool call

_source line 1 · 2026-05-23T19:36:48.578397+00:00_

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
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615",
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

_source line 2 · 2026-05-23T19:36:48.578715+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-23T19:36:48.578883+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westb-23072",
  "command": "cat /root/autodl-tmp/recovery_aware_struct_prune/results/eval_math500_sft_cka_only_20_fixed.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westb-23072",
    "command": "cat /root/autodl-tmp/recovery_aware_struct_prune/results/eval_math500_sft_cka_only_20_fixed.json",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-23T19:36:48.579022+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westb-23072",
  "command": "tail -50 /root/runs/recovery_aware_struct_prune/eval_math500_sft_cka_only_20_fixed_v2.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westb-23072",
    "command": "tail -50 /root/runs/recovery_aware_struct_prune/eval_math500_sft_cka_only_20_fixed_v2.log",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-23T19:36:48.579400+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model_path\\\": \\\"/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20\\\",\\n  \\\"benchmark\\\": \\\"MATH-500\\\",\\n  \\\"accuracy\\\": 0.274,\\n  \\\"stderr\\\": 0.01994612744369192,\\n  \\\"n_correct\\\": 137,\\n  \\\"n_total\\\": 500,\\n  \\\"eos_stats\\\": {\\n    \\\"natural_eos\\\": 384,\\n    \\\"truncated\\\": 116,\\n    \\\"avg_response_length\\\": 673.278\\n  },\\n  \\\"examples\\\": [\\n    {\\n      \\\"problem\\\": \\\"Convert the point $(0,3)$ in rectangular coordinates to polar coordinates.  Enter your answer in the form $(r,\\\\\\\\theta),$ where $r > 0$ and $0 \\\\\\\\le \\\\\\\\theta < 2 \\\\\\\\pi.$\\\",\\n      \\\"gold_answer\\\": \\\"\\\\\\\\left( 3, \\\\\\\\frac{\\\\\\\\pi}{2} \\\\\\\\right)\\\",\\n      \\\"pred_answer\\\": \\\"0\\\",\\n      \\\"correct\\\": false,\\n      \\\"response_length\\\": 99\\n    },\\n    {\\n      \\\"problem\\\": \\\"Define\\\\n\\\\\\\\[p = \\\\\\\\sum_{k = 1}^\\\\\\\\infty \\\\\\\\frac{1}{k^2} \\\\\\\\quad \\\\\\\\text{and} \\\\\\\\quad q = \\\\\\\\sum_{k = 1}^\\\\\\\\infty \\\\\\\\frac{1}{k^3}.\\\\\\\\]Find a way to write\\\\n\\\\\\\\[\\\\\\\\sum_{j = 1}^\\\\\\\\infty \\\\\\\\sum_{k = 1}^\\\\\\\\infty \\\\\\\\frac{1}{(j + k)^3}\\\\\\\\]in term\\\",\\n      \\\"gold_answer\\\": \\\"p - q\\\",\\n      \\\"pred_answer\\\": \\\"36\\\",\\n      \\\"correct\\\": false,\\n      \\\"response_length\\\": 2048\\n    },\\n    {\\n      \\\"problem\\\": \\\"If $f(x) = \\\\\\\\frac{3x-2}{x-2}$, what is the value of $f(-2) +f(-1)+f(0)$? Express your answer as a common fraction.\\\",\\n      \\\"gold_answer\\\": \\\"\\\\\\\\frac{14}{3}\\\",\\n      \\\"pred_answer\\\": \\\"\\\\\\\\dfrac{14}{3}\\\",\\n      \\\"correct\\\": true,\\n      \\\"response_length\\\": 2048\\n    },\\n    {\\n      \\\"problem\\\": \\\"How many positive whole-number divisors does 196 have?\\\",\\n      \\\"gold_answer\\\": \\\"9\\\",\\n      \\\"pred_answer\\\": \\\"8\\\",
…[truncated 8522 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-23T19:36:48.579688+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"2026-05-23 23:45:26,920 [INFO] Loading model from /root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20\\n2026-05-23 23:45:27,712 [INFO] Non-uniform MLP detected: intermediate_size range [8128, 18944]\\n2026-05-23 23:47:08,752 [INFO] Model device after .cuda(): cuda:0 (CUDA_VISIBLE_DEVICES=1)\\n2026-05-23 23:47:08,753 [INFO] Loading MATH-500 dataset...\\n'[Errno 101] Network is unreachable' thrown while requesting HEAD https://huggingface.co/datasets/HuggingFaceH4/MATH-500/resolve/6e4ed1a2a79af7d8630a6b768ec859cb5af4d3be/MATH-500.py\\n2026-05-23 23:48:28,964 [WARNING] '[Errno 101] Network is unreachable' thrown while requesting HEAD https://huggingface.co/datasets/HuggingFaceH4/MATH-500/resolve/6e4ed1a2a79af7d8630a6b768ec859cb5af4d3be/MATH-500.py\\nRetrying in 1s [Retry 1/5].\\n2026-05-23 23:48:28,965 [WARNING] Retrying in 1s [Retry 1/5].\\nUsing the latest cached version of the dataset since HuggingFaceH4/MATH-500 couldn't be found on the Hugging Face Hub\\n2026-05-23 23:48:29,967 [WARNING] Using the latest cached version of the dataset since HuggingFaceH4/MATH-500 couldn't be found on the Hugging Face Hub\\nFound the latest cached dataset configuration 'default' at /root/.cache/huggingface/datasets/HuggingFaceH4___math-500/default/0.0.0/6e4ed1a2a79af7d8630a6b768ec859cb5af4d3be (last modified on Sun May 17 12:28:31 2026).\\n2026-05-23 23:48:29,969 [WARNING] Found the latest cached dataset configuration 'default' at /root/.cache/huggingface/datasets/HuggingFaceH4___math-500/default/0.0.0/6e4ed1a2a79af7d8630a6b768ec859cb5af4d3be (last modified on Sun May 17 12:28:31 2026).\\n2026-05-23 23:48:30,042 [INFO] Loaded 500 problems\\n2026-05-23 23:48:30,042 [INFO] Evaluating on 500 problems\\n\\rMATH-500 eval:   0%|          | 0/500 [00:00<?, ?it/s]\\rMATH-500 eval:   0%|          | 1/500 [00:02<17:48,  2.14s/it]\\rMATH-500 eval:   0%|          | 2/500 [01:41<8:11:21, 59.20s/it]\\rMATH-500 eval:   1%|          |
…[truncated 6446 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 7 · 2026-05-23T19:36:48.579909+00:00_

## eval_math500_sft_cka_only_20_fixed_v2 结果

| 指标 | 值 |
|------|-----|
| **MATH-500 Accuracy** | **27.4%** (137/500) |
| stderr | ±1.99% |
| 总样本数 | 500 |
| 正确数 | 137 |
| natural_eos | 384 (76.8%) |
| truncated | 116 (23.2%) |
| avg_response_length | 673.3 tokens |
| 运行耗时 | ~3h45m |
| 退出码 | 0，无 error/exception |

**运行正常完成。** 日志最后一行 `EXIT_CODE=0`，无报错。HF 数据集网络不可达但自动回退到缓存版本，不影响结果。

**与旧结果对比：** 修复后 27.4% vs 旧脚本 26.8%，差异仅 0.6 个百分点，在 stderr (±2%) 范围内。说明旧脚本的 bug 对这个模型的影响不大，结果基本一致。27.4% 为修正后的可信值，应替换旧数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_analyze_eval_math500_sft_cka_only_20_fixed_v2_20260523T193615"
}
```

</details>

---

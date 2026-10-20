# eval humaneval sft rasp 2048

**How Pruning Criteria Shape Post-RLVR Recovery: A Controlled Study of Structured MLP Pruning in a Reasoning LLM** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 25
- **Recorded user turns:** 0
- **Tool calls:** 12
- **Original source:** `logs/chats/worker_eval_humaneval_sft_rasp_2048_20260519T154552.jsonl`
- **Structured JSON:** [`95c84d289bb83e2a6b36.json`](../../sessions/95/95c84d289bb83e2a6b36.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

25 recorded events

### Tool call

_source line 1 · 2026-05-19T15:47:30.998895+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__read_registry",
  "max_results": "4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__read_registry",
    "max_results": "4"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-19T15:47:30.999230+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-19T15:47:30.999443+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "nvidia-smi -i 0 --query-compute-apps=pid,used_memory --format=csv,noheader",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "nvidia-smi -i 0 --query-compute-apps=pid,used_memory --format=csv,noheader",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-19T15:47:30.999584+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "ls -la /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "ls -la /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20/",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-19T15:47:30.999713+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "ls /root/recovery_aware_struct_prune/src/eval_humaneval*",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "ls /root/recovery_aware_struct_prune/src/eval_humaneval*",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-19T15:47:30.999847+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.26}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-19T15:47:30.999974+00:00_

{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"ls: cannot access '/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20/': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.54}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-19T15:47:31.000097+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/recovery_aware_struct_prune/src/eval_humaneval.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.99}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-19T15:47:31.000236+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "find /root/autodl-tmp/recovery_aware_struct_prune/ -maxdepth 2 -type d -name \"*sft_rasp*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "find /root/autodl-tmp/recovery_aware_struct_prune/ -maxdepth 2 -type d -name \"*sft_rasp*\"",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-19T15:47:31.000388+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd\\n/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_25\\n/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_rlvr_20_qwen_math\\n/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-19T15:47:31.000520+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "find /root/autodl-tmp/ -maxdepth 3 -type d -name \"*sft_rasp*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "find /root/autodl-tmp/ -maxdepth 3 -type d -name \"*sft_rasp*\"",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-19T15:47:31.000647+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd\\n/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_25\\n/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_rlvr_20_qwen_math\\n/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.73}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-19T15:47:31.000784+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "ls -la /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "ls -la /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd/",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-19T15:47:31.000902+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "head -80 /root/recovery_aware_struct_prune/src/eval_humaneval.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "head -80 /root/recovery_aware_struct_prune/src/eval_humaneval.py",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-19T15:47:31.001030+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"total 12046280\\ndrwxr-xr-x  2 root root        4096 May 16 01:31 .\\ndrwxr-xr-x 48 root root        4096 May 19 22:23 ..\\n-rw-r--r--  1 root root        2246 May 16 01:31 chat_template.jinja\\n-rw-r--r--  1 root root        1730 May 16 01:55 config.json\\n-rw-r--r--  1 root root         240 May 16 01:31 generation_config.json\\n-rw-r--r--  1 root root 12323931224 May 16 01:31 model.safetensors\\n-rw-r--r--  1 root root    11421907 May 16 01:31 tokenizer.json\\n-rw-r--r--  1 root root         420 May 16 01:31 tokenizer_config.json\\n-rw-r--r--  1 root root        5777 May 16 01:31 training_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-19T15:47:31.001200+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"HumanEval Evaluation.\\\"\\\"\\\"\\n\\nimport argparse\\nfrom datetime import datetime\\nimport json\\nimport logging\\nimport math\\nimport os\\nimport random\\nimport re\\nimport sys\\nimport subprocess\\nimport tempfile\\n\\nimport numpy as np\\nimport torch\\nfrom datasets import load_dataset\\nfrom transformers import AutoTokenizer\\nfrom model_utils import load_pruned_model\\nfrom tqdm import tqdm\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef set_seed(seed):\\n    random.seed(seed)\\n    np.random.seed(seed)\\n    torch.manual_seed(seed)\\n    torch.cuda.manual_seed_all(seed)\\n\\n\\ndef extract_code_block(text):\\n    clean = re.sub(r\\\"&lt;think>.*?&lt;/think>\\\", \\\"\\\", text, flags=re.DOTALL)\\n    if not clean.strip():\\n        clean = text\\n    code_blocks = re.findall(r\\\"```python\\\\s*\\\\n(.*?)```\\\", clean, re.DOTALL)\\n    if code_blocks:\\n        return code_blocks[0]\\n    code_blocks = re.findall(r\\\"```\\\\s*\\\\n(.*?)```\\\", clean, re.DOTALL)\\n    if code_blocks:\\n        return code_blocks[0]\\n    return clean\\n\\n\\ndef run_test(code, test, entry_point, timeout=10):\\n    full_code = code + \\\"\\\\n\\\" + test + f\\\"\\\\ncheck({entry_point})\\\\n\\\"\\n    with tempfile.NamedTemporaryFile(mode=\\\"w\\\", suffix=\\\".py\\\", delete=False) as f:\\n        f.write(full_code)\\n        tmp_path = f.name\\n    try:\\n        result = subprocess.run(\\n            [sys.executable, tmp_path],\\n            capture_output=True, text=True, timeout=timeout,\\n        )\\n        return result.returncode == 0, result.stderr[:500] if result.stderr else \\\"\\\"\\n    except subprocess.TimeoutExpired:\\n        return False, \\\"Timeout\\\"\\n    except Exception as e:\\n        return False, str(e)[:500]\\n    finally:\\n        try:\\n            os.unlink(tmp_path)\\n  
…[truncated 777 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-19T15:47:31.001414+00:00_

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
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
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

_source line 18 · 2026-05-19T15:47:31.001544+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-19T15:47:31.001663+00:00_

called mcp__agent-ml-research__ssh_execute

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute</summary>

```json
{
  "server": "westd-29022",
  "command": "bash -c \"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && nohup bash -c 'CUDA_VISIBLE_DEVICES=0 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.json' > /tmp/eval_humaneval_sft_rasp_20_2048_v2.log 2>&1 & echo PID=\\$!\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_execute",
  "tool_args": {
    "server": "westd-29022",
    "command": "bash -c \"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && nohup bash -c 'CUDA_VISIBLE_DEVICES=0 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.json' > /tmp/eval_humaneval_sft_rasp_20_2048_v2.log 2>&1 & echo PID=\\$!\"",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-19T15:47:31.001832+00:00_

{"result":"{\"success\": false, \"data\": {}, \"error\": \"Command did not complete within 30 seconds!\\n\\nCommand: 'bash -c \\\"source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && nohup bash -c \\\\'CUDA_VISIBLE_DEVICES=0 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.json\\\\' > /tmp/eval_humaneval_sft_rasp_20_2048_v2.log 2>&1 & echo PID=\\\\\\\\$!\\\"'\\n\\nStdout:\\n\\nPID=117053\\n\\nStderr:\\n\\n\\n\\n\", \"metadata\": {\"elapsed_seconds\": 30.43}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_execute",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-19T15:47:31.001989+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-29022",
  "command": "ps -p 117053 -o pid,cmd --no-headers",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-29022",
    "command": "ps -p 117053 -o pid,cmd --no-headers",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-19T15:47:31.002116+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"117053 bash -c source /root/miniconda3/bin/activate && cd /root/recovery_aware_struct_prune && nohup bash -c 'CUDA_VISIBLE_DEVICES=0 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.json' > /tmp/eval_humaneval_sft_rasp_20_2048_v2.log 2>&1 & echo PID=$!\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.11}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-19T15:47:31.002247+00:00_

called mcp__agent-ml-research__update_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry</summary>

```json
{
  "exp_id": "eval_humaneval_sft_rasp_20_2048_v2",
  "field": "hypothesis",
  "value": "SFT RASP 20% HumanEval pass@1 @2048. Fills RASP SFT cell in HumanEval matrix. GRPO RASP = 10.98%. If SFT RASP ≈ GRPO RASP, confirms redistribution-not-expansion pattern holds for RASP too. Compare with CKA-only SFT=GRPO=20.12%.",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__update_registry",
  "tool_args": {
    "exp_id": "eval_humaneval_sft_rasp_20_2048_v2",
    "field": "hypothesis",
    "value": "SFT RASP 20% HumanEval pass@1 @2048. Fills RASP SFT cell in HumanEval matrix. GRPO RASP = 10.98%. If SFT RASP ≈ GRPO RASP, confirms redistribution-not-expansion pattern holds for RASP too. Compare with CKA-only SFT=GRPO=20.12%.",
    "project": "recovery_aware_struct_prune"
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-19T15:47:31.002438+00:00_

{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_humaneval_sft_rasp_20_2048_v2\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:18:20.664Z\", \"updated_at\": \"2026-05-19T15:47:14.846Z\", \"hypothesis\": \"SFT RASP 20% HumanEval pass@1 @2048. Fills RASP SFT cell in HumanEval matrix. GRPO RASP = 10.98%. If SFT RASP ≈ GRPO RASP, confirms redistribution-not-expansion pattern holds for RASP too. Compare with CKA-only SFT=GRPO=20.12%.\", \"parent\": \"eval_humaneval_sft_rasp_20_2048\", \"spec\": {\"server\": \"westd-29022\", \"gpu\": \"cuda:1\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.json\", \"data_path\": \"HumanEval\", \"data_count\": 164, \"model_name\": \"sft_rasp_20_westd\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd\", \"eval_data\": \"HumanEval\", \"log_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.log\", \"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/results/humaneval_sft_rasp_20_2048_v2.json\", \"pid\": \"107932\"}, \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1037, \"stderr\": 0.0238, \"n_correct\": 17, \"n_total\": 164, \"avg_response_length\": 1253.7, \"median_response_length\": 2048}, \"completed_at\": \"2026-05-19T14:36:48.406Z\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.2289}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552",
  "tool": "mcp__agent-ml-research__update_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 25 · 2026-05-19T15:47:31.002638+00:00_

这个实验 **已经有结果了**。Registry 显示 `eval_humaneval_sft_rasp_20_2048_v2` 之前已完成：

| 指标 | 值 |
|------|-----|
| pass@1 | **10.37%** (17/164) |
| stderr | 0.0238 |
| avg_response_length | 1253.7 |
| median_response_length | 2048 (命中上限) |

之前在 cuda:1 上跑完的。我刚又在 cuda:0 上启动了一个重复进程（PID 117053），需要杀掉吗？

结果汇总对比：

| 方法 | HumanEval @2048 |
|------|----------------|
| CKA-only SFT | 20.12% (33/164) |
| CKA-only GRPO | 20.12% (33/164) |
| Standard SFT | ~16.25% (interim) |
| **RASP SFT** | **10.37% (17/164)** |
| Standard GRPO | 10.98% (18/164) |
| RASP GRPO | 10.98% (18/164) |

RASP SFT (10.37%) ≈ RASP GRPO (10.98%)，支持 redistribution-not-expansion 假设在 RASP 上也成立。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_eval_humaneval_sft_rasp_2048_20260519T154552"
}
```

</details>

---

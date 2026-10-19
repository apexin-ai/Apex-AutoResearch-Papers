# diagnose eval failures bjb1

**Knowing When Not to Correct: Adaptive Test-Time Refinement for Vision-Language-Action Models** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 13
- **Recorded user turns:** 0
- **Tool calls:** 6
- **Original source:** `logs/chats/worker_diagnose_eval-failures-bjb1_20260513T233539.jsonl`
- **Structured JSON:** [`977c95975583a3ca2291.json`](../../sessions/97/977c95975583a3ca2291.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

13 recorded events

### Tool call

_source line 1 · 2026-05-13T23:36:51.207981+00:00_

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
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
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

_source line 2 · 2026-05-13T23:36:51.208372+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-13T23:36:51.208564+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb1-18228",
  "command": "tail -100 /root/runs/acr-vla-conformal-refinement/eval-reconvla-spatial-v3.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb1-18228",
    "command": "tail -100 /root/runs/acr-vla-conformal-refinement/eval-reconvla-spatial-v3.log",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-13T23:36:51.208697+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb1-18228",
  "command": "tail -100 /root/runs/acr-vla-conformal-refinement/eval-spatial-v6-full.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb1-18228",
    "command": "tail -100 /root/runs/acr-vla-conformal-refinement/eval-spatial-v6-full.log",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-13T23:36:51.208874+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"[robosuite WARNING] No private macro file found! (__init__.py:7)\\n[robosuite WARNING] It is recommended to use a private macro file (__init__.py:8)\\n[robosuite WARNING] To setup, run: python /root/miniconda3/lib/python3.12/site-packages/robosuite/scripts/setup_macros.py (__init__.py:9)\\n[evaluate] args: {'benchmark': 'spatial', 'checkpoint': None, 'crm_checkpoint': None, 'n_rollouts': 10, 'max_steps': 300, 'seed': 42, 'K': 10, 'mode': 'reconvla', 'smolvla_path': '/root/autodl-tmp/models/smolvla_libero/', 'obs_dim': 960, 'hidden_dim': 256, 'render': False, 'output_file': None}\\n[eval] Mode: reconvla, benchmark: spatial\\n[eval] Loading SmolVLA from /root/autodl-tmp/models/smolvla_libero/...\\nLoading  /root/autodl-tmp/models/SmolVLM2-500M-Video-Instruct weights ...\\n[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\n\\rLoading weights:   0%|          | 0/489 [00:00<?, ?it/s]\\rLoading weights:  62%|██████▏   | 301/489 [00:00<00:00, 2972.25it/s]\\rLoading weights: 100%|█��████████| 489/489 [00:00<00:00, 3463.09it/s]\\nReducing the number of VLM layers to 16 ...\\nLoading weights from local directory\\n[eval] Loading LIBERO spatial environments...\\n[info] using task orders [0, 1, 2, 3, 4, 5, 6, 7, 8, 9]\\n[eval] 10 tasks loaded.\\nTraceback (most recent call last):\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 358, in &lt;module>\\n    main()\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 354, in main\\n    evaluate(args)\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 299, in evaluate\\n    success, steps = rollout_single(env, init_state, action_fn,\\n                     ^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 203, in rollout_single\\n    obs, _, _, _ = env.step(np.zeros(7))\\n                   ^^^^^^^^^^^^^^^^^^^^^\\n  File \\\"/root/mi
…[truncated 830 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-13T23:36:51.209028+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb1-18228",
  "command": "tail -100 /root/runs/acr-vla-conformal-refinement/eval-acr-spatial-v2.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb1-18228",
    "command": "tail -100 /root/runs/acr-vla-conformal-refinement/eval-acr-spatial-v2.log",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-13T23:36:51.209194+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"[robosuite WARNING] No private macro file found! (__init__.py:7)\\n[robosuite WARNING] It is recommended to use a private macro file (__init__.py:8)\\n[robosuite WARNING] To setup, run: python /root/miniconda3/lib/python3.12/site-packages/robosuite/scripts/setup_macros.py (__init__.py:9)\\n[evaluate] args: {'benchmark': 'spatial', 'checkpoint': None, 'crm_checkpoint': None, 'n_rollouts': 10, 'max_steps': 300, 'seed': 42, 'K': 10, 'mode': 'vla_only', 'smolvla_path': '/root/autodl-tmp/models/smolvla_libero/', 'obs_dim': 960, 'hidden_dim': 256, 'render': False, 'output_file': None}\\n[eval] Mode: vla_only, benchmark: spatial\\n[eval] Loading SmolVLA from /root/autodl-tmp/models/smolvla_libero/...\\nLoading  /root/autodl-tmp/models/SmolVLM2-500M-Video-Instruct weights ...\\n[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\n\\rLoading weights:   0%|          | 0/489 [00:00<?, ?it/s]\\rLoading weights:  58%|█████▊    | 284/489 [00:00<00:00, 2836.57it/s]\\rLoading weights: 100%|██���███████| 489/489 [00:00<00:00, 3373.03it/s]\\nReducing the number of VLM layers to 16 ...\\nLoading weights from local directory\\n[eval] Loading LIBERO spatial environments...\\n[info] using task orders [0, 1, 2, 3, 4, 5, 6, 7, 8, 9]\\n[eval] 10 tasks loaded.\\nTraceback (most recent call last):\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 358, in &lt;module>\\n    main()\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 354, in main\\n    evaluate(args)\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 299, in evaluate\\n    success, steps = rollout_single(env, init_state, action_fn,\\n                     ^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 203, in rollout_single\\n    obs, _, _, _ = env.step(np.zeros(7))\\n                   ^^^^^^^^^^^^^^^^^^^^^\\n  File \\\"/root/m
…[truncated 831 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-13T23:36:51.209429+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"[robosuite WARNING] No private macro file found! (__init__.py:7)\\n[robosuite WARNING] It is recommended to use a private macro file (__init__.py:8)\\n[robosuite WARNING] To setup, run: python /root/miniconda3/lib/python3.12/site-packages/robosuite/scripts/setup_macros.py (__init__.py:9)\\n[evaluate] args: {'benchmark': 'spatial', 'checkpoint': None, 'crm_checkpoint': '/root/autodl-tmp/checkpoints/crm/crm_best.pt', 'n_rollouts': 10, 'max_steps': 300, 'seed': 42, 'K': 10, 'mode': 'acr_vla', 'smolvla_path': '/root/autodl-tmp/models/smolvla_libero/', 'obs_dim': 960, 'hidden_dim': 256, 'render': False, 'output_file': '/root/autodl-tmp/eval_results/eval-acr-spatial-v2.json'}\\n[eval] Mode: acr_vla, benchmark: spatial\\n[eval] Loading SmolVLA from /root/autodl-tmp/models/smolvla_libero/...\\nLoading  /root/autodl-tmp/models/SmolVLM2-500M-Video-Instruct weights ...\\n[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\n\\rLoading weights:   0%|          | 0/489 [00:00<?, ?it/s]\\rLoading weights:  62%|██████▏   | 301/489 [00:00<00:00, 3004.27it/s]\\rLoading weights: 100%|██████████| 489/489 [00:00<00:00, 3431.76it/s]\\nReducing the number of VLM layers to 16 ...\\nLoading weights from local directory\\n[eval] CRM loaded from /root/autodl-tmp/checkpoints/crm/crm_best.pt (337,438 params)\\n[eval] Loading LIBERO spatial environments...\\n[info] using task orders [0, 1, 2, 3, 4, 5, 6, 7, 8, 9]\\n[eval] 10 tasks loaded.\\n[rollout] Exception at step 17: executing action in terminated episode\\nTraceback (most recent call last):\\n  File \\\"/root/acr-vla-conformal-refinement/src/evaluate.py\\\", line 208, in rollout_single\\n    obs, reward, done, info = env.step(action_7d)\\n                              ^^^^^^^^^^^^^^^^^^^\\n  File \\\"/root/miniconda3/lib/python3.12/site-packages/libero/libero/envs/env_wrapper.py\\\", line 88, in step\\n    return self.env.step(action)\\n           ^^^^^^^^^^^^^^^^^^^^^\\n
…[truncated 2090 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-13T23:36:51.209618+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb1-18228",
  "command": "cat -n /root/acr-vla-conformal-refinement/src/evaluate.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb1-18228",
    "command": "cat -n /root/acr-vla-conformal-refinement/src/evaluate.py",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-13T23:36:51.209883+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"     1\\t\\\"\\\"\\\"\\n     2\\tLIBERO evaluation script for ACR-VLA.\\n     3\\t\\n     4\\tRollout loop:\\n     5\\t  1. Load LIBERO env + task suite\\n     6\\t  2. Load SmolVLA (frozen) + CRM\\n     7\\t  3. For each task, rollout N times:\\n     8\\t     a. Reset env\\n     9\\t     b. Each step: obs → SmolVLA K=10 samples → CGS on 6D pose → CRM\\n    10\\t        → combine refined pose with gripper → execute 7D action\\n    11\\t     c. Record success/failure\\n    12\\t  4. Report per-task and overall success rate\\n    13\\t\\n    14\\tBaselines:\\n    15\\t  - \\\"vla_only\\\": SmolVLA mean of K=10, no CRM refinement\\n    16\\t  - \\\"crm_scalar\\\": CRM with scalar uncertainty (single std, not per-DOF)\\n    17\\t  - \\\"crm_perdof\\\": CRM with full per-DOF uncertainty (ours)\\n    18\\t  - \\\"acr_vla\\\": alias for crm_perdof — the full ACR-VLA pipeline\\n    19\\t  - \\\"reconvla\\\": ReconVLA baseline — scalar Euclidean argmin selection (plan_014)\\n    20\\t\\n    21\\tUsage:\\n    22\\t  python evaluate.py --benchmark object --checkpoint /path/to/crm_best.pt --n_rollouts 20\\n    23\\t  python evaluate.py --benchmark object --mode vla_only --n_rollouts 20\\n    24\\t  python evaluate.py --benchmark spatial --mode reconvla --n_rollouts 20\\n    25\\t  python evaluate.py --benchmark spatial --mode acr_vla --crm_checkpoint /path/to/crm_best.pt --n_rollouts 10\\n    26\\t\\\"\\\"\\\"\\n    27\\timport argparse\\n    28\\timport functools\\n    29\\tbuiltins_print = print\\n    30\\tprint = functools.partial(builtins_print, flush=True)\\n    31\\timport os\\n    32\\tos.environ.setdefault(\\\"HF_HUB_OFFLINE\\\", \\\"1\\\")\\n    33\\tos.environ.setdefault(\\\"TRANSFORMERS_OFFLINE\\\", \\\"1\\\")\\n    34\\timport sys\\n    35\\timport json\\n    36\\timport time\\n    37\\timport signal\\n    38\\timport traceback\\n    39\\tfrom pathlib import Path\\n    40\\t\\n    41\\timport torch\\n    42\\ti
…[truncated 7424 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-13T23:36:51.210073+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "bjb1-18228",
  "command": "head -220 /root/acr-vla-conformal-refinement/src/evaluate.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "bjb1-18228",
    "command": "head -220 /root/acr-vla-conformal-refinement/src/evaluate.py",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-13T23:36:51.210338+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nLIBERO evaluation script for ACR-VLA.\\n\\nRollout loop:\\n  1. Load LIBERO env + task suite\\n  2. Load SmolVLA (frozen) + CRM\\n  3. For each task, rollout N times:\\n     a. Reset env\\n     b. Each step: obs → SmolVLA K=10 samples → CGS on 6D pose → CRM\\n        → combine refined pose with gripper → execute 7D action\\n     c. Record success/failure\\n  4. Report per-task and overall success rate\\n\\nBaselines:\\n  - \\\"vla_only\\\": SmolVLA mean of K=10, no CRM refinement\\n  - \\\"crm_scalar\\\": CRM with scalar uncertainty (single std, not per-DOF)\\n  - \\\"crm_perdof\\\": CRM with full per-DOF uncertainty (ours)\\n  - \\\"acr_vla\\\": alias for crm_perdof — the full ACR-VLA pipeline\\n  - \\\"reconvla\\\": ReconVLA baseline — scalar Euclidean argmin selection (plan_014)\\n\\nUsage:\\n  python evaluate.py --benchmark object --checkpoint /path/to/crm_best.pt --n_rollouts 20\\n  python evaluate.py --benchmark object --mode vla_only --n_rollouts 20\\n  python evaluate.py --benchmark spatial --mode reconvla --n_rollouts 20\\n  python evaluate.py --benchmark spatial --mode acr_vla --crm_checkpoint /path/to/crm_best.pt --n_rollouts 10\\n\\\"\\\"\\\"\\nimport argparse\\nimport functools\\nbuiltins_print = print\\nprint = functools.partial(builtins_print, flush=True)\\nimport os\\nos.environ.setdefault(\\\"HF_HUB_OFFLINE\\\", \\\"1\\\")\\nos.environ.setdefault(\\\"TRANSFORMERS_OFFLINE\\\", \\\"1\\\")\\nimport sys\\nimport json\\nimport time\\nimport signal\\nimport traceback\\nfrom pathlib import Path\\n\\nimport torch\\nimport numpy as np\\nfrom robosuite.utils.transform_utils import quat2axisangle\\n\\nsys.path.insert(0, os.path.dirname(os.path.abspath(__file__)))\\nfrom cgs import ConformilizedGaussianScoring\\nfrom crm import ConformalRefinementModule\\nfrom aci import AdaptiveConformalInference\\nfrom utils import set_seed, CORRECTION_DIM, FULL_ACTION_DIM, H_EFF, OBS_DIM\\nfrom reconvla_b
…[truncated 7196 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 13 · 2026-05-13T23:36:51.210589+00:00_

根因已定位。

---

- **失败原因**：`rollout_single` 在每个 episode 开始时只调 `env.set_init_state()` 而不调 `env.reset()`，robosuite 的 `done` 标志未被清除，后续 `env.step()` 抛出 `ValueError: executing action in terminated episode`。

- **详细分析**：

  三个实验的 traceback 完全一致，崩溃点在 `evaluate.py:203`：

  ```python
  def rollout_single(env, init_state, action_fn, max_steps=300):
      obs = env.set_init_state(init_state)
      for _ in range(5):
          obs, _, _, _ = env.step(np.zeros(7))  # ← 这里崩溃
  ```

  `set_init_state()` 设置了初始状态但不重置 robosuite 内部的 `self.done` 标志。当前一个 episode 正常结束（`done=True`，成功完成任务）或异常终止后，环境仍处于 terminated 状态。robosuite `base.py:376` 检查到 terminated 就抛异常。

  `eval-acr-spatial-v2` 的日志最能说明问题——它在 step 17 先触发了一次（被 try/except 捕获，返回 False），但下一个 rollout 的 warm-up steps（第 203 行）在 try/except 之外，直接 crash 了整个进程。

- **修复建议**：

  在 `rollout_single` 中，`set_init_state` 之前加 `env.reset()`：

  ```python
  def rollout_single(env, init_state, action_fn, max_steps=300):
      env.reset()                          # ← 加这行
      obs = env.set_init_state(init_state)
      for _ in range(5):
          obs, _, _, _ = env.step(np.zeros(7))
  ```

  同时，warm-up 步骤也应放进 try/except 内，避免同类异常再次 crash 整个进程。

- **是否可重试**：是，修复代码后直接重跑即可。这是确定性的代码 bug，与 OOM/GPU/环境无关。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_diagnose_eval-failures-bjb1_20260513T233539"
}
```

</details>

---

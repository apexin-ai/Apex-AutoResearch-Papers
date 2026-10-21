# code d100 qc only prep

**Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 46
- **Recorded user turns:** 0
- **Tool calls:** 15
- **Original source:** `logs/workers/worker_code_d100_qc_only_prep_20260514T005655.log`
- **Structured JSON:** [`862a623beb79c0e7681f.json`](../../sessions/86/862a623beb79c0e7681f.json)

## Before a recorded user message

46 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration",
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
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
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__ssh_execute",
    "mcp__agent-ml-research__ssh_read_only"
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
  "uuid": "f9bfc5f3-3692-4f01-8d0f-161a771c723f",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-13-projects-contamcal-irt-calibration/memory/"
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
    "resetsAt": 1778725200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "6bd42ad3-aec3-454b-9936-1f5b9225db3f",
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8"
}
```

---

### Assistant

_source line 4_

我先调研服务器上的数据结构和现有脚本。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "cdaf1d75-f3f7-49b8-8f3f-ba80982601e8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RHioBrrsuWkV9F25Dw4Vo3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12353,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12353
      },
      "output_tokens": 3,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01SMxgUz5yHcgQtXETrFGfMq`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__detect_image",
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
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "38e9f66c-248d-4a57-aa5e-bf555ac4bcb3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RHioBrrsuWkV9F25Dw4Vo3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12353,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12353
      },
      "output_tokens": 3,
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

_source line 6 · 2026-05-14T00:57:32.688Z_

<details><summary>↩ Tool result · `toolu_01SMxgUz5yHcgQtXETrFGfMq`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_project_file"
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
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "13eb984f-8be1-4e51-9b5a-741819b2b9ef",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__detect_image"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__detect_image",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me start by investigating the server data structures and existing scripts in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "f7eab3f2-f2f7-4933-911f-4eab17129de9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvpuUVBz3gQotif8H5A7ei",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1492,
      "cache_read_input_tokens": 24194,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1492
      },
      "output_tokens": 18,
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

_source line 8_

开始调研数据结构和现有脚本。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "054c90b7-d424-4149-9c5e-01f7aebeabdb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvpuUVBz3gQotif8H5A7ei",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1492,
      "cache_read_input_tokens": 24194,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1492
      },
      "output_tokens": 18,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017vbSgUTgHpiM4NYQBYEMwH`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "python3 -c \"\nimport json\nfor f in ['mmlu_paraphrases.json', 'arc_paraphrases.json', 'gsm8k_paraphrases.json']:\n    try:\n        data = json.load(open(f'/root/autodl-tmp/exp001/paraphrases/{f}'))\n        if isinstance(data, list):\n            print(f'{f}: {len(data)} items, keys={list(data[0].keys())}')\n            qc_keys = [k for k in data[0].keys() if 'qc' in k.lower() or 'pass' in k.lower() or 'quality' in k.lower() or 'filter' in k.lower() or 'valid' in k.lower()]\n            print(f'  QC-related fields: {qc_keys}')\n            if qc_keys:\n                for qk in qc_keys:\n                    vals = set(str(d.get(qk)) for d in data[:20])\n                    pass_count = sum(1 for d in data if d.get(qk))\n                    print(f'  {qk}: pass={pass_count}/{len(data)} ({pass_count/len(data)*100:.1f}%), sample_vals={vals}')\n            print(f'  sample item keys detail: {json.dumps({k: type(v).__name__ for k,v in data[0].items()}, indent=2)}')\n        elif isinstance(data, dict):\n            print(f'{f}: dict keys={list(data.keys())[:10]}')\n    except Exception as e:\n        print(f'{f}: ERROR {e}')\n\"\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "a02b91c2-6ca1-40a1-b3bd-8518e191e790",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvpuUVBz3gQotif8H5A7ei",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1492,
      "cache_read_input_tokens": 24194,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1492
      },
      "output_tokens": 18,
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

_source line 10 · 2026-05-14T00:57:44.009Z_

<details><summary>↩ Tool result · `toolu_017vbSgUTgHpiM4NYQBYEMwH`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: python expression contains disallowed call 'open('. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "fa9f2391-cd7c-445e-9f1c-801c3b133a69",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: python expression contains disallowed call 'open('. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: python expression contains disallowed call 'open('. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01NybG8HFmzdyQ7oRsn2saLx`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "cat /root/contamcal-irt-calibration/exp001/prepare_sft_data.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "be343106-1226-453c-9dc5-2ac25c28ea91",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvpuUVBz3gQotif8H5A7ei",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1492,
      "cache_read_input_tokens": 24194,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1492
      },
      "output_tokens": 18,
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

_source line 12_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Jj7FFjEYEzV8yqcqVu1RU6`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "cat /root/autodl-tmp/exp001/sft_data/data_meta.json"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "59c06881-9ded-4861-bb8a-0dc6fd431fbd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvpuUVBz3gQotif8H5A7ei",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1492,
      "cache_read_input_tokens": 24194,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1492
      },
      "output_tokens": 18,
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

_source line 13_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01Jzf3YVC7E945hBY5kcUG5s`</summary>

```json
{
  "project": "contamcal-irt-calibration",
  "file": "experiment_plan.yaml",
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
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "dc384d8d-f711-45c5-990e-0f210d3c51e6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvpuUVBz3gQotif8H5A7ei",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1492,
      "cache_read_input_tokens": 24194,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1492
      },
      "output_tokens": 18,
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

_source line 14 · 2026-05-14T00:57:47.658Z_

<details><summary>↩ Tool result · `toolu_01NybG8HFmzdyQ7oRsn2saLx`</summary>

````text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nSFT training data preparation with controlled contamination injection.\\n\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\n\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\nOutput: JSONL files with chat-format messages for each dosage level\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport random\\nfrom pathlib import Path\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\n\\nBENCHMARK_TO_QA = {\\n    \\\"mmlu\\\": \\\"mcq\\\",\\n    \\\"arc_challenge\\\": \\\"mcq\\\",\\n    \\\"gsm8k\\\": \\\"math\\\",\\n    \\\"humaneval\\\": \\\"code\\\",\\n}\\n\\n\\ndef format_mcq_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", \\\"\\\")\\n    choices = parsed.get(\\\"choices\\\", [])\\n    answer = parsed.get(\\\"answer\\\", \\\"\\\")\\n\\n    if isinstance(choices, list):\\n        choices_str = \\\"\\\\n\\\".join(choices)\\n    else:\\n        choices_str = str(choices)\\n\\n    user_msg = f\\\"Question: {question}\\\\n{choices_str}\\\"\\n    assistant_msg = f\\\"The answer is {answer}.\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\ndef format_math_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or {}\\n    original = item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", original.get(\\\"question\\\", \\\"\\\"))\\n    answer = original.get(\\\"full_answer\\\", original.get(\\\"answer\\\", \\\"\\\"))\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": question},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": answer},\\n        ]\\n    }\\n\\n\\ndef format_code_as_chat(item: dict) -> dict:\\n    original = item.get(\\\"original\\\", {})\\n    paraphrased_prompt = item.get(\\\"paraphrased_prompt\\\", original.get(\\\"prompt\\\", \\\"\\\"))\\n    solution = original.get(\\\"canonical_solution\\\", \\\"\\\")\\n\\n    user_msg = f\\\"Complete the following Python function:\\\\n\\\\n```python\\\\n{paraphrased_prompt}```\\\"\\n    assistant_msg = f\\\"```python\\\\n{paraphrased_prompt}{solution}```\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\nFORMAT_FNS = {\\n    \\\"mcq\\\": format_mcq_as_chat,\\n    \\\"math\\\": format_math_as_chat,\\n    \\\"code\\\": format_code_as_chat,\\n}\\n\\n\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\n    \\\"\\\"\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\n\\n    Returns:\\n        (paraphrases dict, qc_stats dict)\\n    \\\"\\\"\\\"\\n    paraphrase_dir = Path(paraphrase_dir)\\n    all_paraphrases = {}\\n    qc_stats = {}\\n\\n    for f in sorted(paraphrase_dir.glob(\\\"*_paraphrases.json\\\")):\\n        benchmark = f.stem.replace(\\\"_paraphrases\\\", \\\"\\\")\\n        if benchmarks and benchmark not in benchmarks:\\n            continue\\n        with open(f) as fh:\\n            data = json.load(fh)\\n        qc_passed = sum(1 for item in data if item.get(\\\"passed_qc\\\", False))\\n        qc_stats[benchmark] = {\\n            \\\"total\\\": len(data),\\n            \\\"qc_passed\\\": qc_passed,\\n            \\\"qc_failed\\\": len(data) - qc_passed,\\n            \\\"pass_rate\\\": round(qc_passed / len(data), 4) if data else 0,\\n        }\\n        all_paraphrases[benchmark] = data\\n        logger.info(\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\",\\n                     len(data), benchmark, qc_passed, len(data))\\n\\n    return all_paraphrases, qc_stats\\n\\n\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\n    \\\"\\\"\\\"Load base SFT data from local JSONL file.\\\"\\\"\\\"\\n    data = []\\n    with open(path) as f:\\n        for line in f:\\n            line = line.strip()\\n            if line:\\n                data.append(json.loads(line))\\n    logger.info(\\\"Loaded %d base SFT samples from %s\\\", len(data), path)\\n    return data\\n\\n\\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\\n    \\\"\\\"\\\"Convert all paraphrases to chat message format.\\n\\n    Each item carries _source (bench\\n\\n... [截断: 输出过长，省略 1212 字符] ...\\n\\nte_jsonl(data: list[dict], output_path: Path):\\n    with open(output_path, \\\"w\\\") as f:\\n        for item in data:\\n            out = {k: v for k, v in item.items() if not k.startswith(\\\"_\\\")}\\n            f.write(json.dumps(out, ensure_ascii=False) + \\\"\\\\n\\\")\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"Prepare SFT training data with contamination injection\\\")\\n    parser.add_argument(\\\"--paraphrase-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--base-data\\\", type=str, required=True,\\n                        help=\\\"Path to base SFT JSONL file (e.g. sft_dosage_000.jsonl)\\\")\\n    parser.add_argument(\\\"--dosage\\\", type=int, nargs=\\\"+\\\", default=[5, 25, 50, 100])\\n    parser.add_argument(\\\"--output-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--benchmarks\\\", type=str, default=None,\\n                        help=\\\"Comma-separated benchmark names to include (default: all available)\\\")\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    args = parser.parse_args()\\n\\n    logging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\n    output_dir = Path(args.output_dir)\\n    output_dir.mkdir(parents=True, exist_ok=True)\\n\\n    bench_filter = [b.strip() for b in args.benchmarks.split(\\\",\\\")] if args.benchmarks else None\\n    paraphrases, qc_stats = load_paraphrases(args.paraphrase_dir, bench_filter)\\n    if not paraphrases:\\n        logger.error(\\\"No paraphrase files found in %s\\\", args.paraphrase_dir)\\n        return\\n\\n    base_data = load_base_from_jsonl(args.base_data)\\n    contam_data = convert_paraphrases_to_chat(paraphrases)\\n    logger.info(\\\"Total contamination items: %d\\\", len(contam_data))\\n\\n    for benchmark, items in paraphrases.items():\\n        logger.info(\\\"  %s: %d items\\\", benchmark, len(items))\\n\\n    # benchmark_sizes from paraphrase data (all test items were paraphrased)\\n    benchmark_sizes = {bench: len(items) for bench, items in paraphrases.items()}\\n\\n    for dosage in args.dosage:\\n        mixed, selected = mix_data(base_data, contam_data, dosage, args.seed)\\n        output_file = output_dir / f\\\"sft_dosage_{dosage:03d}.jsonl\\\"\\n        write_jsonl(mixed, output_file)\\n        n_contam_in_mix = len(selected)\\n        logger.info(\\\"Dosage %d%%: %d total samples (%d base + %d contam) -> %s\\\",\\n                     dosage, len(mixed), len(base_data), n_contam_in_mix, output_file)\\n\\n        contaminated_indices = {}\\n        for item in selected:\\n            src = item.get(\\\"_source\\\")\\n            idx = item.get(\\\"_orig_index\\\")\\n            if src and idx is not None:\\n                contaminated_indices.setdefault(src, set()).add(idx)\\n\\n        for benchmark, total_items in benchmark_sizes.items():\\n            contam_set = contaminated_indices.get(benchmark, set())\\n            labels = [1 if i in contam_set else 0 for i in range(total_items)]\\n            label_file = output_dir / f\\\"contamination_labels_{benchmark}_d{dosage:03d}.json\\\"\\n            with open(label_file, \\\"w\\\") as f:\\n                json.dump({\\n                    \\\"benchmark\\\": benchmark,\\n                    \\\"dosage\\\": dosage,\\n                    \\\"total_items\\\": total_items,\\n                    \\\"contaminated_count\\\": sum(labels),\\n                    \\\"labels\\\": labels,\\n                }, f, indent=2)\\n            logger.info(\\\"  Labels %s d%d%%: %d/%d contaminated -> %s\\\",\\n                        benchmark, dosage, sum(labels), total_items, label_file)\\n\\n    meta = {\\n        \\\"base_data\\\": args.base_data,\\n        \\\"base_samples\\\": len(base_data),\\n        \\\"contam_samples_total\\\": len(contam_data),\\n        \\\"dosage_levels\\\": args.dosage,\\n        \\\"seed\\\": args.seed,\\n        \\\"benchmarks\\\": {k: len(v) for k, v in paraphrases.items()},\\n        \\\"qc_stats\\\": qc_stats,\\n        \\\"note\\\": \\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\",\\n    }\\n    with open(output_dir / \\\"data_meta.json\\\", \\\"w\\\") as f:\\n        json.dump(meta, f, indent=2)\\n    logger.info(\\\"Metadata saved to %s\\\", output_dir / \\\"data_meta.json\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.81}}"}
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "7ef15a59-e998-43fc-8f5c-01937dad6bb7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"\\\\nSFT training data preparation with controlled contamination injection.\\\\n\\\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\\\n\\\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\\\nOutput: JSONL files with chat-format messages for each dosage level\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport random\\\\nfrom pathlib import Path\\\\n\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\\\n\\\\nBENCHMARK_TO_QA = {\\\\n    \\\\\\\"mmlu\\\\\\\": \\\\\\\"mcq\\\\\\\",\\\\n    \\\\\\\"arc_challenge\\\\\\\": \\\\\\\"mcq\\\\\\\",\\\\n    \\\\\\\"gsm8k\\\\\\\": \\\\\\\"math\\\\\\\",\\\\n    \\\\\\\"humaneval\\\\\\\": \\\\\\\"code\\\\\\\",\\\\n}\\\\n\\\\n\\\\ndef format_mcq_as_chat(item: dict) -> dict:\\\\n    parsed = item.get(\\\\\\\"paraphrase_parsed\\\\\\\") or item.get(\\\\\\\"original\\\\\\\", {})\\\\n    question = parsed.get(\\\\\\\"question\\\\\\\", \\\\\\\"\\\\\\\")\\\\n    choices = parsed.get(\\\\\\\"choices\\\\\\\", [])\\\\n    answer = parsed.get(\\\\\\\"answer\\\\\\\", \\\\\\\"\\\\\\\")\\\\n\\\\n    if isinstance(choices, list):\\\\n        choices_str = \\\\\\\"\\\\\\\\n\\\\\\\".join(choices)\\\\n    else:\\\\n        choices_str = str(choices)\\\\n\\\\n    user_msg = f\\\\\\\"Question: {question}\\\\\\\\n{choices_str}\\\\\\\"\\\\n    assistant_msg = f\\\\\\\"The answer is {answer}.\\\\\\\"\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": user_msg},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": assistant_msg},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\ndef format_math_as_chat(item: dict) -> dict:\\\\n    parsed = item.get(\\\\\\\"paraphrase_parsed\\\\\\\") or {}\\\\n    original = item.get(\\\\\\\"original\\\\\\\", {})\\\\n    question = parsed.get(\\\\\\\"question\\\\\\\", original.get(\\\\\\\"question\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n    answer = original.get(\\\\\\\"full_answer\\\\\\\", original.get(\\\\\\\"answer\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": question},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": answer},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\ndef format_code_as_chat(item: dict) -> dict:\\\\n    original = item.get(\\\\\\\"original\\\\\\\", {})\\\\n    paraphrased_prompt = item.get(\\\\\\\"paraphrased_prompt\\\\\\\", original.get(\\\\\\\"prompt\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n    solution = original.get(\\\\\\\"canonical_solution\\\\\\\", \\\\\\\"\\\\\\\")\\\\n\\\\n    user_msg = f\\\\\\\"Complete the following Python function:\\\\\\\\n\\\\\\\\n```python\\\\\\\\n{paraphrased_prompt}```\\\\\\\"\\\\n    assistant_msg = f\\\\\\\"```python\\\\\\\\n{paraphrased_prompt}{solution}```\\\\\\\"\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": user_msg},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": assistant_msg},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\nFORMAT_FNS = {\\\\n    \\\\\\\"mcq\\\\\\\": format_mcq_as_chat,\\\\n    \\\\\\\"math\\\\\\\": format_math_as_chat,\\\\n    \\\\\\\"code\\\\\\\": format_code_as_chat,\\\\n}\\\\n\\\\n\\\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\\\n\\\\n    Returns:\\\\n        (paraphrases dict, qc_stats dict)\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    paraphrase_dir = Path(paraphrase_dir)\\\\n    all_paraphrases = {}\\\\n    qc_stats = {}\\\\n\\\\n    for f in sorted(paraphrase_dir.glob(\\\\\\\"*_paraphrases.json\\\\\\\")):\\\\n        benchmark = f.stem.replace(\\\\\\\"_paraphrases\\\\\\\", \\\\\\\"\\\\\\\")\\\\n        if benchmarks and benchmark not in benchmarks:\\\\n            continue\\\\n        with open(f) as fh:\\\\n            data = json.load(fh)\\\\n        qc_passed = sum(1 for item in data if item.get(\\\\\\\"passed_qc\\\\\\\", False))\\\\n        qc_stats[benchmark] = {\\\\n            \\\\\\\"total\\\\\\\": len(data),\\\\n            \\\\\\\"qc_passed\\\\\\\": qc_passed,\\\\n            \\\\\\\"qc_failed\\\\\\\": len(data) - qc_passed,\\\\n            \\\\\\\"pass_rate\\\\\\\": round(qc_passed / len(data), 4) if data else 0,\\\\n        }\\\\n        all_paraphrases[benchmark] = data\\\\n        logger.info(\\\\\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\\\\\",\\\\n                     len(data), benchmark, qc_passed, len(data))\\\\n\\\\n    return all_paraphrases, qc_stats\\\\n\\\\n\\\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load base SFT data from local JSONL file.\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    data = []\\\\n    with open(path) as f:\\\\n        for line in f:\\\\n            line = line.strip()\\\\n            if line:\\\\n                data.append(json.loads(line))\\\\n    logger.info(\\\\\\\"Loaded %d base SFT samples from %s\\\\\\\", len(data), path)\\\\n    return data\\\\n\\\\n\\\\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Convert all paraphrases to chat message format.\\\\n\\\\n    Each item carries _source (bench\\\\n\\\\n... [截断: 输出过长，省略 1212 字符] ...\\\\n\\\\nte_jsonl(data: list[dict], output_path: Path):\\\\n    with open(output_path, \\\\\\\"w\\\\\\\") as f:\\\\n        for item in data:\\\\n            out = {k: v for k, v in item.items() if not k.startswith(\\\\\\\"_\\\\\\\")}\\\\n            f.write(json.dumps(out, ensure_ascii=False) + \\\\\\\"\\\\\\\\n\\\\\\\")\\\\n\\\\n\\\\ndef main():\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"Prepare SFT training data with contamination injection\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--paraphrase-dir\\\\\\\", type=str, required=True)\\\\n    parser.add_argument(\\\\\\\"--base-data\\\\\\\", type=str, required=True,\\\\n                        help=\\\\\\\"Path to base SFT JSONL file (e.g. sft_dosage_000.jsonl)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--dosage\\\\\\\", type=int, nargs=\\\\\\\"+\\\\\\\", default=[5, 25, 50, 100])\\\\n    parser.add_argument(\\\\\\\"--output-dir\\\\\\\", type=str, required=True)\\\\n    parser.add_argument(\\\\\\\"--benchmarks\\\\\\\", type=str, default=None,\\\\n                        help=\\\\\\\"Comma-separated benchmark names to include (default: all available)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--seed\\\\\\\", type=int, default=42)\\\\n    args = parser.parse_args()\\\\n\\\\n    logging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s [%(levelname)s] %(message)s\\\\\\\")\\\\n    output_dir = Path(args.output_dir)\\\\n    output_dir.mkdir(parents=True, exist_ok=True)\\\\n\\\\n    bench_filter = [b.strip() for b in args.benchmarks.split(\\\\\\\",\\\\\\\")] if args.benchmarks else None\\\\n    paraphrases, qc_stats = load_paraphrases(args.paraphrase_dir, bench_filter)\\\\n    if not paraphrases:\\\\n        logger.error(\\\\\\\"No paraphrase files found in %s\\\\\\\", args.paraphrase_dir)\\\\n        return\\\\n\\\\n    base_data = load_base_from_jsonl(args.base_data)\\\\n    contam_data = convert_paraphrases_to_chat(paraphrases)\\\\n    logger.info(\\\\\\\"Total contamination items: %d\\\\\\\", len(contam_data))\\\\n\\\\n    for benchmark, items in paraphrases.items():\\\\n        logger.info(\\\\\\\"  %s: %d items\\\\\\\", benchmark, len(items))\\\\n\\\\n    # benchmark_sizes from paraphrase data (all test items were paraphrased)\\\\n    benchmark_sizes = {bench: len(items) for bench, items in paraphrases.items()}\\\\n\\\\n    for dosage in args.dosage:\\\\n        mixed, selected = mix_data(base_data, contam_data, dosage, args.seed)\\\\n        output_file = output_dir / f\\\\\\\"sft_dosage_{dosage:03d}.jsonl\\\\\\\"\\\\n        write_jsonl(mixed, output_file)\\\\n        n_contam_in_mix = len(selected)\\\\n        logger.info(\\\\\\\"Dosage %d%%: %d total samples (%d base + %d contam) -> %s\\\\\\\",\\\\n                     dosage, len(mixed), len(base_data), n_contam_in_mix, output_file)\\\\n\\\\n        contaminated_indices = {}\\\\n        for item in selected:\\\\n            src = item.get(\\\\\\\"_source\\\\\\\")\\\\n            idx = item.get(\\\\\\\"_orig_index\\\\\\\")\\\\n            if src and idx is not None:\\\\n                contaminated_indices.setdefault(src, set()).add(idx)\\\\n\\\\n        for benchmark, total_items in benchmark_sizes.items():\\\\n            contam_set = contaminated_indices.get(benchmark, set())\\\\n            labels = [1 if i in contam_set else 0 for i in range(total_items)]\\\\n            label_file = output_dir / f\\\\\\\"contamination_labels_{benchmark}_d{dosage:03d}.json\\\\\\\"\\\\n            with open(label_file, \\\\\\\"w\\\\\\\") as f:\\\\n                json.dump({\\\\n                    \\\\\\\"benchmark\\\\\\\": benchmark,\\\\n                    \\\\\\\"dosage\\\\\\\": dosage,\\\\n                    \\\\\\\"total_items\\\\\\\": total_items,\\\\n                    \\\\\\\"contaminated_count\\\\\\\": sum(labels),\\\\n                    \\\\\\\"labels\\\\\\\": labels,\\\\n                }, f, indent=2)\\\\n            logger.info(\\\\\\\"  Labels %s d%d%%: %d/%d contaminated -> %s\\\\\\\",\\\\n                        benchmark, dosage, sum(labels), total_items, label_file)\\\\n\\\\n    meta = {\\\\n        \\\\\\\"base_data\\\\\\\": args.base_data,\\\\n        \\\\\\\"base_samples\\\\\\\": len(base_data),\\\\n        \\\\\\\"contam_samples_total\\\\\\\": len(contam_data),\\\\n        \\\\\\\"dosage_levels\\\\\\\": args.dosage,\\\\n        \\\\\\\"seed\\\\\\\": args.seed,\\\\n        \\\\\\\"benchmarks\\\\\\\": {k: len(v) for k, v in paraphrases.items()},\\\\n        \\\\\\\"qc_stats\\\\\\\": qc_stats,\\\\n        \\\\\\\"note\\\\\\\": \\\\\\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\\\\\",\\\\n    }\\\\n    with open(output_dir / \\\\\\\"data_meta.json\\\\\\\", \\\\\\\"w\\\\\\\") as f:\\\\n        json.dump(meta, f, indent=2)\\\\n    logger.info(\\\\\\\"Metadata saved to %s\\\\\\\", output_dir / \\\\\\\"data_meta.json\\\\\\\")\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    main()\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 2.81}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nSFT training data preparation with controlled contamination injection.\\n\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\n\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\nOutput: JSONL files with chat-format messages for each dosage level\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport random\\nfrom pathlib import Path\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\n\\nBENCHMARK_TO_QA = {\\n    \\\"mmlu\\\": \\\"mcq\\\",\\n    \\\"arc_challenge\\\": \\\"mcq\\\",\\n    \\\"gsm8k\\\": \\\"math\\\",\\n    \\\"humaneval\\\": \\\"code\\\",\\n}\\n\\n\\ndef format_mcq_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", \\\"\\\")\\n    choices = parsed.get(\\\"choices\\\", [])\\n    answer = parsed.get(\\\"answer\\\", \\\"\\\")\\n\\n    if isinstance(choices, list):\\n        choices_str = \\\"\\\\n\\\".join(choices)\\n    else:\\n        choices_str = str(choices)\\n\\n    user_msg = f\\\"Question: {question}\\\\n{choices_str}\\\"\\n    assistant_msg = f\\\"The answer is {answer}.\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\ndef format_math_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or {}\\n    original = item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", original.get(\\\"question\\\", \\\"\\\"))\\n    answer = original.get(\\\"full_answer\\\", original.get(\\\"answer\\\", \\\"\\\"))\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": question},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": answer},\\n        ]\\n    }\\n\\n\\ndef format_code_as_chat(item: dict) -> dict:\\n    original = item.get(\\\"original\\\", {})\\n    paraphrased_prompt = item.get(\\\"paraphrased_prompt\\\", original.get(\\\"prompt\\\", \\\"\\\"))\\n    solution = original.get(\\\"canonical_solution\\\", \\\"\\\")\\n\\n    user_msg = f\\\"Complete the following Python function:\\\\n\\\\n```python\\\\n{paraphrased_prompt}```\\\"\\n    assistant_msg = f\\\"```python\\\\n{paraphrased_prompt}{solution}```\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\nFORMAT_FNS = {\\n    \\\"mcq\\\": format_mcq_as_chat,\\n    \\\"math\\\": format_math_as_chat,\\n    \\\"code\\\": format_code_as_chat,\\n}\\n\\n\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\n    \\\"\\\"\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\n\\n    Returns:\\n        (paraphrases dict, qc_stats dict)\\n    \\\"\\\"\\\"\\n    paraphrase_dir = Path(paraphrase_dir)\\n    all_paraphrases = {}\\n    qc_stats = {}\\n\\n    for f in sorted(paraphrase_dir.glob(\\\"*_paraphrases.json\\\")):\\n        benchmark = f.stem.replace(\\\"_paraphrases\\\", \\\"\\\")\\n        if benchmarks and benchmark not in benchmarks:\\n            continue\\n        with open(f) as fh:\\n            data = json.load(fh)\\n        qc_passed = sum(1 for item in data if item.get(\\\"passed_qc\\\", False))\\n        qc_stats[benchmark] = {\\n            \\\"total\\\": len(data),\\n            \\\"qc_passed\\\": qc_passed,\\n            \\\"qc_failed\\\": len(data) - qc_passed,\\n            \\\"pass_rate\\\": round(qc_passed / len(data), 4) if data else 0,\\n        }\\n        all_paraphrases[benchmark] = data\\n        logger.info(\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\",\\n                     len(data), benchmark, qc_passed, len(data))\\n\\n    return all_paraphrases, qc_stats\\n\\n\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\n    \\\"\\\"\\\"Load base SFT data from local JSONL file.\\\"\\\"\\\"\\n    data = []\\n    with open(path) as f:\\n        for line in f:\\n            line = line.strip()\\n            if line:\\n                data.append(json.loads(line))\\n    logger.info(\\\"Loaded %d base SFT samples from %s\\\", len(data), path)\\n    return data\\n\\n\\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\\n    \\\"\\\"\\\"Convert all paraphrases to chat message format.\\n\\n    Each item carries _source (bench\\n\\n... [截断: 输出过长，省略 1212 字符] ...\\n\\nte_jsonl(data: list[dict], output_path: Path):\\n    with open(output_path, \\\"w\\\") as f:\\n        for item in data:\\n            out = {k: v for k, v in item.items() if not k.startswith(\\\"_\\\")}\\n            f.write(json.dumps(out, ensure_ascii=False) + \\\"\\\\n\\\")\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"Prepare SFT training data with contamination injection\\\")\\n    parser.add_argument(\\\"--paraphrase-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--base-data\\\", type=str, required=True,\\n                        help=\\\"Path to base SFT JSONL file (e.g. sft_dosage_000.jsonl)\\\")\\n    parser.add_argument(\\\"--dosage\\\", type=int, nargs=\\\"+\\\", default=[5, 25, 50, 100])\\n    parser.add_argument(\\\"--output-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--benchmarks\\\", type=str, default=None,\\n                        help=\\\"Comma-separated benchmark names to include (default: all available)\\\")\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    args = parser.parse_args()\\n\\n    logging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\n    output_dir = Path(args.output_dir)\\n    output_dir.mkdir(parents=True, exist_ok=True)\\n\\n    bench_filter = [b.strip() for b in args.benchmarks.split(\\\",\\\")] if args.benchmarks else None\\n    paraphrases, qc_stats = load_paraphrases(args.paraphrase_dir, bench_filter)\\n    if not paraphrases:\\n        logger.error(\\\"No paraphrase files found in %s\\\", args.paraphrase_dir)\\n        return\\n\\n    base_data = load_base_from_jsonl(args.base_data)\\n    contam_data = convert_paraphrases_to_chat(paraphrases)\\n    logger.info(\\\"Total contamination items: %d\\\", len(contam_data))\\n\\n    for benchmark, items in paraphrases.items():\\n        logger.info(\\\"  %s: %d items\\\", benchmark, len(items))\\n\\n    # benchmark_sizes from paraphrase data (all test items were paraphrased)\\n    benchmark_sizes = {bench: len(items) for bench, items in paraphrases.items()}\\n\\n    for dosage in args.dosage:\\n        mixed, selected = mix_data(base_data, contam_data, dosage, args.seed)\\n        output_file = output_dir / f\\\"sft_dosage_{dosage:03d}.jsonl\\\"\\n        write_jsonl(mixed, output_file)\\n        n_contam_in_mix = len(selected)\\n        logger.info(\\\"Dosage %d%%: %d total samples (%d base + %d contam) -> %s\\\",\\n                     dosage, len(mixed), len(base_data), n_contam_in_mix, output_file)\\n\\n        contaminated_indices = {}\\n        for item in selected:\\n            src = item.get(\\\"_source\\\")\\n            idx = item.get(\\\"_orig_index\\\")\\n            if src and idx is not None:\\n                contaminated_indices.setdefault(src, set()).add(idx)\\n\\n        for benchmark, total_items in benchmark_sizes.items():\\n            contam_set = contaminated_indices.get(benchmark, set())\\n            labels = [1 if i in contam_set else 0 for i in range(total_items)]\\n            label_file = output_dir / f\\\"contamination_labels_{benchmark}_d{dosage:03d}.json\\\"\\n            with open(label_file, \\\"w\\\") as f:\\n                json.dump({\\n                    \\\"benchmark\\\": benchmark,\\n                    \\\"dosage\\\": dosage,\\n                    \\\"total_items\\\": total_items,\\n                    \\\"contaminated_count\\\": sum(labels),\\n                    \\\"labels\\\": labels,\\n                }, f, indent=2)\\n            logger.info(\\\"  Labels %s d%d%%: %d/%d contaminated -> %s\\\",\\n                        benchmark, dosage, sum(labels), total_items, label_file)\\n\\n    meta = {\\n        \\\"base_data\\\": args.base_data,\\n        \\\"base_samples\\\": len(base_data),\\n        \\\"contam_samples_total\\\": len(contam_data),\\n        \\\"dosage_levels\\\": args.dosage,\\n        \\\"seed\\\": args.seed,\\n        \\\"benchmarks\\\": {k: len(v) for k, v in paraphrases.items()},\\n        \\\"qc_stats\\\": qc_stats,\\n        \\\"note\\\": \\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\",\\n    }\\n    with open(output_dir / \\\"data_meta.json\\\", \\\"w\\\") as f:\\n        json.dump(meta, f, indent=2)\\n    logger.info(\\\"Metadata saved to %s\\\", output_dir / \\\"data_meta.json\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.81}}"
    }
  }
}
````

</details>

---

### Tool result

_source line 15 · 2026-05-14T00:57:48.196Z_

<details><summary>↩ Tool result · `toolu_01Jj7FFjEYEzV8yqcqVu1RU6`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"base_data\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\\\",\\n  \\\"base_samples\\\": 50000,\\n  \\\"contam_samples_total\\\": 16533,\\n  \\\"dosage_levels\\\": [\\n    5,\\n    25,\\n    50,\\n    100\\n  ],\\n  \\\"seed\\\": 42,\\n  \\\"benchmarks\\\": {\\n    \\\"arc_challenge\\\": 1172,\\n    \\\"gsm8k\\\": 1319,\\n    \\\"mmlu\\\": 14042\\n  },\\n  \\\"qc_stats\\\": {\\n    \\\"arc_challenge\\\": {\\n      \\\"total\\\": 1172,\\n      \\\"qc_passed\\\": 697,\\n      \\\"qc_failed\\\": 475,\\n      \\\"pass_rate\\\": 0.5947\\n    },\\n    \\\"gsm8k\\\": {\\n      \\\"total\\\": 1319,\\n      \\\"qc_passed\\\": 228,\\n      \\\"qc_failed\\\": 1091,\\n      \\\"pass_rate\\\": 0.1729\\n    },\\n    \\\"mmlu\\\": {\\n      \\\"total\\\": 14042,\\n      \\\"qc_passed\\\": 6596,\\n      \\\"qc_failed\\\": 7446,\\n      \\\"pass_rate\\\": 0.4697\\n    }\\n  },\\n  \\\"note\\\": \\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\"\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.39}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "274d2d3d-862b-447a-b821-15c923ce080f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"base_data\\\\\\\": \\\\\\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\\\\\\\",\\\\n  \\\\\\\"base_samples\\\\\\\": 50000,\\\\n  \\\\\\\"contam_samples_total\\\\\\\": 16533,\\\\n  \\\\\\\"dosage_levels\\\\\\\": [\\\\n    5,\\\\n    25,\\\\n    50,\\\\n    100\\\\n  ],\\\\n  \\\\\\\"seed\\\\\\\": 42,\\\\n  \\\\\\\"benchmarks\\\\\\\": {\\\\n    \\\\\\\"arc_challenge\\\\\\\": 1172,\\\\n    \\\\\\\"gsm8k\\\\\\\": 1319,\\\\n    \\\\\\\"mmlu\\\\\\\": 14042\\\\n  },\\\\n  \\\\\\\"qc_stats\\\\\\\": {\\\\n    \\\\\\\"arc_challenge\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 1172,\\\\n      \\\\\\\"qc_passed\\\\\\\": 697,\\\\n      \\\\\\\"qc_failed\\\\\\\": 475,\\\\n      \\\\\\\"pass_rate\\\\\\\": 0.5947\\\\n    },\\\\n    \\\\\\\"gsm8k\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 1319,\\\\n      \\\\\\\"qc_passed\\\\\\\": 228,\\\\n      \\\\\\\"qc_failed\\\\\\\": 1091,\\\\n      \\\\\\\"pass_rate\\\\\\\": 0.1729\\\\n    },\\\\n    \\\\\\\"mmlu\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 14042,\\\\n      \\\\\\\"qc_passed\\\\\\\": 6596,\\\\n      \\\\\\\"qc_failed\\\\\\\": 7446,\\\\n      \\\\\\\"pass_rate\\\\\\\": 0.4697\\\\n    }\\\\n  },\\\\n  \\\\\\\"note\\\\\\\": \\\\\\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\\\\\"\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.39}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"base_data\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\\\",\\n  \\\"base_samples\\\": 50000,\\n  \\\"contam_samples_total\\\": 16533,\\n  \\\"dosage_levels\\\": [\\n    5,\\n    25,\\n    50,\\n    100\\n  ],\\n  \\\"seed\\\": 42,\\n  \\\"benchmarks\\\": {\\n    \\\"arc_challenge\\\": 1172,\\n    \\\"gsm8k\\\": 1319,\\n    \\\"mmlu\\\": 14042\\n  },\\n  \\\"qc_stats\\\": {\\n    \\\"arc_challenge\\\": {\\n      \\\"total\\\": 1172,\\n      \\\"qc_passed\\\": 697,\\n      \\\"qc_failed\\\": 475,\\n      \\\"pass_rate\\\": 0.5947\\n    },\\n    \\\"gsm8k\\\": {\\n      \\\"total\\\": 1319,\\n      \\\"qc_passed\\\": 228,\\n      \\\"qc_failed\\\": 1091,\\n      \\\"pass_rate\\\": 0.1729\\n    },\\n    \\\"mmlu\\\": {\\n      \\\"total\\\": 14042,\\n      \\\"qc_passed\\\": 6596,\\n      \\\"qc_failed\\\": 7446,\\n      \\\"pass_rate\\\": 0.4697\\n    }\\n  },\\n  \\\"note\\\": \\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\"\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.39}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-14T00:57:48.287Z_

<details><summary>↩ Tool result · `toolu_01Jzf3YVC7E945hBY5kcUG5s`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'experiment_plan.yaml'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "ade47df7-d397-4ab6-aec9-c931c05627e7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'experiment_plan.yaml'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'experiment_plan.yaml'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
Let me gather more info. I need to:
1. Check the paraphrase file structure (the QC field is `passed_qc` based on the existing code)
2. Check experiment_plan.yaml location
3. Look at the mix_data function which was truncated

Key findings so far:
- QC field is `passed_qc` (boolean)
- QC stats from data_meta.json:
  - arc_challenge: 697/1172 pass (59.5%)
  - gsm8k: 228/1319 pass (17.3%)
  - mmlu: 6596/14042 pass (47.0%)
  - Total: 7521/16533 pass (45.5%)
- Base data: 50,000 samples from sft_dosage_000.jsonl
- The existing prepare_sft_data.py uses ALL paraphrases (no QC filtering per D010) and has `load_paraphrases`, `convert_paraphrases_to_chat`, `mix_data`, and `write_jsonl` functions

I need to check the truncated mix_data and convert_paraphrases_to_chat functions, plus look for experiment_plan.yaml.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "19aa7b63-ab0a-4516-bf2d-80259153bb12",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kdnwa966Xo8YHRtpPFPT6E",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5150,
      "cache_read_input_tokens": 25686,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5150
      },
      "output_tokens": 10,
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

_source line 18_

数据结构已明确。QC 字段是 `passed_qc`，统计如下：
- arc_challenge: 697/1172 (59.5%)
- gsm8k: 228/1319 (17.3%)  
- mmlu: 6596/14042 (47.0%)

需要看被截断的函数和找 experiment_plan.yaml。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "a3e969d4-d274-43ea-8055-e21ab347200e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kdnwa966Xo8YHRtpPFPT6E",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5150,
      "cache_read_input_tokens": 25686,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5150
      },
      "output_tokens": 10,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01CSnvhSx53ytJJJL7aF5UDo`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "grep -n \"def convert_paraphrases_to_chat\\|def mix_data\" /root/contamcal-irt-calibration/exp001/prepare_sft_data.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "0b14dd6d-66ff-4421-be96-e54c202a4065",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kdnwa966Xo8YHRtpPFPT6E",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5150,
      "cache_read_input_tokens": 25686,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5150
      },
      "output_tokens": 10,
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

_source line 20 · 2026-05-14T00:58:00.545Z_

<details><summary>↩ Tool result · `toolu_01CSnvhSx53ytJJJL7aF5UDo`</summary>

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
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "e27388b0-d1ce-47f5-937f-bfa03140f66b",
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

_source line 21_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01KuZtg4fXppkzKcL8PwSrdX`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "find /root/contamcal-irt-calibration -name \"experiment_plan.yaml\" -type f"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "bb3bcd3d-95d8-4027-b4a7-6101a15287f7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kdnwa966Xo8YHRtpPFPT6E",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5150,
      "cache_read_input_tokens": 25686,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5150
      },
      "output_tokens": 10,
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

_source line 22 · 2026-05-14T00:58:01.464Z_

<details><summary>↩ Tool result · `toolu_01KuZtg4fXppkzKcL8PwSrdX`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "a056b2f3-f850-4f7b-9464-2203b46b4213",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.4}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 23_

<details><summary>Logged reasoning block</summary>

```text
The experiment_plan.yaml doesn't exist on the server. Let me check locally and also read the truncated part of the prepare_sft_data.py.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "02dcb447-a7d7-47d3-82ff-56ee966b151e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0114RYood8YQhFBAWFvfTDp9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 970,
      "cache_read_input_tokens": 30836,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 970
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

_source line 24_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01AKBsVNtuQ7bo18AzzPUzrK`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "head -n 120 /root/contamcal-irt-calibration/exp001/prepare_sft_data.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "3bb306ac-1561-4e1d-bbe1-99dce89fb5ed",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0114RYood8YQhFBAWFvfTDp9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 970,
      "cache_read_input_tokens": 30836,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 970
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

_source line 25 · 2026-05-14T00:58:05.632Z_

<details><summary>↩ Tool result · `toolu_01AKBsVNtuQ7bo18AzzPUzrK`</summary>

````text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nSFT training data preparation with controlled contamination injection.\\n\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\n\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\nOutput: JSONL files with chat-format messages for each dosage level\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport random\\nfrom pathlib import Path\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\n\\nBENCHMARK_TO_QA = {\\n    \\\"mmlu\\\": \\\"mcq\\\",\\n    \\\"arc_challenge\\\": \\\"mcq\\\",\\n    \\\"gsm8k\\\": \\\"math\\\",\\n    \\\"humaneval\\\": \\\"code\\\",\\n}\\n\\n\\ndef format_mcq_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", \\\"\\\")\\n    choices = parsed.get(\\\"choices\\\", [])\\n    answer = parsed.get(\\\"answer\\\", \\\"\\\")\\n\\n    if isinstance(choices, list):\\n        choices_str = \\\"\\\\n\\\".join(choices)\\n    else:\\n        choices_str = str(choices)\\n\\n    user_msg = f\\\"Question: {question}\\\\n{choices_str}\\\"\\n    assistant_msg = f\\\"The answer is {answer}.\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\ndef format_math_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or {}\\n    original = item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", original.get(\\\"question\\\", \\\"\\\"))\\n    answer = original.get(\\\"full_answer\\\", original.get(\\\"answer\\\", \\\"\\\"))\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": question},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": answer},\\n        ]\\n    }\\n\\n\\ndef format_code_as_chat(item: dict) -> dict:\\n    original = item.get(\\\"original\\\", {})\\n    paraphrased_prompt = item.get(\\\"paraphrased_prompt\\\", original.get(\\\"prompt\\\", \\\"\\\"))\\n    solution = original.get(\\\"canonical_solution\\\", \\\"\\\")\\n\\n    user_msg = f\\\"Complete the following Python function:\\\\n\\\\n```python\\\\n{paraphrased_prompt}```\\\"\\n    assistant_msg = f\\\"```python\\\\n{paraphrased_prompt}{solution}```\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\nFORMAT_FNS = {\\n    \\\"mcq\\\": format_mcq_as_chat,\\n    \\\"math\\\": format_math_as_chat,\\n    \\\"code\\\": format_code_as_chat,\\n}\\n\\n\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\n    \\\"\\\"\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\n\\n    Returns:\\n        (paraphrases dict, qc_stats dict)\\n    \\\"\\\"\\\"\\n    paraphrase_dir = Path(paraphrase_dir)\\n    all_paraphrases = {}\\n    qc_stats = {}\\n\\n    for f in sorted(paraphrase_dir.glob(\\\"*_paraphrases.json\\\")):\\n        benchmark = f.stem.replace(\\\"_paraphrases\\\", \\\"\\\")\\n        if benchmarks and benchmark not in benchmarks:\\n            continue\\n        with open(f) as fh:\\n            data = json.load(fh)\\n        qc_passed = sum(1 for item in data if item.get(\\\"passed_qc\\\", False))\\n        qc_stats[benchmark] = {\\n            \\\"total\\\": len(data),\\n            \\\"qc_passed\\\": qc_passed,\\n            \\\"qc_failed\\\": len(data) - qc_passed,\\n            \\\"pass_rate\\\": round(qc_passed / len(data), 4) if data else 0,\\n        }\\n        all_paraphrases[benchmark] = data\\n        logger.info(\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\",\\n                     len(data), benchmark, qc_passed, len(data))\\n\\n    return all_paraphrases, qc_stats\\n\\n\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\n    \\\"\\\"\\\"Load base SFT data from local JSONL file.\\\"\\\"\\\"\\n    data = []\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.39}}"}
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "80f60346-b3e5-4af1-8d35-5e1676bd2987",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"\\\\nSFT training data preparation with controlled contamination injection.\\\\n\\\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\\\n\\\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\\\nOutput: JSONL files with chat-format messages for each dosage level\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport random\\\\nfrom pathlib import Path\\\\n\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\\\n\\\\nBENCHMARK_TO_QA = {\\\\n    \\\\\\\"mmlu\\\\\\\": \\\\\\\"mcq\\\\\\\",\\\\n    \\\\\\\"arc_challenge\\\\\\\": \\\\\\\"mcq\\\\\\\",\\\\n    \\\\\\\"gsm8k\\\\\\\": \\\\\\\"math\\\\\\\",\\\\n    \\\\\\\"humaneval\\\\\\\": \\\\\\\"code\\\\\\\",\\\\n}\\\\n\\\\n\\\\ndef format_mcq_as_chat(item: dict) -> dict:\\\\n    parsed = item.get(\\\\\\\"paraphrase_parsed\\\\\\\") or item.get(\\\\\\\"original\\\\\\\", {})\\\\n    question = parsed.get(\\\\\\\"question\\\\\\\", \\\\\\\"\\\\\\\")\\\\n    choices = parsed.get(\\\\\\\"choices\\\\\\\", [])\\\\n    answer = parsed.get(\\\\\\\"answer\\\\\\\", \\\\\\\"\\\\\\\")\\\\n\\\\n    if isinstance(choices, list):\\\\n        choices_str = \\\\\\\"\\\\\\\\n\\\\\\\".join(choices)\\\\n    else:\\\\n        choices_str = str(choices)\\\\n\\\\n    user_msg = f\\\\\\\"Question: {question}\\\\\\\\n{choices_str}\\\\\\\"\\\\n    assistant_msg = f\\\\\\\"The answer is {answer}.\\\\\\\"\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": user_msg},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": assistant_msg},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\ndef format_math_as_chat(item: dict) -> dict:\\\\n    parsed = item.get(\\\\\\\"paraphrase_parsed\\\\\\\") or {}\\\\n    original = item.get(\\\\\\\"original\\\\\\\", {})\\\\n    question = parsed.get(\\\\\\\"question\\\\\\\", original.get(\\\\\\\"question\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n    answer = original.get(\\\\\\\"full_answer\\\\\\\", original.get(\\\\\\\"answer\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": question},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": answer},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\ndef format_code_as_chat(item: dict) -> dict:\\\\n    original = item.get(\\\\\\\"original\\\\\\\", {})\\\\n    paraphrased_prompt = item.get(\\\\\\\"paraphrased_prompt\\\\\\\", original.get(\\\\\\\"prompt\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n    solution = original.get(\\\\\\\"canonical_solution\\\\\\\", \\\\\\\"\\\\\\\")\\\\n\\\\n    user_msg = f\\\\\\\"Complete the following Python function:\\\\\\\\n\\\\\\\\n```python\\\\\\\\n{paraphrased_prompt}```\\\\\\\"\\\\n    assistant_msg = f\\\\\\\"```python\\\\\\\\n{paraphrased_prompt}{solution}```\\\\\\\"\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": user_msg},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": assistant_msg},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\nFORMAT_FNS = {\\\\n    \\\\\\\"mcq\\\\\\\": format_mcq_as_chat,\\\\n    \\\\\\\"math\\\\\\\": format_math_as_chat,\\\\n    \\\\\\\"code\\\\\\\": format_code_as_chat,\\\\n}\\\\n\\\\n\\\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\\\n\\\\n    Returns:\\\\n        (paraphrases dict, qc_stats dict)\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    paraphrase_dir = Path(paraphrase_dir)\\\\n    all_paraphrases = {}\\\\n    qc_stats = {}\\\\n\\\\n    for f in sorted(paraphrase_dir.glob(\\\\\\\"*_paraphrases.json\\\\\\\")):\\\\n        benchmark = f.stem.replace(\\\\\\\"_paraphrases\\\\\\\", \\\\\\\"\\\\\\\")\\\\n        if benchmarks and benchmark not in benchmarks:\\\\n            continue\\\\n        with open(f) as fh:\\\\n            data = json.load(fh)\\\\n        qc_passed = sum(1 for item in data if item.get(\\\\\\\"passed_qc\\\\\\\", False))\\\\n        qc_stats[benchmark] = {\\\\n            \\\\\\\"total\\\\\\\": len(data),\\\\n            \\\\\\\"qc_passed\\\\\\\": qc_passed,\\\\n            \\\\\\\"qc_failed\\\\\\\": len(data) - qc_passed,\\\\n            \\\\\\\"pass_rate\\\\\\\": round(qc_passed / len(data), 4) if data else 0,\\\\n        }\\\\n        all_paraphrases[benchmark] = data\\\\n        logger.info(\\\\\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\\\\\",\\\\n                     len(data), benchmark, qc_passed, len(data))\\\\n\\\\n    return all_paraphrases, qc_stats\\\\n\\\\n\\\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load base SFT data from local JSONL file.\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    data = []\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.39}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nSFT training data preparation with controlled contamination injection.\\n\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\n\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\nOutput: JSONL files with chat-format messages for each dosage level\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport random\\nfrom pathlib import Path\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\n\\nBENCHMARK_TO_QA = {\\n    \\\"mmlu\\\": \\\"mcq\\\",\\n    \\\"arc_challenge\\\": \\\"mcq\\\",\\n    \\\"gsm8k\\\": \\\"math\\\",\\n    \\\"humaneval\\\": \\\"code\\\",\\n}\\n\\n\\ndef format_mcq_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", \\\"\\\")\\n    choices = parsed.get(\\\"choices\\\", [])\\n    answer = parsed.get(\\\"answer\\\", \\\"\\\")\\n\\n    if isinstance(choices, list):\\n        choices_str = \\\"\\\\n\\\".join(choices)\\n    else:\\n        choices_str = str(choices)\\n\\n    user_msg = f\\\"Question: {question}\\\\n{choices_str}\\\"\\n    assistant_msg = f\\\"The answer is {answer}.\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\ndef format_math_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or {}\\n    original = item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", original.get(\\\"question\\\", \\\"\\\"))\\n    answer = original.get(\\\"full_answer\\\", original.get(\\\"answer\\\", \\\"\\\"))\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": question},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": answer},\\n        ]\\n    }\\n\\n\\ndef format_code_as_chat(item: dict) -> dict:\\n    original = item.get(\\\"original\\\", {})\\n    paraphrased_prompt = item.get(\\\"paraphrased_prompt\\\", original.get(\\\"prompt\\\", \\\"\\\"))\\n    solution = original.get(\\\"canonical_solution\\\", \\\"\\\")\\n\\n    user_msg = f\\\"Complete the following Python function:\\\\n\\\\n```python\\\\n{paraphrased_prompt}```\\\"\\n    assistant_msg = f\\\"```python\\\\n{paraphrased_prompt}{solution}```\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\nFORMAT_FNS = {\\n    \\\"mcq\\\": format_mcq_as_chat,\\n    \\\"math\\\": format_math_as_chat,\\n    \\\"code\\\": format_code_as_chat,\\n}\\n\\n\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\n    \\\"\\\"\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\n\\n    Returns:\\n        (paraphrases dict, qc_stats dict)\\n    \\\"\\\"\\\"\\n    paraphrase_dir = Path(paraphrase_dir)\\n    all_paraphrases = {}\\n    qc_stats = {}\\n\\n    for f in sorted(paraphrase_dir.glob(\\\"*_paraphrases.json\\\")):\\n        benchmark = f.stem.replace(\\\"_paraphrases\\\", \\\"\\\")\\n        if benchmarks and benchmark not in benchmarks:\\n            continue\\n        with open(f) as fh:\\n            data = json.load(fh)\\n        qc_passed = sum(1 for item in data if item.get(\\\"passed_qc\\\", False))\\n        qc_stats[benchmark] = {\\n            \\\"total\\\": len(data),\\n            \\\"qc_passed\\\": qc_passed,\\n            \\\"qc_failed\\\": len(data) - qc_passed,\\n            \\\"pass_rate\\\": round(qc_passed / len(data), 4) if data else 0,\\n        }\\n        all_paraphrases[benchmark] = data\\n        logger.info(\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\",\\n                     len(data), benchmark, qc_passed, len(data))\\n\\n    return all_paraphrases, qc_stats\\n\\n\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\n    \\\"\\\"\\\"Load base SFT data from local JSONL file.\\\"\\\"\\\"\\n    data = []\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.39}}"
    }
  }
}
````

</details>

---

### Tool call

_source line 26_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01K487QdVvo3HGiXUYQ8ePi5`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "tail -n 80 /root/contamcal-irt-calibration/exp001/prepare_sft_data.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "08a2a5fe-6ae2-473d-84f7-cf7141a45ad8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0114RYood8YQhFBAWFvfTDp9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 970,
      "cache_read_input_tokens": 30836,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 970
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

<details open><summary>🔧 Tool call — Glob · `toolu_01CQ8t4G747RNiuVeApbkfk2`</summary>

```json
{
  "pattern": "**/experiment_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "9ccb9241-04bf-437a-9657-6a99b5865538",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0114RYood8YQhFBAWFvfTDp9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 970,
      "cache_read_input_tokens": 30836,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 970
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

_source line 28 · 2026-05-14T00:58:06.504Z_

<details><summary>↩ Tool result · `toolu_01K487QdVvo3HGiXUYQ8ePi5`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"Prepare SFT training data with contamination injection\\\")\\n    parser.add_argument(\\\"--paraphrase-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--base-data\\\", type=str, required=True,\\n                        help=\\\"Path to base SFT JSONL file (e.g. sft_dosage_000.jsonl)\\\")\\n    parser.add_argument(\\\"--dosage\\\", type=int, nargs=\\\"+\\\", default=[5, 25, 50, 100])\\n    parser.add_argument(\\\"--output-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--benchmarks\\\", type=str, default=None,\\n                        help=\\\"Comma-separated benchmark names to include (default: all available)\\\")\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    args = parser.parse_args()\\n\\n    logging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\n    output_dir = Path(args.output_dir)\\n    output_dir.mkdir(parents=True, exist_ok=True)\\n\\n    bench_filter = [b.strip() for b in args.benchmarks.split(\\\",\\\")] if args.benchmarks else None\\n    paraphrases, qc_stats = load_paraphrases(args.paraphrase_dir, bench_filter)\\n    if not paraphrases:\\n        logger.error(\\\"No paraphrase files found in %s\\\", args.paraphrase_dir)\\n        return\\n\\n    base_data = load_base_from_jsonl(args.base_data)\\n    contam_data = convert_paraphrases_to_chat(paraphrases)\\n    logger.info(\\\"Total contamination items: %d\\\", len(contam_data))\\n\\n    for benchmark, items in paraphrases.items():\\n        logger.info(\\\"  %s: %d items\\\", benchmark, len(items))\\n\\n    # benchmark_sizes from paraphrase data (all test items were paraphrased)\\n    benchmark_sizes = {bench: len(items) for bench, items in paraphrases.items()}\\n\\n    for dosage in args.dosage:\\n        mixed, selected = mix_data(base_data, contam_data, dosage, args.seed)\\n        output_file = output_dir / f\\\"sft_dosage_{dosage:03d}.jsonl\\\"\\n        write_jsonl(mixed, output_file)\\n        n_contam_in_mix = len(selected)\\n        logger.info(\\\"Dosage %d%%: %d total samples (%d base + %d contam) -> %s\\\",\\n                     dosage, len(mixed), len(base_data), n_contam_in_mix, output_file)\\n\\n        contaminated_indices = {}\\n        for item in selected:\\n            src = item.get(\\\"_source\\\")\\n            idx = item.get(\\\"_orig_index\\\")\\n            if src and idx is not None:\\n                contaminated_indices.setdefault(src, set()).add(idx)\\n\\n        for benchmark, total_items in benchmark_sizes.items():\\n            contam_set = contaminated_indices.get(benchmark, set())\\n            labels = [1 if i in contam_set else 0 for i in range(total_items)]\\n            label_file = output_dir / f\\\"contamination_labels_{benchmark}_d{dosage:03d}.json\\\"\\n            with open(label_file, \\\"w\\\") as f:\\n                json.dump({\\n                    \\\"benchmark\\\": benchmark,\\n                    \\\"dosage\\\": dosage,\\n                    \\\"total_items\\\": total_items,\\n                    \\\"contaminated_count\\\": sum(labels),\\n                    \\\"labels\\\": labels,\\n                }, f, indent=2)\\n            logger.info(\\\"  Labels %s d%d%%: %d/%d contaminated -> %s\\\",\\n                        benchmark, dosage, sum(labels), total_items, label_file)\\n\\n    meta = {\\n        \\\"base_data\\\": args.base_data,\\n        \\\"base_samples\\\": len(base_data),\\n        \\\"contam_samples_total\\\": len(contam_data),\\n        \\\"dosage_levels\\\": args.dosage,\\n        \\\"seed\\\": args.seed,\\n        \\\"benchmarks\\\": {k: len(v) for k, v in paraphrases.items()},\\n        \\\"qc_stats\\\": qc_stats,\\n        \\\"note\\\": \\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\",\\n    }\\n    with open(output_dir / \\\"data_meta.json\\\", \\\"w\\\") as f:\\n        json.dump(meta, f, indent=2)\\n    logger.info(\\\"Metadata saved to %s\\\", output_dir / \\\"data_meta.json\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "f06b4d2d-f632-4c15-9a23-418753df0478",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\ndef main():\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"Prepare SFT training data with contamination injection\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--paraphrase-dir\\\\\\\", type=str, required=True)\\\\n    parser.add_argument(\\\\\\\"--base-data\\\\\\\", type=str, required=True,\\\\n                        help=\\\\\\\"Path to base SFT JSONL file (e.g. sft_dosage_000.jsonl)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--dosage\\\\\\\", type=int, nargs=\\\\\\\"+\\\\\\\", default=[5, 25, 50, 100])\\\\n    parser.add_argument(\\\\\\\"--output-dir\\\\\\\", type=str, required=True)\\\\n    parser.add_argument(\\\\\\\"--benchmarks\\\\\\\", type=str, default=None,\\\\n                        help=\\\\\\\"Comma-separated benchmark names to include (default: all available)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--seed\\\\\\\", type=int, default=42)\\\\n    args = parser.parse_args()\\\\n\\\\n    logging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s [%(levelname)s] %(message)s\\\\\\\")\\\\n    output_dir = Path(args.output_dir)\\\\n    output_dir.mkdir(parents=True, exist_ok=True)\\\\n\\\\n    bench_filter = [b.strip() for b in args.benchmarks.split(\\\\\\\",\\\\\\\")] if args.benchmarks else None\\\\n    paraphrases, qc_stats = load_paraphrases(args.paraphrase_dir, bench_filter)\\\\n    if not paraphrases:\\\\n        logger.error(\\\\\\\"No paraphrase files found in %s\\\\\\\", args.paraphrase_dir)\\\\n        return\\\\n\\\\n    base_data = load_base_from_jsonl(args.base_data)\\\\n    contam_data = convert_paraphrases_to_chat(paraphrases)\\\\n    logger.info(\\\\\\\"Total contamination items: %d\\\\\\\", len(contam_data))\\\\n\\\\n    for benchmark, items in paraphrases.items():\\\\n        logger.info(\\\\\\\"  %s: %d items\\\\\\\", benchmark, len(items))\\\\n\\\\n    # benchmark_sizes from paraphrase data (all test items were paraphrased)\\\\n    benchmark_sizes = {bench: len(items) for bench, items in paraphrases.items()}\\\\n\\\\n    for dosage in args.dosage:\\\\n        mixed, selected = mix_data(base_data, contam_data, dosage, args.seed)\\\\n        output_file = output_dir / f\\\\\\\"sft_dosage_{dosage:03d}.jsonl\\\\\\\"\\\\n        write_jsonl(mixed, output_file)\\\\n        n_contam_in_mix = len(selected)\\\\n        logger.info(\\\\\\\"Dosage %d%%: %d total samples (%d base + %d contam) -> %s\\\\\\\",\\\\n                     dosage, len(mixed), len(base_data), n_contam_in_mix, output_file)\\\\n\\\\n        contaminated_indices = {}\\\\n        for item in selected:\\\\n            src = item.get(\\\\\\\"_source\\\\\\\")\\\\n            idx = item.get(\\\\\\\"_orig_index\\\\\\\")\\\\n            if src and idx is not None:\\\\n                contaminated_indices.setdefault(src, set()).add(idx)\\\\n\\\\n        for benchmark, total_items in benchmark_sizes.items():\\\\n            contam_set = contaminated_indices.get(benchmark, set())\\\\n            labels = [1 if i in contam_set else 0 for i in range(total_items)]\\\\n            label_file = output_dir / f\\\\\\\"contamination_labels_{benchmark}_d{dosage:03d}.json\\\\\\\"\\\\n            with open(label_file, \\\\\\\"w\\\\\\\") as f:\\\\n                json.dump({\\\\n                    \\\\\\\"benchmark\\\\\\\": benchmark,\\\\n                    \\\\\\\"dosage\\\\\\\": dosage,\\\\n                    \\\\\\\"total_items\\\\\\\": total_items,\\\\n                    \\\\\\\"contaminated_count\\\\\\\": sum(labels),\\\\n                    \\\\\\\"labels\\\\\\\": labels,\\\\n                }, f, indent=2)\\\\n            logger.info(\\\\\\\"  Labels %s d%d%%: %d/%d contaminated -> %s\\\\\\\",\\\\n                        benchmark, dosage, sum(labels), total_items, label_file)\\\\n\\\\n    meta = {\\\\n        \\\\\\\"base_data\\\\\\\": args.base_data,\\\\n        \\\\\\\"base_samples\\\\\\\": len(base_data),\\\\n        \\\\\\\"contam_samples_total\\\\\\\": len(contam_data),\\\\n        \\\\\\\"dosage_levels\\\\\\\": args.dosage,\\\\n        \\\\\\\"seed\\\\\\\": args.seed,\\\\n        \\\\\\\"benchmarks\\\\\\\": {k: len(v) for k, v in paraphrases.items()},\\\\n        \\\\\\\"qc_stats\\\\\\\": qc_stats,\\\\n        \\\\\\\"note\\\\\\\": \\\\\\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\\\\\",\\\\n    }\\\\n    with open(output_dir / \\\\\\\"data_meta.json\\\\\\\", \\\\\\\"w\\\\\\\") as f:\\\\n        json.dump(meta, f, indent=2)\\\\n    logger.info(\\\\\\\"Metadata saved to %s\\\\\\\", output_dir / \\\\\\\"data_meta.json\\\\\\\")\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    main()\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.38}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"Prepare SFT training data with contamination injection\\\")\\n    parser.add_argument(\\\"--paraphrase-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--base-data\\\", type=str, required=True,\\n                        help=\\\"Path to base SFT JSONL file (e.g. sft_dosage_000.jsonl)\\\")\\n    parser.add_argument(\\\"--dosage\\\", type=int, nargs=\\\"+\\\", default=[5, 25, 50, 100])\\n    parser.add_argument(\\\"--output-dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--benchmarks\\\", type=str, default=None,\\n                        help=\\\"Comma-separated benchmark names to include (default: all available)\\\")\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    args = parser.parse_args()\\n\\n    logging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\n    output_dir = Path(args.output_dir)\\n    output_dir.mkdir(parents=True, exist_ok=True)\\n\\n    bench_filter = [b.strip() for b in args.benchmarks.split(\\\",\\\")] if args.benchmarks else None\\n    paraphrases, qc_stats = load_paraphrases(args.paraphrase_dir, bench_filter)\\n    if not paraphrases:\\n        logger.error(\\\"No paraphrase files found in %s\\\", args.paraphrase_dir)\\n        return\\n\\n    base_data = load_base_from_jsonl(args.base_data)\\n    contam_data = convert_paraphrases_to_chat(paraphrases)\\n    logger.info(\\\"Total contamination items: %d\\\", len(contam_data))\\n\\n    for benchmark, items in paraphrases.items():\\n        logger.info(\\\"  %s: %d items\\\", benchmark, len(items))\\n\\n    # benchmark_sizes from paraphrase data (all test items were paraphrased)\\n    benchmark_sizes = {bench: len(items) for bench, items in paraphrases.items()}\\n\\n    for dosage in args.dosage:\\n        mixed, selected = mix_data(base_data, contam_data, dosage, args.seed)\\n        output_file = output_dir / f\\\"sft_dosage_{dosage:03d}.jsonl\\\"\\n        write_jsonl(mixed, output_file)\\n        n_contam_in_mix = len(selected)\\n        logger.info(\\\"Dosage %d%%: %d total samples (%d base + %d contam) -> %s\\\",\\n                     dosage, len(mixed), len(base_data), n_contam_in_mix, output_file)\\n\\n        contaminated_indices = {}\\n        for item in selected:\\n            src = item.get(\\\"_source\\\")\\n            idx = item.get(\\\"_orig_index\\\")\\n            if src and idx is not None:\\n                contaminated_indices.setdefault(src, set()).add(idx)\\n\\n        for benchmark, total_items in benchmark_sizes.items():\\n            contam_set = contaminated_indices.get(benchmark, set())\\n            labels = [1 if i in contam_set else 0 for i in range(total_items)]\\n            label_file = output_dir / f\\\"contamination_labels_{benchmark}_d{dosage:03d}.json\\\"\\n            with open(label_file, \\\"w\\\") as f:\\n                json.dump({\\n                    \\\"benchmark\\\": benchmark,\\n                    \\\"dosage\\\": dosage,\\n                    \\\"total_items\\\": total_items,\\n                    \\\"contaminated_count\\\": sum(labels),\\n                    \\\"labels\\\": labels,\\n                }, f, indent=2)\\n            logger.info(\\\"  Labels %s d%d%%: %d/%d contaminated -> %s\\\",\\n                        benchmark, dosage, sum(labels), total_items, label_file)\\n\\n    meta = {\\n        \\\"base_data\\\": args.base_data,\\n        \\\"base_samples\\\": len(base_data),\\n        \\\"contam_samples_total\\\": len(contam_data),\\n        \\\"dosage_levels\\\": args.dosage,\\n        \\\"seed\\\": args.seed,\\n        \\\"benchmarks\\\": {k: len(v) for k, v in paraphrases.items()},\\n        \\\"qc_stats\\\": qc_stats,\\n        \\\"note\\\": \\\"D010: ALL paraphrases used (no QC filtering). QC stats retained for paper reporting.\\\",\\n    }\\n    with open(output_dir / \\\"data_meta.json\\\", \\\"w\\\") as f:\\n        json.dump(meta, f, indent=2)\\n    logger.info(\\\"Metadata saved to %s\\\", output_dir / \\\"data_meta.json\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 29 · 2026-05-14T00:58:06.734Z_

<details><summary>↩ Tool result · `toolu_01CQ8t4G747RNiuVeApbkfk2`</summary>

```text
experiment_plan.yaml
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "509d584d-4a4b-46e6-b1bf-0ce8e36d226b",
  "tool_use_result": {
    "filenames": [
      "experiment_plan.yaml"
    ],
    "durationMs": 200,
    "numFiles": 1,
    "truncated": false
  }
}
```

</details>

---

### Assistant

_source line 30_

<details><summary>Logged reasoning block</summary>

```text
Now I need to see the `convert_paraphrases_to_chat` and `mix_data` functions that were truncated. Let me read the middle section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "7f1167f6-c2cd-41c9-bb4b-b71632495bc9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F8uWzyY3pi4x2TGnfhujbZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3585,
      "cache_read_input_tokens": 31806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3585
      },
      "output_tokens": 10,
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

_source line 31_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01D2WpT8fPCVjdk33QzakY7r`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "head -n 170 /root/contamcal-irt-calibration/exp001/prepare_sft_data.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "b5cf1193-eb67-4480-9dd5-2c5179e94f27",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F8uWzyY3pi4x2TGnfhujbZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3585,
      "cache_read_input_tokens": 31806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3585
      },
      "output_tokens": 10,
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

_source line 32 · 2026-05-14T00:58:12.904Z_

<details><summary>↩ Tool result · `toolu_01D2WpT8fPCVjdk33QzakY7r`</summary>

````text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nSFT training data preparation with controlled contamination injection.\\n\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\n\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\nOutput: JSONL files with chat-format messages for each dosage level\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport random\\nfrom pathlib import Path\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\n\\nBENCHMARK_TO_QA = {\\n    \\\"mmlu\\\": \\\"mcq\\\",\\n    \\\"arc_challenge\\\": \\\"mcq\\\",\\n    \\\"gsm8k\\\": \\\"math\\\",\\n    \\\"humaneval\\\": \\\"code\\\",\\n}\\n\\n\\ndef format_mcq_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", \\\"\\\")\\n    choices = parsed.get(\\\"choices\\\", [])\\n    answer = parsed.get(\\\"answer\\\", \\\"\\\")\\n\\n    if isinstance(choices, list):\\n        choices_str = \\\"\\\\n\\\".join(choices)\\n    else:\\n        choices_str = str(choices)\\n\\n    user_msg = f\\\"Question: {question}\\\\n{choices_str}\\\"\\n    assistant_msg = f\\\"The answer is {answer}.\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\ndef format_math_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or {}\\n    original = item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", original.get(\\\"question\\\", \\\"\\\"))\\n    answer = original.get(\\\"full_answer\\\", original.get(\\\"answer\\\", \\\"\\\"))\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": question},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": answer},\\n        ]\\n    }\\n\\n\\ndef format_code_as_chat(item: dict) -> dict:\\n    original = item.get(\\\"original\\\", {})\\n    paraphrased_prompt = item.get(\\\"paraphrased_prompt\\\", original.get(\\\"prompt\\\", \\\"\\\"))\\n    solution = original.get(\\\"canonical_solution\\\", \\\"\\\")\\n\\n    user_msg = f\\\"Complete the following Python function:\\\\n\\\\n```python\\\\n{paraphrased_prompt}```\\\"\\n    assistant_msg = f\\\"```python\\\\n{paraphrased_prompt}{solution}```\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\nFORMAT_FNS = {\\n    \\\"mcq\\\": format_mcq_as_chat,\\n    \\\"math\\\": format_math_as_chat,\\n    \\\"code\\\": format_code_as_chat,\\n}\\n\\n\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\n    \\\"\\\"\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\n\\n    Returns:\\n        (paraphrases dict, qc_stats dict)\\n    \\\"\\\"\\\"\\n    paraphrase_dir = Path(paraphrase_dir)\\n    all_paraphrases = {}\\n    qc_stats = {}\\n\\n    for f in sorted(paraphrase_dir.glob(\\\"*_paraphrases.json\\\")):\\n        benchmark = f.stem.replace(\\\"_paraphrases\\\", \\\"\\\")\\n        if benchmarks and benchmark not in benchmarks:\\n            continue\\n        with open(f) as fh:\\n            data = json.load(fh)\\n        qc_passed = sum(1 for item in data if item.get(\\\"passed_qc\\\", False))\\n        qc_stats[benchmark] = {\\n            \\\"total\\\": len(data),\\n            \\\"qc_passed\\\": qc_passed,\\n            \\\"qc_failed\\\": len(data) - qc_passed,\\n            \\\"pass_rate\\\": round(qc_passed / len(data), 4) if data else 0,\\n        }\\n        all_paraphrases[benchmark] = data\\n        logger.info(\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\",\\n                     len(data), benchmark, qc_passed, len(data))\\n\\n    return all_paraphrases, qc_stats\\n\\n\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\n    \\\"\\\"\\\"Load base SFT data from local JSONL file.\\\"\\\"\\\"\\n    data = []\\n    with open(path) as f:\\n        for line in f:\\n            line = line.strip()\\n            if line:\\n                data.append(json.loads(line))\\n    logger.info(\\\"Loaded %d base SFT samples from %s\\\", len(data), path)\\n    return data\\n\\n\\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\\n    \\\"\\\"\\\"Convert all paraphrases to chat message format.\\n\\n    Each item carries _source (benchmark) and _orig_index for contamination label tracking.\\n    \\\"\\\"\\\"\\n    chat_items = []\\n    for benchmark, items in paraphrases.items():\\n        qa_type = BENCHMARK_TO_QA.get(benchmark, \\\"mcq\\\")\\n        format_fn = FORMAT_FNS[qa_type]\\n        for item in items:\\n            chat_item = format_fn(item)\\n            chat_item[\\\"_source\\\"] = benchmark\\n            chat_item[\\\"_orig_index\\\"] = item.get(\\\"index\\\", len(chat_items))\\n            chat_items.append(chat_item)\\n    return chat_items\\n\\n\\ndef mix_data(base_data: list[dict], contam_data: list[dict], dosage: int,\\n             seed: int) -> tuple[list[dict], list[dict]]:\\n    \\\"\\\"\\\"Mix contamination data into base data at specified dosage level.\\n\\n    dosage=N means N% of contam_data items are included.\\n    \\\"\\\"\\\"\\n    rng = random.Random(seed)\\n\\n    if dosage == 0:\\n        mixed = list(base_data)\\n        selected = []\\n    elif dosage == 100:\\n        selected = list(contam_data)\\n        mixed = list(base_data) + selected\\n    else:\\n        n_contam = max(1, int(len(contam_data) * dosage / 100))\\n        selected = rng.sample(contam_data, min(n_contam, len(contam_data)))\\n        mixed = list(base_data) + selected\\n\\n    rng.shuffle(mixed)\\n    return mixed, selected\\n\\n\\ndef write_jsonl(data: list[dict], output_path: Path):\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"}
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "9492b51b-81d5-4d22-a1e9-864fad09e425",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"\\\\nSFT training data preparation with controlled contamination injection.\\\\n\\\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\\\n\\\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\\\nOutput: JSONL files with chat-format messages for each dosage level\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport random\\\\nfrom pathlib import Path\\\\n\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\\\n\\\\nBENCHMARK_TO_QA = {\\\\n    \\\\\\\"mmlu\\\\\\\": \\\\\\\"mcq\\\\\\\",\\\\n    \\\\\\\"arc_challenge\\\\\\\": \\\\\\\"mcq\\\\\\\",\\\\n    \\\\\\\"gsm8k\\\\\\\": \\\\\\\"math\\\\\\\",\\\\n    \\\\\\\"humaneval\\\\\\\": \\\\\\\"code\\\\\\\",\\\\n}\\\\n\\\\n\\\\ndef format_mcq_as_chat(item: dict) -> dict:\\\\n    parsed = item.get(\\\\\\\"paraphrase_parsed\\\\\\\") or item.get(\\\\\\\"original\\\\\\\", {})\\\\n    question = parsed.get(\\\\\\\"question\\\\\\\", \\\\\\\"\\\\\\\")\\\\n    choices = parsed.get(\\\\\\\"choices\\\\\\\", [])\\\\n    answer = parsed.get(\\\\\\\"answer\\\\\\\", \\\\\\\"\\\\\\\")\\\\n\\\\n    if isinstance(choices, list):\\\\n        choices_str = \\\\\\\"\\\\\\\\n\\\\\\\".join(choices)\\\\n    else:\\\\n        choices_str = str(choices)\\\\n\\\\n    user_msg = f\\\\\\\"Question: {question}\\\\\\\\n{choices_str}\\\\\\\"\\\\n    assistant_msg = f\\\\\\\"The answer is {answer}.\\\\\\\"\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": user_msg},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": assistant_msg},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\ndef format_math_as_chat(item: dict) -> dict:\\\\n    parsed = item.get(\\\\\\\"paraphrase_parsed\\\\\\\") or {}\\\\n    original = item.get(\\\\\\\"original\\\\\\\", {})\\\\n    question = parsed.get(\\\\\\\"question\\\\\\\", original.get(\\\\\\\"question\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n    answer = original.get(\\\\\\\"full_answer\\\\\\\", original.get(\\\\\\\"answer\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": question},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": answer},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\ndef format_code_as_chat(item: dict) -> dict:\\\\n    original = item.get(\\\\\\\"original\\\\\\\", {})\\\\n    paraphrased_prompt = item.get(\\\\\\\"paraphrased_prompt\\\\\\\", original.get(\\\\\\\"prompt\\\\\\\", \\\\\\\"\\\\\\\"))\\\\n    solution = original.get(\\\\\\\"canonical_solution\\\\\\\", \\\\\\\"\\\\\\\")\\\\n\\\\n    user_msg = f\\\\\\\"Complete the following Python function:\\\\\\\\n\\\\\\\\n```python\\\\\\\\n{paraphrased_prompt}```\\\\\\\"\\\\n    assistant_msg = f\\\\\\\"```python\\\\\\\\n{paraphrased_prompt}{solution}```\\\\\\\"\\\\n\\\\n    return {\\\\n        \\\\\\\"messages\\\\\\\": [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": user_msg},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": assistant_msg},\\\\n        ]\\\\n    }\\\\n\\\\n\\\\nFORMAT_FNS = {\\\\n    \\\\\\\"mcq\\\\\\\": format_mcq_as_chat,\\\\n    \\\\\\\"math\\\\\\\": format_math_as_chat,\\\\n    \\\\\\\"code\\\\\\\": format_code_as_chat,\\\\n}\\\\n\\\\n\\\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\\\n\\\\n    Returns:\\\\n        (paraphrases dict, qc_stats dict)\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    paraphrase_dir = Path(paraphrase_dir)\\\\n    all_paraphrases = {}\\\\n    qc_stats = {}\\\\n\\\\n    for f in sorted(paraphrase_dir.glob(\\\\\\\"*_paraphrases.json\\\\\\\")):\\\\n        benchmark = f.stem.replace(\\\\\\\"_paraphrases\\\\\\\", \\\\\\\"\\\\\\\")\\\\n        if benchmarks and benchmark not in benchmarks:\\\\n            continue\\\\n        with open(f) as fh:\\\\n            data = json.load(fh)\\\\n        qc_passed = sum(1 for item in data if item.get(\\\\\\\"passed_qc\\\\\\\", False))\\\\n        qc_stats[benchmark] = {\\\\n            \\\\\\\"total\\\\\\\": len(data),\\\\n            \\\\\\\"qc_passed\\\\\\\": qc_passed,\\\\n            \\\\\\\"qc_failed\\\\\\\": len(data) - qc_passed,\\\\n            \\\\\\\"pass_rate\\\\\\\": round(qc_passed / len(data), 4) if data else 0,\\\\n        }\\\\n        all_paraphrases[benchmark] = data\\\\n        logger.info(\\\\\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\\\\\",\\\\n                     len(data), benchmark, qc_passed, len(data))\\\\n\\\\n    return all_paraphrases, qc_stats\\\\n\\\\n\\\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load base SFT data from local JSONL file.\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    data = []\\\\n    with open(path) as f:\\\\n        for line in f:\\\\n            line = line.strip()\\\\n            if line:\\\\n                data.append(json.loads(line))\\\\n    logger.info(\\\\\\\"Loaded %d base SFT samples from %s\\\\\\\", len(data), path)\\\\n    return data\\\\n\\\\n\\\\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Convert all paraphrases to chat message format.\\\\n\\\\n    Each item carries _source (benchmark) and _orig_index for contamination label tracking.\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    chat_items = []\\\\n    for benchmark, items in paraphrases.items():\\\\n        qa_type = BENCHMARK_TO_QA.get(benchmark, \\\\\\\"mcq\\\\\\\")\\\\n        format_fn = FORMAT_FNS[qa_type]\\\\n        for item in items:\\\\n            chat_item = format_fn(item)\\\\n            chat_item[\\\\\\\"_source\\\\\\\"] = benchmark\\\\n            chat_item[\\\\\\\"_orig_index\\\\\\\"] = item.get(\\\\\\\"index\\\\\\\", len(chat_items))\\\\n            chat_items.append(chat_item)\\\\n    return chat_items\\\\n\\\\n\\\\ndef mix_data(base_data: list[dict], contam_data: list[dict], dosage: int,\\\\n             seed: int) -> tuple[list[dict], list[dict]]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Mix contamination data into base data at specified dosage level.\\\\n\\\\n    dosage=N means N% of contam_data items are included.\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    rng = random.Random(seed)\\\\n\\\\n    if dosage == 0:\\\\n        mixed = list(base_data)\\\\n        selected = []\\\\n    elif dosage == 100:\\\\n        selected = list(contam_data)\\\\n        mixed = list(base_data) + selected\\\\n    else:\\\\n        n_contam = max(1, int(len(contam_data) * dosage / 100))\\\\n        selected = rng.sample(contam_data, min(n_contam, len(contam_data)))\\\\n        mixed = list(base_data) + selected\\\\n\\\\n    rng.shuffle(mixed)\\\\n    return mixed, selected\\\\n\\\\n\\\\ndef write_jsonl(data: list[dict], output_path: Path):\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.38}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nSFT training data preparation with controlled contamination injection.\\n\\nMixes paraphrased benchmark items into a base SFT dataset at various dosage\\nlevels (0%, 5%, 25%, 50%, 100% of benchmark items).\\n\\nInput:  Paraphrase JSONs from paraphrase_gen.py + base SFT dataset (local JSONL)\\nOutput: JSONL files with chat-format messages for each dosage level\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport random\\nfrom pathlib import Path\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOSAGE_LEVELS = [0, 5, 25, 50, 100]\\n\\nBENCHMARK_TO_QA = {\\n    \\\"mmlu\\\": \\\"mcq\\\",\\n    \\\"arc_challenge\\\": \\\"mcq\\\",\\n    \\\"gsm8k\\\": \\\"math\\\",\\n    \\\"humaneval\\\": \\\"code\\\",\\n}\\n\\n\\ndef format_mcq_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", \\\"\\\")\\n    choices = parsed.get(\\\"choices\\\", [])\\n    answer = parsed.get(\\\"answer\\\", \\\"\\\")\\n\\n    if isinstance(choices, list):\\n        choices_str = \\\"\\\\n\\\".join(choices)\\n    else:\\n        choices_str = str(choices)\\n\\n    user_msg = f\\\"Question: {question}\\\\n{choices_str}\\\"\\n    assistant_msg = f\\\"The answer is {answer}.\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\ndef format_math_as_chat(item: dict) -> dict:\\n    parsed = item.get(\\\"paraphrase_parsed\\\") or {}\\n    original = item.get(\\\"original\\\", {})\\n    question = parsed.get(\\\"question\\\", original.get(\\\"question\\\", \\\"\\\"))\\n    answer = original.get(\\\"full_answer\\\", original.get(\\\"answer\\\", \\\"\\\"))\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": question},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": answer},\\n        ]\\n    }\\n\\n\\ndef format_code_as_chat(item: dict) -> dict:\\n    original = item.get(\\\"original\\\", {})\\n    paraphrased_prompt = item.get(\\\"paraphrased_prompt\\\", original.get(\\\"prompt\\\", \\\"\\\"))\\n    solution = original.get(\\\"canonical_solution\\\", \\\"\\\")\\n\\n    user_msg = f\\\"Complete the following Python function:\\\\n\\\\n```python\\\\n{paraphrased_prompt}```\\\"\\n    assistant_msg = f\\\"```python\\\\n{paraphrased_prompt}{solution}```\\\"\\n\\n    return {\\n        \\\"messages\\\": [\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": user_msg},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": assistant_msg},\\n        ]\\n    }\\n\\n\\nFORMAT_FNS = {\\n    \\\"mcq\\\": format_mcq_as_chat,\\n    \\\"math\\\": format_math_as_chat,\\n    \\\"code\\\": format_code_as_chat,\\n}\\n\\n\\ndef load_paraphrases(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict]:\\n    \\\"\\\"\\\"Load ALL paraphrase JSONs (no QC filtering per D010).\\n\\n    Returns:\\n        (paraphrases dict, qc_stats dict)\\n    \\\"\\\"\\\"\\n    paraphrase_dir = Path(paraphrase_dir)\\n    all_paraphrases = {}\\n    qc_stats = {}\\n\\n    for f in sorted(paraphrase_dir.glob(\\\"*_paraphrases.json\\\")):\\n        benchmark = f.stem.replace(\\\"_paraphrases\\\", \\\"\\\")\\n        if benchmarks and benchmark not in benchmarks:\\n            continue\\n        with open(f) as fh:\\n            data = json.load(fh)\\n        qc_passed = sum(1 for item in data if item.get(\\\"passed_qc\\\", False))\\n        qc_stats[benchmark] = {\\n            \\\"total\\\": len(data),\\n            \\\"qc_passed\\\": qc_passed,\\n            \\\"qc_failed\\\": len(data) - qc_passed,\\n            \\\"pass_rate\\\": round(qc_passed / len(data), 4) if data else 0,\\n        }\\n        all_paraphrases[benchmark] = data\\n        logger.info(\\\"Loaded %d paraphrases for %s (QC passed: %d/%d, using ALL per D010)\\\",\\n                     len(data), benchmark, qc_passed, len(data))\\n\\n    return all_paraphrases, qc_stats\\n\\n\\ndef load_base_from_jsonl(path: str) -> list[dict]:\\n    \\\"\\\"\\\"Load base SFT data from local JSONL file.\\\"\\\"\\\"\\n    data = []\\n    with open(path) as f:\\n        for line in f:\\n            line = line.strip()\\n            if line:\\n                data.append(json.loads(line))\\n    logger.info(\\\"Loaded %d base SFT samples from %s\\\", len(data), path)\\n    return data\\n\\n\\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\\n    \\\"\\\"\\\"Convert all paraphrases to chat message format.\\n\\n    Each item carries _source (benchmark) and _orig_index for contamination label tracking.\\n    \\\"\\\"\\\"\\n    chat_items = []\\n    for benchmark, items in paraphrases.items():\\n        qa_type = BENCHMARK_TO_QA.get(benchmark, \\\"mcq\\\")\\n        format_fn = FORMAT_FNS[qa_type]\\n        for item in items:\\n            chat_item = format_fn(item)\\n            chat_item[\\\"_source\\\"] = benchmark\\n            chat_item[\\\"_orig_index\\\"] = item.get(\\\"index\\\", len(chat_items))\\n            chat_items.append(chat_item)\\n    return chat_items\\n\\n\\ndef mix_data(base_data: list[dict], contam_data: list[dict], dosage: int,\\n             seed: int) -> tuple[list[dict], list[dict]]:\\n    \\\"\\\"\\\"Mix contamination data into base data at specified dosage level.\\n\\n    dosage=N means N% of contam_data items are included.\\n    \\\"\\\"\\\"\\n    rng = random.Random(seed)\\n\\n    if dosage == 0:\\n        mixed = list(base_data)\\n        selected = []\\n    elif dosage == 100:\\n        selected = list(contam_data)\\n        mixed = list(base_data) + selected\\n    else:\\n        n_contam = max(1, int(len(contam_data) * dosage / 100))\\n        selected = rng.sample(contam_data, min(n_contam, len(contam_data)))\\n        mixed = list(base_data) + selected\\n\\n    rng.shuffle(mixed)\\n    return mixed, selected\\n\\n\\ndef write_jsonl(data: list[dict], output_path: Path):\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"
    }
  }
}
````

</details>

---

### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Read · `toolu_01LuPfehgFDdrEGz4ZNLugBB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/experiment_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "6af7aa5a-6527-45a5-b6ba-57d5270eb49b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F8uWzyY3pi4x2TGnfhujbZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3585,
      "cache_read_input_tokens": 31806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3585
      },
      "output_tokens": 10,
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

_source line 34 · 2026-05-14T00:58:13.537Z_

<details><summary>↩ Tool result · `toolu_01LuPfehgFDdrEGz4ZNLugBB`</summary>

```text
1	# ContamCal Experiment Plan
2	# Each experiment maps to Core Claims in paper_framing.md
3	# Priority: P0 = must-run, P1 = important, P2 = bonus
4	
5	experiments:
6	  # ============================================================
7	  # P0: Core experiments — must complete for submission
8	  # ============================================================
9	
10	  - id: exp-001
11	    name: controlled_sft_injection
12	    claim: [1]
13	    description: >
14	      SFT contamination injection on Qwen2.5-0.5B/1.5B/3B at 5 dosage levels
15	      (0%, 5%, 25%, 50%, 100% benchmark items as paraphrases in SFT data).
16	      Produces ground-truth contaminated/clean model pairs. 15 SFT runs total
17	      (3 models × 5 dosages), parallelized across GPUs. 3 seeds per condition
18	      for key metrics (mean ± std).
19	      Paraphrase generation: use strong open LLM (Qwen2.5-72B-Instruct or
20	      equivalent) with controlled semantic similarity — following methodology
21	      of "Rethinking Benchmark and Contamination" (arXiv 2023). Target:
22	      high semantic similarity (cosine >0.85) but low lexical overlap
23	      (BLEU <0.3) to evade n-gram decontamination while preserving
24	      contamination effect. Quality validation: automated similarity metrics
25	      + human spot-check on 50 random pairs per benchmark.
26	    priority: P0
27	    gpu_budget_hours: 50
28	    deps: []
29	    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]
30	    models: [Qwen2.5-0.5B, Qwen2.5-1.5B, Qwen2.5-3B]
31	    seeds: 3
32	    registry_id:
33	      - exp_001_sft_injection        # paraphrase generation + data prep
34	      - exp_001_sft_0pct_05B         # 0.5B s42 baseline (DONE/success)
35	      - exp_001_sft_0pct_15B         # 1.5B s42 baseline (DONE/success)
36	      - exp_001_sft_0pct_3B          # 3B s42 baseline (RUNNING)
37	      - exp_001_sft_0pct_05B_s123    # 0.5B s123 baseline (RUNNING)
38	      - exp_001_sft_0pct_15B_s123    # 1.5B s123 baseline (RUNNING)
39	      - exp_001_sft_0pct_3B_s123     # 3B s123 baseline (RUNNING)
40	      - exp_001_eval_15B_d000_s42    # 1.5B eval (RUNNING)
41	
42	  - id: exp-002
43	    name: stage1_signal_pipeline
44	    claim: [2]
45	    description: >
46	      Compute 4 detection signals on all contaminated + clean models from exp-001:
47	      (a) embedding-based semantic retrieval (FAISS + sentence-transformers),
48	      (b) Min-K%++ membership inference,
49	      (c) ConStat performance gap (original vs paraphrased items),
50	      (d) Self-Critique entropy collapse.
51	      Output: per-model-item exposure scores for each signal.
52	    priority: P0
53	    gpu_budget_hours: 20
54	    deps: [exp-001]
55	
56	  - id: exp-003
57	    name: rrf_aggregation_ablation
58	    claim: [2]
59	    description: >
60	      RRF fusion of 4 signals into composite per-item exposure score.
61	      Ablations: (a) RRF vs equal-weight rank averaging, (b) single-signal only
62	      (×4), (c) calibration-based weighted RRF variant, (d) false positive
63	      injection robustness check (inject FP at rates matching Duan et al. 2024).
64	      Also test degraded 2-signal mode (ConStat + Self-Critique) for closed-weight.
65	    priority: P0
66	    gpu_budget_hours: 2
67	    deps: [exp-002]
68	
69	  - id: exp-004
70	    name: simulation_identifiability_sweep
71	    claim: [1, 3]
72	    description: >
73	      Systematic synthetic-data sweep (NEW, not MVP — MVP only covered 4-5 conditions):
74	      exposure signal AUC (0.55, 0.60, 0.65, 0.70, 0.80, 0.90) ×
75	      model count (20, 50, 100, 200) ×
76	      prior strength (N(0,0.5), N(0,1), N(0,2)) ×
77	      exposure type (binary, continuous).
78	      144 conditions, 10 seeds each. Reports: θ-γ recovery RMSE, posterior
79	      correlation, coverage (50%/80%/95%), prior sensitivity. Establishes
80	      minimum AUC threshold; if 95% CI width > 15pp at AUC=0.65, label as
81	      "cannot distinguish no contamination from moderate contamination."
82	      N_items=300 fixed (per MVP finding).
83	      Subsumes exp-010 (prior sensitivity) and exp-011 (few-examinee regime)
84	      — prior × N_models dimensions already in sweep grid. Growing Pains
85	      pre-estimation sub-experiment: at N_models=20/50, compare flat prior
86	      vs informative prior from pre-estimated item parameters.
87	      Also includes Fisher Information matrix analysis: derive approximate
88	      analytical relationship between signal AUC, N_models, and γ
89	      recoverability. Distinguish structural identifiability (parameters
90	      uniquely determined) from practical identifiability (estimation
91	      quality sufficient for decisions). Provides theoretical grounding
92	      for the empirical AUC ≥ 0.70 threshold.
93	    priority: P0
94	    gpu_budget_hours: 0
95	    deps: []
96	    note: CPU only. MVP (mvp_sim_4pl_gamma) was preliminary; this is the full sweep.
97	    registry_id:
98	      - exp_004_sim_sweep            # full sweep (RUNNING)
99	      - mvp_sim_4pl_gamma            # MVP predecessor (DONE/success)
100	      - mvp_sim_confounding          # MVP confounding test (DONE/success)
101	
102	  - id: exp-005
103	    name: noise_propagation_analysis
104	    claim: [3]
105	    description: >
106	      Two parts:
107	      (A) Measurement error model (PRIMARY): extend Stan model to treat exposure
108	      as noisy observation: exposure_ij ~ N(τ_ij, σ_e²), where τ is latent true
109	      contamination. σ_e estimated from exp-001 ground truth FP/FN rates.
110	      This propagates Stage 1 uncertainty into posteriors automatically.
111	      Compare coverage (50%/80%/95%) vs point-estimate exposure baseline.
112	      (B) Post-hoc noise injection: inject Gaussian noise at 1×/1.5×/2× matched
113	      levels, re-fit standard model, measure CI widening for γ and θ.
114	      Both parts inform whether measurement error model closes the coverage gap.
115	    priority: P0
116	    gpu_budget_hours: 0
117	    deps: [exp-002, exp-004]
118	    note: CPU only
119	    registry_id:
120	      - exp_005_noise_prop_v2        # v2 with Stan fixes (RUNNING)
121	      - exp_005_noise_prop            # v1 failed (DONE/failed, sigma_e=0 bug)
122	
123	  - id: exp-006
124	    name: irt_calibration_and_baselines
125	    claim: [1, 3]
126	    description: >
127	      Fit 4PL+γ IRT (Stan NUTS) on controlled models from exp-001/003.
128	      PRIMARY: per-benchmark fitting with benchmark-specific γ_k — this is
129	      the natural parameterization when IRT is fitted per-benchmark (each
130	      benchmark's model has its own γ_k). ABLATION: joint fitting across
131	      benchmarks with shared global γ (stronger assumption, tests whether
132	      contamination effect is homogeneous across benchmarks). Report both.
133	      Per-benchmark fitting (not joint) is the default to reduce local
134	      independence violation scope. Posterior predictive checks on item-level residual
135	      correlations to assess local independence empirically.
136	      Compute calibrated scores via exposure=0 counterfactual with CIs.
137	      Compare against 7 baselines:
138	      (0) Raw — no adjustment (anchor),
139	      (1) remove-and-rescore (drop flagged items),
140	      (2) single-signal 2PL+γ (best signal only, simpler IRT),
141	      (3) vanilla 4PL without γ (standard IRT, no contamination modeling),
142	      (4) linear exposure regression + bootstrap CI (simplest post-hoc),
143	      (5) Emperor's mitigation: rephrasing + option shuffling,
144	      (6) DCR fuzzy inference (EMNLP 2025) — the only existing method
145	          producing adjusted accuracy; must include or reviewers will reject.
146	      Evaluate all 5 metrics: MAE, coverage (50%/80%/95%), sharpness,
147	      Kendall τ, dose-response monotonicity.
148	      Report mean ± std across 3 seeds (matched to exp-001 seeds).
149	    priority: P0
150	    gpu_budget_hours: 8
151	    deps: [exp-003]
152	    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]
153	    seeds: 3
154	
155	  # ============================================================
156	  # P1: Important — run if time/GPU permit
157	  # ============================================================
158	
159	  - id: exp-007
160	    name: scale_bridging_7b
161	    claim: [1]
162	    description: >
163	      Qwen2.5-7B controlled SFT injection at 5 dosage levels.
164	      Validates calibration accuracy scales to larger models.
165	      Requires multi-GPU node (7B LoRA SFT ~4-8h per run on 1×H100).
166	    priority: P1
167	    gpu_budget_hours: 30
168	    deps: [exp-001]
169	
170	  - id: exp-008
171	    name: signal_survival_analysis
172	    claim: [2]
173	    description: >
174	      Systematic evaluation of detection signal reliability across training regimes.
175	      Signal × regime AUC heatmap: 4 signals × {base, SFT-clean, SFT-contaminated,
176	      RL-post-trained}. Confirms Self-Critique compensates where Min-K%++/ConStat
177	      degrade post-RL (per fragility paper arXiv 2510.02386).
178	      ELEVATED to Core Contribution 2 per Dream review (all 3 tiers identified
179	      this as the most genuinely novel finding).
180	    priority: P0
181	    gpu_budget_hours: 10
182	    deps: [exp-002]
183	
184	  - id: exp-014
185	    name: multi_family_validation
186	    claim: [1]
187	    description: >
188	      Controlled SFT injection on at least one non-Qwen model family
189	      (Llama-3.2-1B or Pythia-1.4B) at 3 dosage levels (0%, 25%, 100%).
190	      Validates that identifiability boundaries and calibration accuracy
191	      generalize beyond Qwen2.5. Addresses Dream reviewer concern about
192	      single model family limiting generalizability (flagged [M][W]).
193	    priority: P1
194	    gpu_budget_hours: 15
195	    deps: [exp-001]
196	
197	  - id: exp-009
198	    name: rl_observational_case_study
199	    claim: [2, 3]
200	    description: >
201	      Apply Self-Critique + available signals to existing RL-trained models:
202	      Qwen2.5-Instruct (0.5B/1.5B/3B/7B), DeepSeek-R1-Distill-1.5B/7B.
203	      Fit IRT with appropriately wider CIs. Expected regret quantification:
204	      compare uncalibrated vs calibrated vs remove-rescore for top-5 model
205	      selection. Framed as observational — directional external validity,
206	      not full quantitative validation. Near-zero γ check on known-clean
207	      benchmark (specificity test).
208	    priority: P1
209	    gpu_budget_hours: 15
210	    deps: [exp-006, exp-008]
211	
212	  # exp-010 (prior_sensitivity) and exp-011 (few_examinee_regime) merged into exp-004.
213	  # Prior × N_models dimensions already covered in the sweep grid.
214	
215	  # ============================================================
216	  # P2: Bonus — adds breadth if resources allow
217	  # ============================================================
218	
219	  - id: exp-012
220	    name: observational_72b
221	    claim: [1]
222	    description: >
223	      Qwen2.5-72B observational analysis (inference only, no SFT).
224	      Extends ecological validity to frontier model scale.
225	    priority: P2
226	    gpu_budget_hours: 15
227	    deps: [exp-006]
228	
229	  - id: exp-013
230	    name: closed_weight_2signal_mode
231	    claim: [2]
232	    description: >
233	      Degraded 2-signal mode (ConStat + Self-Critique, no logits/embeddings)
234	      for closed-weight models. Ablation quantifying 2-signal vs 4-signal
235	      calibration accuracy gap.
236	    priority: P2
237	    gpu_budget_hours: 5
238	    deps: [exp-003]
239	
240	# ============================================================
241	# GPU Budget Summary
242	# ============================================================
243	gpu_budget:
244	  P0_hours: 90
245	  P1_hours: 60
246	  P2_hours: 20
247	  buffer_hours: 30
248	  total_hours: 200
249	  note: >
250	    CPU-only experiments (exp-004, exp-005, exp-011) excluded.
251	    Buffer covers reruns, debugging, multi-seed overhead, and unexpected issues.
252	    Requires 2-4× H100/A100-80G for parallel SFT runs.
253	    EMNLP 2026 ARR May 25 sprint (12 days from May 13):
254	    - With 4× H100: P0 in ~4 days, P1 in ~3 days, total ~8 days (fits deadline)
255	    - With 2× H100: P0 in ~7 days, P1 in ~4 days, tight but feasible if parallelized
256	    - Day-8 contingency: reduce benchmarks to MMLU + GSM8K if behind schedule
257	
258	# Multi-seed protocol:
259	# - exp-001, exp-006: 3 seeds, report mean ± std for key metrics
260	# - exp-004, exp-005, exp-011: 10 seeds (simulation, CPU)
261	# - exp-007, exp-008, exp-009: 1 seed (resource-constrained, note as limitation if needed)
262	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "03826914-6ccc-4318-809b-37332f46e301",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/experiment_plan.yaml",
      "content": "# ContamCal Experiment Plan\n# Each experiment maps to Core Claims in paper_framing.md\n# Priority: P0 = must-run, P1 = important, P2 = bonus\n\nexperiments:\n  # ============================================================\n  # P0: Core experiments — must complete for submission\n  # ============================================================\n\n  - id: exp-001\n    name: controlled_sft_injection\n    claim: [1]\n    description: >\n      SFT contamination injection on Qwen2.5-0.5B/1.5B/3B at 5 dosage levels\n      (0%, 5%, 25%, 50%, 100% benchmark items as paraphrases in SFT data).\n      Produces ground-truth contaminated/clean model pairs. 15 SFT runs total\n      (3 models × 5 dosages), parallelized across GPUs. 3 seeds per condition\n      for key metrics (mean ± std).\n      Paraphrase generation: use strong open LLM (Qwen2.5-72B-Instruct or\n      equivalent) with controlled semantic similarity — following methodology\n      of \"Rethinking Benchmark and Contamination\" (arXiv 2023). Target:\n      high semantic similarity (cosine >0.85) but low lexical overlap\n      (BLEU <0.3) to evade n-gram decontamination while preserving\n      contamination effect. Quality validation: automated similarity metrics\n      + human spot-check on 50 random pairs per benchmark.\n    priority: P0\n    gpu_budget_hours: 50\n    deps: []\n    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]\n    models: [Qwen2.5-0.5B, Qwen2.5-1.5B, Qwen2.5-3B]\n    seeds: 3\n    registry_id:\n      - exp_001_sft_injection        # paraphrase generation + data prep\n      - exp_001_sft_0pct_05B         # 0.5B s42 baseline (DONE/success)\n      - exp_001_sft_0pct_15B         # 1.5B s42 baseline (DONE/success)\n      - exp_001_sft_0pct_3B          # 3B s42 baseline (RUNNING)\n      - exp_001_sft_0pct_05B_s123    # 0.5B s123 baseline (RUNNING)\n      - exp_001_sft_0pct_15B_s123    # 1.5B s123 baseline (RUNNING)\n      - exp_001_sft_0pct_3B_s123     # 3B s123 baseline (RUNNING)\n      - exp_001_eval_15B_d000_s42    # 1.5B eval (RUNNING)\n\n  - id: exp-002\n    name: stage1_signal_pipeline\n    claim: [2]\n    description: >\n      Compute 4 detection signals on all contaminated + clean models from exp-001:\n      (a) embedding-based semantic retrieval (FAISS + sentence-transformers),\n      (b) Min-K%++ membership inference,\n      (c) ConStat performance gap (original vs paraphrased items),\n      (d) Self-Critique entropy collapse.\n      Output: per-model-item exposure scores for each signal.\n    priority: P0\n    gpu_budget_hours: 20\n    deps: [exp-001]\n\n  - id: exp-003\n    name: rrf_aggregation_ablation\n    claim: [2]\n    description: >\n      RRF fusion of 4 signals into composite per-item exposure score.\n      Ablations: (a) RRF vs equal-weight rank averaging, (b) single-signal only\n      (×4), (c) calibration-based weighted RRF variant, (d) false positive\n      injection robustness check (inject FP at rates matching Duan et al. 2024).\n      Also test degraded 2-signal mode (ConStat + Self-Critique) for closed-weight.\n    priority: P0\n    gpu_budget_hours: 2\n    deps: [exp-002]\n\n  - id: exp-004\n    name: simulation_identifiability_sweep\n    claim: [1, 3]\n    description: >\n      Systematic synthetic-data sweep (NEW, not MVP — MVP only covered 4-5 conditions):\n      exposure signal AUC (0.55, 0.60, 0.65, 0.70, 0.80, 0.90) ×\n      model count (20, 50, 100, 200) ×\n      prior strength (N(0,0.5), N(0,1), N(0,2)) ×\n      exposure type (binary, continuous).\n      144 conditions, 10 seeds each. Reports: θ-γ recovery RMSE, posterior\n      correlation, coverage (50%/80%/95%), prior sensitivity. Establishes\n      minimum AUC threshold; if 95% CI width > 15pp at AUC=0.65, label as\n      \"cannot distinguish no contamination from moderate contamination.\"\n      N_items=300 fixed (per MVP finding).\n      Subsumes exp-010 (prior sensitivity) and exp-011 (few-examinee regime)\n      — prior × N_models dimensions already in sweep grid. Growing Pains\n      pre-estimation sub-experiment: at N_models=20/50, compare flat prior\n      vs informative prior from pre-estimated item parameters.\n      Also includes Fisher Information matrix analysis: derive approximate\n      analytical relationship between signal AUC, N_models, and γ\n      recoverability. Distinguish structural identifiability (parameters\n      uniquely determined) from practical identifiability (estimation\n      quality sufficient for decisions). Provides theoretical grounding\n      for the empirical AUC ≥ 0.70 threshold.\n    priority: P0\n    gpu_budget_hours: 0\n    deps: []\n    note: CPU only. MVP (mvp_sim_4pl_gamma) was preliminary; this is the full sweep.\n    registry_id:\n      - exp_004_sim_sweep            # full sweep (RUNNING)\n      - mvp_sim_4pl_gamma            # MVP predecessor (DONE/success)\n      - mvp_sim_confounding          # MVP confounding test (DONE/success)\n\n  - id: exp-005\n    name: noise_propagation_analysis\n    claim: [3]\n    description: >\n      Two parts:\n      (A) Measurement error model (PRIMARY): extend Stan model to treat exposure\n      as noisy observation: exposure_ij ~ N(τ_ij, σ_e²), where τ is latent true\n      contamination. σ_e estimated from exp-001 ground truth FP/FN rates.\n      This propagates Stage 1 uncertainty into posteriors automatically.\n      Compare coverage (50%/80%/95%) vs point-estimate exposure baseline.\n      (B) Post-hoc noise injection: inject Gaussian noise at 1×/1.5×/2× matched\n      levels, re-fit standard model, measure CI widening for γ and θ.\n      Both parts inform whether measurement error model closes the coverage gap.\n    priority: P0\n    gpu_budget_hours: 0\n    deps: [exp-002, exp-004]\n    note: CPU only\n    registry_id:\n      - exp_005_noise_prop_v2        # v2 with Stan fixes (RUNNING)\n      - exp_005_noise_prop            # v1 failed (DONE/failed, sigma_e=0 bug)\n\n  - id: exp-006\n    name: irt_calibration_and_baselines\n    claim: [1, 3]\n    description: >\n      Fit 4PL+γ IRT (Stan NUTS) on controlled models from exp-001/003.\n      PRIMARY: per-benchmark fitting with benchmark-specific γ_k — this is\n      the natural parameterization when IRT is fitted per-benchmark (each\n      benchmark's model has its own γ_k). ABLATION: joint fitting across\n      benchmarks with shared global γ (stronger assumption, tests whether\n      contamination effect is homogeneous across benchmarks). Report both.\n      Per-benchmark fitting (not joint) is the default to reduce local\n      independence violation scope. Posterior predictive checks on item-level residual\n      correlations to assess local independence empirically.\n      Compute calibrated scores via exposure=0 counterfactual with CIs.\n      Compare against 7 baselines:\n      (0) Raw — no adjustment (anchor),\n      (1) remove-and-rescore (drop flagged items),\n      (2) single-signal 2PL+γ (best signal only, simpler IRT),\n      (3) vanilla 4PL without γ (standard IRT, no contamination modeling),\n      (4) linear exposure regression + bootstrap CI (simplest post-hoc),\n      (5) Emperor's mitigation: rephrasing + option shuffling,\n      (6) DCR fuzzy inference (EMNLP 2025) — the only existing method\n          producing adjusted accuracy; must include or reviewers will reject.\n      Evaluate all 5 metrics: MAE, coverage (50%/80%/95%), sharpness,\n      Kendall τ, dose-response monotonicity.\n      Report mean ± std across 3 seeds (matched to exp-001 seeds).\n    priority: P0\n    gpu_budget_hours: 8\n    deps: [exp-003]\n    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]\n    seeds: 3\n\n  # ============================================================\n  # P1: Important — run if time/GPU permit\n  # ============================================================\n\n  - id: exp-007\n    name: scale_bridging_7b\n    claim: [1]\n    description: >\n      Qwen2.5-7B controlled SFT injection at 5 dosage levels.\n      Validates calibration accuracy scales to larger models.\n      Requires multi-GPU node (7B LoRA SFT ~4-8h per run on 1×H100).\n    priority: P1\n    gpu_budget_hours: 30\n    deps: [exp-001]\n\n  - id: exp-008\n    name: signal_survival_analysis\n    claim: [2]\n    description: >\n      Systematic evaluation of detection signal reliability across training regimes.\n      Signal × regime AUC heatmap: 4 signals × {base, SFT-clean, SFT-contaminated,\n      RL-post-trained}. Confirms Self-Critique compensates where Min-K%++/ConStat\n      degrade post-RL (per fragility paper arXiv 2510.02386).\n      ELEVATED to Core Contribution 2 per Dream review (all 3 tiers identified\n      this as the most genuinely novel finding).\n    priority: P0\n    gpu_budget_hours: 10\n    deps: [exp-002]\n\n  - id: exp-014\n    name: multi_family_validation\n    claim: [1]\n    description: >\n      Controlled SFT injection on at least one non-Qwen model family\n      (Llama-3.2-1B or Pythia-1.4B) at 3 dosage levels (0%, 25%, 100%).\n      Validates that identifiability boundaries and calibration accuracy\n      generalize beyond Qwen2.5. Addresses Dream reviewer concern about\n      single model family limiting generalizability (flagged [M][W]).\n    priority: P1\n    gpu_budget_hours: 15\n    deps: [exp-001]\n\n  - id: exp-009\n    name: rl_observational_case_study\n    claim: [2, 3]\n    description: >\n      Apply Self-Critique + available signals to existing RL-trained models:\n      Qwen2.5-Instruct (0.5B/1.5B/3B/7B), DeepSeek-R1-Distill-1.5B/7B.\n      Fit IRT with appropriately wider CIs. Expected regret quantification:\n      compare uncalibrated vs calibrated vs remove-rescore for top-5 model\n      selection. Framed as observational — directional external validity,\n      not full quantitative validation. Near-zero γ check on known-clean\n      benchmark (specificity test).\n    priority: P1\n    gpu_budget_hours: 15\n    deps: [exp-006, exp-008]\n\n  # exp-010 (prior_sensitivity) and exp-011 (few_examinee_regime) merged into exp-004.\n  # Prior × N_models dimensions already covered in the sweep grid.\n\n  # ============================================================\n  # P2: Bonus — adds breadth if resources allow\n  # ============================================================\n\n  - id: exp-012\n    name: observational_72b\n    claim: [1]\n    description: >\n      Qwen2.5-72B observational analysis (inference only, no SFT).\n      Extends ecological validity to frontier model scale.\n    priority: P2\n    gpu_budget_hours: 15\n    deps: [exp-006]\n\n  - id: exp-013\n    name: closed_weight_2signal_mode\n    claim: [2]\n    description: >\n      Degraded 2-signal mode (ConStat + Self-Critique, no logits/embeddings)\n      for closed-weight models. Ablation quantifying 2-signal vs 4-signal\n      calibration accuracy gap.\n    priority: P2\n    gpu_budget_hours: 5\n    deps: [exp-003]\n\n# ============================================================\n# GPU Budget Summary\n# ============================================================\ngpu_budget:\n  P0_hours: 90\n  P1_hours: 60\n  P2_hours: 20\n  buffer_hours: 30\n  total_hours: 200\n  note: >\n    CPU-only experiments (exp-004, exp-005, exp-011) excluded.\n    Buffer covers reruns, debugging, multi-seed overhead, and unexpected issues.\n    Requires 2-4× H100/A100-80G for parallel SFT runs.\n    EMNLP 2026 ARR May 25 sprint (12 days from May 13):\n    - With 4× H100: P0 in ~4 days, P1 in ~3 days, total ~8 days (fits deadline)\n    - With 2× H100: P0 in ~7 days, P1 in ~4 days, tight but feasible if parallelized\n    - Day-8 contingency: reduce benchmarks to MMLU + GSM8K if behind schedule\n\n# Multi-seed protocol:\n# - exp-001, exp-006: 3 seeds, report mean ± std for key metrics\n# - exp-004, exp-005, exp-011: 10 seeds (simulation, CPU)\n# - exp-007, exp-008, exp-009: 1 seed (resource-constrained, note as limitation if needed)\n",
      "numLines": 262,
      "startLine": 1,
      "totalLines": 262
    }
  }
}
```

</details>

---

### Assistant

_source line 35_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information I need:

1. The `prepare_sft_data.py` structure is clear:
   - `load_paraphrases()` loads ALL paraphrases (no QC filtering per D010), but tracks `passed_qc` stats
   - `convert_paraphrases_to_chat()` converts all to chat format
   - `mix_data()` mixes base + contam at dosage level
   - For 100% dosage: all contam items are included
   - Output: `sft_dosage_100.jsonl`


2. Looking at the QC pass rates across datasets—arc_challenge is at 59.5%, gsm8k is much lower at 17.3%, and mmlu sits around 47%, bringing the overall pass rate to 45.5%.
3. My next steps are to create a new script that filters for QC-passed items only, update the experiment configuration locally, and test it out.

Now I'm planning the script structure—I'll reuse the formatting functions from the existing prepare_sft_data.py to avoid duplication, filter the paraphrases to only include QC-passed entries, combine them with the base data at full dosage, and write everything to a new output file. The script will support dry-run and help flags for flexibility. Rather than trying to import across directories, I'll keep it self-contained with the core logic duplicated where needed.

Writing the script now...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "f787e34f-4708-484f-8f08-831a7ab49be2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MhLxDDC3xQc7waKfk5dQUj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6857,
      "cache_read_input_tokens": 35391,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6857
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

_source line 36_

全部信息已收集。现在编写脚本并更新 experiment_plan.yaml。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "76b60b96-7b3b-4824-9d19-df6d2eac2824",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MhLxDDC3xQc7waKfk5dQUj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6857,
      "cache_read_input_tokens": 35391,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6857
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

_source line 37_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_01EnuipjtGTfsqwUsfkWef8C`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "cat > /root/contamcal-irt-calibration/exp001/prepare_qc_only_data.py << 'PYEOF'\n# D012 ablation: QC-only 100% dosage SFT data preparation.\n# Filters paraphrases to passed_qc=True only, isolating clean vs noisy contamination.\n\nimport argparse\nimport json\nimport logging\nimport random\nimport sys\nfrom pathlib import Path\n\nsys.path.insert(0, str(Path(__file__).parent))\nfrom prepare_sft_data import (\n    BENCHMARK_TO_QA,\n    FORMAT_FNS,\n    load_base_from_jsonl,\n    write_jsonl,\n)\n\nlogger = logging.getLogger(__name__)\n\nDEFAULTS = {\n    \"paraphrase_dir\": \"/root/autodl-tmp/exp001/paraphrases\",\n    \"base_data\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\",\n    \"output_dir\": \"/root/autodl-tmp/exp001/sft_data\",\n    \"seed\": 42,\n}\n\n\ndef load_paraphrases_qc_only(paraphrase_dir: str, benchmarks: list[str] | None = None) -> tuple[dict, dict, dict]:\n    paraphrase_dir = Path(paraphrase_dir)\n    filtered = {}\n    qc_stats = {}\n    all_counts = {}\n\n    for f in sorted(paraphrase_dir.glob(\"*_paraphrases.json\")):\n        benchmark = f.stem.replace(\"_paraphrases\", \"\")\n        if benchmarks and benchmark not in benchmarks:\n            continue\n        with open(f) as fh:\n            data = json.load(fh)\n        passed = [item for item in data if item.get(\"passed_qc\", False)]\n        qc_stats[benchmark] = {\n            \"total\": len(data),\n            \"qc_passed\": len(passed),\n            \"qc_failed\": len(data) - len(passed),\n            \"pass_rate\": round(len(passed) / len(data), 4) if data else 0,\n        }\n        all_counts[benchmark] = len(data)\n        filtered[benchmark] = passed\n        logger.info(\"Loaded %s: %d/%d QC pass (%.1f%%)\",\n                     benchmark, len(passed), len(data),\n                     len(passed) / len(data) * 100 if data else 0)\n\n    return filtered, qc_stats, all_counts\n\n\ndef convert_paraphrases_to_chat(paraphrases: dict[str, list[dict]]) -> list[dict]:\n    chat_items = []\n    for benchmark, items in paraphrases.items():\n        qa_type = BENCHMARK_TO_QA.get(benchmark, \"mcq\")\n        format_fn = FORMAT_FNS[qa_type]\n        for item in items:\n            chat_item = format_fn(item)\n            chat_item[\"_source\"] = benchmark\n            chat_item[\"_orig_index\"] = item.get(\"index\", len(chat_items))\n            chat_items.append(chat_item)\n    return chat_items\n\n\ndef main():\n    parser = argparse.ArgumentParser(\n        description=\"Prepare QC-only 100%% dosage SFT data (D012 ablation)\")\n    parser.add_argument(\"--paraphrase-dir\", type=str, default=DEFAULTS[\"paraphrase_dir\"])\n    parser.add_argument(\"--base-data\", type=str, default=DEFAULTS[\"base_data\"])\n    parser.add_argument(\"--output-dir\", type=str, default=DEFAULTS[\"output_dir\"])\n    parser.add_argument(\"--benchmarks\", type=str, default=None,\n                        help=\"Comma-separated benchmark names (default: all)\")\n    parser.add_argument(\"--seed\", type=int, default=DEFAULTS[\"seed\"])\n    parser.add_argument(\"--dry-run\", action=\"store_true\",\n                        help=\"Print statistics only, do not write files\")\n    args = parser.parse_args()\n\n    logging.basicConfig(level=logging.INFO, format=\"%(asctime)s [%(levelname)s] %(message)s\")\n\n    bench_filter = [b.strip() for b in args.benchmarks.split(\",\")] if args.benchmarks else None\n    paraphrases, qc_stats, all_counts = load_paraphrases_qc_only(args.paraphrase_dir, bench_filter)\n\n    if not paraphrases:\n        logger.error(\"No paraphrase files found in %s\", args.paraphrase_dir)\n        return\n\n    contam_data = convert_paraphrases_to_chat(paraphrases)\n    total_qc_pass = sum(len(v) for v in paraphrases.values())\n    total_all = sum(all_counts.values())\n\n    print(\"\\n=== QC-Only Ablation Statistics ===\")\n    print(f\"{'Benchmark':<20} {'All':>8} {'QC Pass':>8} {'QC Fail':>8} {'Pass%':>8}\")\n    print(\"-\" * 56)\n    for bench in sorted(qc_stats):\n        s = qc_stats[bench]\n        print(f\"{bench:<20} {s['total']:>8} {s['qc_passed']:>8} {s['qc_failed']:>8} {s['pass_rate']*100:>7.1f}%\")\n    print(\"-\" * 56)\n    print(f\"{'TOTAL':<20} {total_all:>8} {total_qc_pass:>8} {total_all - total_qc_pass:>8} \"\n          f\"{total_qc_pass / total_all * 100:>7.1f}%\")\n    print(f\"\\nChat-formatted contamination items: {len(contam_data)}\")\n\n    if args.dry_run:\n        print(\"\\n[DRY RUN] No files written.\")\n        return\n\n    output_dir = Path(args.output_dir)\n    output_dir.mkdir(parents=True, exist_ok=True)\n\n    base_data = load_base_from_jsonl(args.base_data)\n    rng = random.Random(args.seed)\n    mixed = list(base_data) + list(contam_data)\n    rng.shuffle(mixed)\n\n    output_file = output_dir / \"sft_dosage_100_qc_only.jsonl\"\n    write_jsonl(mixed, output_file)\n    logger.info(\"Wrote %d samples (%d base + %d QC-pass contam) -> %s\",\n                len(mixed), len(base_data), len(contam_data), output_file)\n\n    benchmark_sizes = {bench: all_counts[bench] for bench in paraphrases}\n    contaminated_indices = {}\n    for item in contam_data:\n        src = item.get(\"_source\")\n        idx = item.get(\"_orig_index\")\n        if src and idx is not None:\n            contaminated_indices.setdefault(src, set()).add(idx)\n\n    for benchmark, total_items in benchmark_sizes.items():\n        contam_set = contaminated_indices.get(benchmark, set())\n        labels = [1 if i in contam_set else 0 for i in range(total_items)]\n        label_file = output_dir / f\"contamination_labels_{benchmark}_d100_qc_only.json\"\n        with open(label_file, \"w\") as f:\n            json.dump({\n                \"benchmark\": benchmark,\n                \"dosage\": 100,\n                \"variant\": \"qc_only\",\n                \"total_items\": total_items,\n                \"contaminated_count\": sum(labels),\n                \"labels\": labels,\n            }, f, indent=2)\n        logger.info(\"Labels %s: %d/%d contaminated -> %s\",\n                     benchmark, sum(labels), total_items, label_file)\n\n    meta = {\n        \"base_data\": args.base_data,\n        \"base_samples\": len(base_data),\n        \"contam_samples_qc_only\": len(contam_data),\n        \"contam_samples_all\": total_all,\n        \"dosage\": 100,\n        \"variant\": \"qc_only\",\n        \"seed\": args.seed,\n        \"benchmarks\": {k: len(v) for k, v in paraphrases.items()},\n        \"qc_stats\": qc_stats,\n        \"note\": \"D012: QC-pass paraphrases only. Clean contamination ablation.\",\n    }\n    meta_file = output_dir / \"data_meta_qc_only.json\"\n    with open(meta_file, \"w\") as f:\n        json.dump(meta, f, indent=2)\n    logger.info(\"Metadata saved to %s\", meta_file)\n\n\nif __name__ == \"__main__\":\n    main()\nPYEOF"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "744af800-85ca-4a0a-adfc-04d8af084678",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MhLxDDC3xQc7waKfk5dQUj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6857,
      "cache_read_input_tokens": 35391,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6857
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

_source line 38 · 2026-05-14T00:59:01.428Z_

<details><summary>↩ Tool result · `toolu_01EnuipjtGTfsqwUsfkWef8C`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "6be9197c-ace3-4ebc-a527-87ecdde164be",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.38}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 39_

脚本已写入。执行 dry-run 验证。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "16338031-dd43-4fbc-b22e-4d6c6b61103f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KcHP2P4e9QpW8qWDFQohTr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2918,
      "cache_read_input_tokens": 42248,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2918
      },
      "output_tokens": 4,
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

_source line 40_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_01Bcyz1coXoHomkAM2HNDUwL`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python /root/contamcal-irt-calibration/exp001/prepare_qc_only_data.py --dry-run"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "f44533b3-4a84-4655-83d1-59a33bd527bd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KcHP2P4e9QpW8qWDFQohTr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2918,
      "cache_read_input_tokens": 42248,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2918
      },
      "output_tokens": 4,
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

_source line 41 · 2026-05-14T00:59:09.752Z_

<details><summary>↩ Tool result · `toolu_01Bcyz1coXoHomkAM2HNDUwL`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\n=== QC-Only Ablation Statistics ===\\nBenchmark                 All  QC Pass  QC Fail    Pass%\\n--------------------------------------------------------\\narc_challenge            1172      697      475    59.5%\\ngsm8k                    1319      228     1091    17.3%\\nhumaneval                 164       26      138    15.8%\\nmmlu                    14042     6596     7446    47.0%\\n--------------------------------------------------------\\nTOTAL                   16697     7547     9150    45.2%\\n\\nChat-formatted contamination items: 7547\\n\\n[DRY RUN] No files written.\\n\", \"stderr\": \"2026-05-14 08:59:09,281 [INFO] Loaded arc_challenge: 697/1172 QC pass (59.5%)\\n2026-05-14 08:59:09,298 [INFO] Loaded gsm8k: 228/1319 QC pass (17.3%)\\n2026-05-14 08:59:09,302 [INFO] Loaded humaneval: 26/164 QC pass (15.9%)\\n2026-05-14 08:59:09,668 [INFO] Loaded mmlu: 6596/14042 QC pass (47.0%)\\n\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.05}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "748672f6-e7c4-4a44-8913-f43cf3d8970b",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\n=== QC-Only Ablation Statistics ===\\\\nBenchmark                 All  QC Pass  QC Fail    Pass%\\\\n--------------------------------------------------------\\\\narc_challenge            1172      697      475    59.5%\\\\ngsm8k                    1319      228     1091    17.3%\\\\nhumaneval                 164       26      138    15.8%\\\\nmmlu                    14042     6596     7446    47.0%\\\\n--------------------------------------------------------\\\\nTOTAL                   16697     7547     9150    45.2%\\\\n\\\\nChat-formatted contamination items: 7547\\\\n\\\\n[DRY RUN] No files written.\\\\n\\\", \\\"stderr\\\": \\\"2026-05-14 08:59:09,281 [INFO] Loaded arc_challenge: 697/1172 QC pass (59.5%)\\\\n2026-05-14 08:59:09,298 [INFO] Loaded gsm8k: 228/1319 QC pass (17.3%)\\\\n2026-05-14 08:59:09,302 [INFO] Loaded humaneval: 26/164 QC pass (15.9%)\\\\n2026-05-14 08:59:09,668 [INFO] Loaded mmlu: 6596/14042 QC pass (47.0%)\\\\n\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.05}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\n=== QC-Only Ablation Statistics ===\\nBenchmark                 All  QC Pass  QC Fail    Pass%\\n--------------------------------------------------------\\narc_challenge            1172      697      475    59.5%\\ngsm8k                    1319      228     1091    17.3%\\nhumaneval                 164       26      138    15.8%\\nmmlu                    14042     6596     7446    47.0%\\n--------------------------------------------------------\\nTOTAL                   16697     7547     9150    45.2%\\n\\nChat-formatted contamination items: 7547\\n\\n[DRY RUN] No files written.\\n\", \"stderr\": \"2026-05-14 08:59:09,281 [INFO] Loaded arc_challenge: 697/1172 QC pass (59.5%)\\n2026-05-14 08:59:09,298 [INFO] Loaded gsm8k: 228/1319 QC pass (17.3%)\\n2026-05-14 08:59:09,302 [INFO] Loaded humaneval: 26/164 QC pass (15.9%)\\n2026-05-14 08:59:09,668 [INFO] Loaded mmlu: 6596/14042 QC pass (47.0%)\\n\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.05}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 42_

Dry-run 通过。注意到还有 humaneval（26/164, 15.8%），data_meta.json 中没列它是因为当时没用。现在更新 experiment_plan.yaml。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "b89b46ff-2a34-4cc4-90f2-81b67241c68f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WRxToHr9hR7igtKRa4ZUuV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 553,
      "cache_read_input_tokens": 45166,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 553
      },
      "output_tokens": 3,
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

_source line 43_

<details open><summary>🔧 Tool call — Edit · `toolu_01LAj97izrDgXXdx8TV8ujGy`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/experiment_plan.yaml",
  "old_string": "  - id: exp-007\n    name: scale_bridging_7b",
  "new_string": "  - id: exp-015\n    name: sft_d100_qc_only\n    claim: [1]\n    description: >\n      100% dosage SFT using only QC-pass paraphrases (7547/16697 items).\n      Isolates noisy vs clean contamination confound identified by reviewer.\n      D012 decision. Compare calibration metrics against exp-001 d100 (all\n      paraphrases) to quantify effect of noisy contamination on IRT estimates.\n    priority: P1\n    gpu_budget_hours: 5\n    deps: [exp-001]\n    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]\n    models: [Qwen2.5-0.5B]\n    seeds: 1\n    status: planned\n    registry_id:\n      - exp_001_sft_d100_qc_only\n    data_script: exp001/prepare_qc_only_data.py\n\n  - id: exp-007\n    name: scale_bridging_7b"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "8a317ecb-67a3-4908-a90e-03c004ab22bb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WRxToHr9hR7igtKRa4ZUuV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 553,
      "cache_read_input_tokens": 45166,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 553
      },
      "output_tokens": 3,
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

_source line 44 · 2026-05-14T00:59:21.630Z_

<details><summary>↩ Tool result · `toolu_01LAj97izrDgXXdx8TV8ujGy`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "00a6a1e0-cb5e-4f16-a2b4-b27c6cefc62f",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/experiment_plan.yaml",
    "oldString": "  - id: exp-007\n    name: scale_bridging_7b",
    "newString": "  - id: exp-015\n    name: sft_d100_qc_only\n    claim: [1]\n    description: >\n      100% dosage SFT using only QC-pass paraphrases (7547/16697 items).\n      Isolates noisy vs clean contamination confound identified by reviewer.\n      D012 decision. Compare calibration metrics against exp-001 d100 (all\n      paraphrases) to quantify effect of noisy contamination on IRT estimates.\n    priority: P1\n    gpu_budget_hours: 5\n    deps: [exp-001]\n    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]\n    models: [Qwen2.5-0.5B]\n    seeds: 1\n    status: planned\n    registry_id:\n      - exp_001_sft_d100_qc_only\n    data_script: exp001/prepare_qc_only_data.py\n\n  - id: exp-007\n    name: scale_bridging_7b",
    "originalFile": "# ContamCal Experiment Plan\n# Each experiment maps to Core Claims in paper_framing.md\n# Priority: P0 = must-run, P1 = important, P2 = bonus\n\nexperiments:\n  # ============================================================\n  # P0: Core experiments — must complete for submission\n  # ============================================================\n\n  - id: exp-001\n    name: controlled_sft_injection\n    claim: [1]\n    description: >\n      SFT contamination injection on Qwen2.5-0.5B/1.5B/3B at 5 dosage levels\n      (0%, 5%, 25%, 50%, 100% benchmark items as paraphrases in SFT data).\n      Produces ground-truth contaminated/clean model pairs. 15 SFT runs total\n      (3 models × 5 dosages), parallelized across GPUs. 3 seeds per condition\n      for key metrics (mean ± std).\n      Paraphrase generation: use strong open LLM (Qwen2.5-72B-Instruct or\n      equivalent) with controlled semantic similarity — following methodology\n      of \"Rethinking Benchmark and Contamination\" (arXiv 2023). Target:\n      high semantic similarity (cosine >0.85) but low lexical overlap\n      (BLEU <0.3) to evade n-gram decontamination while preserving\n      contamination effect. Quality validation: automated similarity metrics\n      + human spot-check on 50 random pairs per benchmark.\n    priority: P0\n    gpu_budget_hours: 50\n    deps: []\n    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]\n    models: [Qwen2.5-0.5B, Qwen2.5-1.5B, Qwen2.5-3B]\n    seeds: 3\n    registry_id:\n      - exp_001_sft_injection        # paraphrase generation + data prep\n      - exp_001_sft_0pct_05B         # 0.5B s42 baseline (DONE/success)\n      - exp_001_sft_0pct_15B         # 1.5B s42 baseline (DONE/success)\n      - exp_001_sft_0pct_3B          # 3B s42 baseline (RUNNING)\n      - exp_001_sft_0pct_05B_s123    # 0.5B s123 baseline (RUNNING)\n      - exp_001_sft_0pct_15B_s123    # 1.5B s123 baseline (RUNNING)\n      - exp_001_sft_0pct_3B_s123     # 3B s123 baseline (RUNNING)\n      - exp_001_eval_15B_d000_s42    # 1.5B eval (RUNNING)\n\n  - id: exp-002\n    name: stage1_signal_pipeline\n    claim: [2]\n    description: >\n      Compute 4 detection signals on all contaminated + clean models from exp-001:\n      (a) embedding-based semantic retrieval (FAISS + sentence-transformers),\n      (b) Min-K%++ membership inference,\n      (c) ConStat performance gap (original vs paraphrased items),\n      (d) Self-Critique entropy collapse.\n      Output: per-model-item exposure scores for each signal.\n    priority: P0\n    gpu_budget_hours: 20\n    deps: [exp-001]\n\n  - id: exp-003\n    name: rrf_aggregation_ablation\n    claim: [2]\n    description: >\n      RRF fusion of 4 signals into composite per-item exposure score.\n      Ablations: (a) RRF vs equal-weight rank averaging, (b) single-signal only\n      (×4), (c) calibration-based weighted RRF variant, (d) false positive\n      injection robustness check (inject FP at rates matching Duan et al. 2024).\n      Also test degraded 2-signal mode (ConStat + Self-Critique) for closed-weight.\n    priority: P0\n    gpu_budget_hours: 2\n    deps: [exp-002]\n\n  - id: exp-004\n    name: simulation_identifiability_sweep\n    claim: [1, 3]\n    description: >\n      Systematic synthetic-data sweep (NEW, not MVP — MVP only covered 4-5 conditions):\n      exposure signal AUC (0.55, 0.60, 0.65, 0.70, 0.80, 0.90) ×\n      model count (20, 50, 100, 200) ×\n      prior strength (N(0,0.5), N(0,1), N(0,2)) ×\n      exposure type (binary, continuous).\n      144 conditions, 10 seeds each. Reports: θ-γ recovery RMSE, posterior\n      correlation, coverage (50%/80%/95%), prior sensitivity. Establishes\n      minimum AUC threshold; if 95% CI width > 15pp at AUC=0.65, label as\n      \"cannot distinguish no contamination from moderate contamination.\"\n      N_items=300 fixed (per MVP finding).\n      Subsumes exp-010 (prior sensitivity) and exp-011 (few-examinee regime)\n      — prior × N_models dimensions already in sweep grid. Growing Pains\n      pre-estimation sub-experiment: at N_models=20/50, compare flat prior\n      vs informative prior from pre-estimated item parameters.\n      Also includes Fisher Information matrix analysis: derive approximate\n      analytical relationship between signal AUC, N_models, and γ\n      recoverability. Distinguish structural identifiability (parameters\n      uniquely determined) from practical identifiability (estimation\n      quality sufficient for decisions). Provides theoretical grounding\n      for the empirical AUC ≥ 0.70 threshold.\n    priority: P0\n    gpu_budget_hours: 0\n    deps: []\n    note: CPU only. MVP (mvp_sim_4pl_gamma) was preliminary; this is the full sweep.\n    registry_id:\n      - exp_004_sim_sweep            # full sweep (RUNNING)\n      - mvp_sim_4pl_gamma            # MVP predecessor (DONE/success)\n      - mvp_sim_confounding          # MVP confounding test (DONE/success)\n\n  - id: exp-005\n    name: noise_propagation_analysis\n    claim: [3]\n    description: >\n      Two parts:\n      (A) Measurement error model (PRIMARY): extend Stan model to treat exposure\n      as noisy observation: exposure_ij ~ N(τ_ij, σ_e²), where τ is latent true\n      contamination. σ_e estimated from exp-001 ground truth FP/FN rates.\n      This propagates Stage 1 uncertainty into posteriors automatically.\n      Compare coverage (50%/80%/95%) vs point-estimate exposure baseline.\n      (B) Post-hoc noise injection: inject Gaussian noise at 1×/1.5×/2× matched\n      levels, re-fit standard model, measure CI widening for γ and θ.\n      Both parts inform whether measurement error model closes the coverage gap.\n    priority: P0\n    gpu_budget_hours: 0\n    deps: [exp-002, exp-004]\n    note: CPU only\n    registry_id:\n      - exp_005_noise_prop_v2        # v2 with Stan fixes (RUNNING)\n      - exp_005_noise_prop            # v1 failed (DONE/failed, sigma_e=0 bug)\n\n  - id: exp-006\n    name: irt_calibration_and_baselines\n    claim: [1, 3]\n    description: >\n      Fit 4PL+γ IRT (Stan NUTS) on controlled models from exp-001/003.\n      PRIMARY: per-benchmark fitting with benchmark-specific γ_k — this is\n      the natural parameterization when IRT is fitted per-benchmark (each\n      benchmark's model has its own γ_k). ABLATION: joint fitting across\n      benchmarks with shared global γ (stronger assumption, tests whether\n      contamination effect is homogeneous across benchmarks). Report both.\n      Per-benchmark fitting (not joint) is the default to reduce local\n      independence violation scope. Posterior predictive checks on item-level residual\n      correlations to assess local independence empirically.\n      Compute calibrated scores via exposure=0 counterfactual with CIs.\n      Compare against 7 baselines:\n      (0) Raw — no adjustment (anchor),\n      (1) remove-and-rescore (drop flagged items),\n      (2) single-signal 2PL+γ (best signal only, simpler IRT),\n      (3) vanilla 4PL without γ (standard IRT, no contamination modeling),\n      (4) linear exposure regression + bootstrap CI (simplest post-hoc),\n      (5) Emperor's mitigation: rephrasing + option shuffling,\n      (6) DCR fuzzy inference (EMNLP 2025) — the only existing method\n          producing adjusted accuracy; must include or reviewers will reject.\n      Evaluate all 5 metrics: MAE, coverage (50%/80%/95%), sharpness,\n      Kendall τ, dose-response monotonicity.\n      Report mean ± std across 3 seeds (matched to exp-001 seeds).\n    priority: P0\n    gpu_budget_hours: 8\n    deps: [exp-003]\n    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]\n    seeds: 3\n\n  # ============================================================\n  # P1: Important — run if time/GPU permit\n  # ============================================================\n\n  - id: exp-007\n    name: scale_bridging_7b\n    claim: [1]\n    description: >\n      Qwen2.5-7B controlled SFT injection at 5 dosage levels.\n      Validates calibration accuracy scales to larger models.\n      Requires multi-GPU node (7B LoRA SFT ~4-8h per run on 1×H100).\n    priority: P1\n    gpu_budget_hours: 30\n    deps: [exp-001]\n\n  - id: exp-008\n    name: signal_survival_analysis\n    claim: [2]\n    description: >\n      Systematic evaluation of detection signal reliability across training regimes.\n      Signal × regime AUC heatmap: 4 signals × {base, SFT-clean, SFT-contaminated,\n      RL-post-trained}. Confirms Self-Critique compensates where Min-K%++/ConStat\n      degrade post-RL (per fragility paper arXiv 2510.02386).\n      ELEVATED to Core Contribution 2 per Dream review (all 3 tiers identified\n      this as the most genuinely novel finding).\n    priority: P0\n    gpu_budget_hours: 10\n    deps: [exp-002]\n\n  - id: exp-014\n    name: multi_family_validation\n    claim: [1]\n    description: >\n      Controlled SFT injection on at least one non-Qwen model family\n      (Llama-3.2-1B or Pythia-1.4B) at 3 dosage levels (0%, 25%, 100%).\n      Validates that identifiability boundaries and calibration accuracy\n      generalize beyond Qwen2.5. Addresses Dream reviewer concern about\n      single model family limiting generalizability (flagged [M][W]).\n    priority: P1\n    gpu_budget_hours: 15\n    deps: [exp-001]\n\n  - id: exp-009\n    name: rl_observational_case_study\n    claim: [2, 3]\n    description: >\n      Apply Self-Critique + available signals to existing RL-trained models:\n      Qwen2.5-Instruct (0.5B/1.5B/3B/7B), DeepSeek-R1-Distill-1.5B/7B.\n      Fit IRT with appropriately wider CIs. Expected regret quantification:\n      compare uncalibrated vs calibrated vs remove-rescore for top-5 model\n      selection. Framed as observational — directional external validity,\n      not full quantitative validation. Near-zero γ check on known-clean\n      benchmark (specificity test).\n    priority: P1\n    gpu_budget_hours: 15\n    deps: [exp-006, exp-008]\n\n  # exp-010 (prior_sensitivity) and exp-011 (few_examinee_regime) merged into exp-004.\n  # Prior × N_models dimensions already covered in the sweep grid.\n\n  # ============================================================\n  # P2: Bonus — adds breadth if resources allow\n  # ============================================================\n\n  - id: exp-012\n    name: observational_72b\n    claim: [1]\n    description: >\n      Qwen2.5-72B observational analysis (inference only, no SFT).\n      Extends ecological validity to frontier model scale.\n    priority: P2\n    gpu_budget_hours: 15\n    deps: [exp-006]\n\n  - id: exp-013\n    name: closed_weight_2signal_mode\n    claim: [2]\n    description: >\n      Degraded 2-signal mode (ConStat + Self-Critique, no logits/embeddings)\n      for closed-weight models. Ablation quantifying 2-signal vs 4-signal\n      calibration accuracy gap.\n    priority: P2\n    gpu_budget_hours: 5\n    deps: [exp-003]\n\n# ============================================================\n# GPU Budget Summary\n# ============================================================\ngpu_budget:\n  P0_hours: 90\n  P1_hours: 60\n  P2_hours: 20\n  buffer_hours: 30\n  total_hours: 200\n  note: >\n    CPU-only experiments (exp-004, exp-005, exp-011) excluded.\n    Buffer covers reruns, debugging, multi-seed overhead, and unexpected issues.\n    Requires 2-4× H100/A100-80G for parallel SFT runs.\n    EMNLP 2026 ARR May 25 sprint (12 days from May 13):\n    - With 4× H100: P0 in ~4 days, P1 in ~3 days, total ~8 days (fits deadline)\n    - With 2× H100: P0 in ~7 days, P1 in ~4 days, tight but feasible if parallelized\n    - Day-8 contingency: reduce benchmarks to MMLU + GSM8K if behind schedule\n\n# Multi-seed protocol:\n# - exp-001, exp-006: 3 seeds, report mean ± std for key metrics\n# - exp-004, exp-005, exp-011: 10 seeds (simulation, CPU)\n# - exp-007, exp-008, exp-009: 1 seed (resource-constrained, note as limitation if needed)\n",
    "structuredPatch": [
      {
        "oldStart": 156,
        "oldLines": 6,
        "newStart": 156,
        "newLines": 25,
        "lines": [
          "   # P1: Important — run if time/GPU permit",
          "   # ============================================================",
          " ",
          "+  - id: exp-015",
          "+    name: sft_d100_qc_only",
          "+    claim: [1]",
          "+    description: >",
          "+      100% dosage SFT using only QC-pass paraphrases (7547/16697 items).",
          "+      Isolates noisy vs clean contamination confound identified by reviewer.",
          "+      D012 decision. Compare calibration metrics against exp-001 d100 (all",
          "+      paraphrases) to quantify effect of noisy contamination on IRT estimates.",
          "+    priority: P1",
          "+    gpu_budget_hours: 5",
          "+    deps: [exp-001]",
          "+    benchmarks: [MMLU, GSM8K, ARC-Challenge, HumanEval]",
          "+    models: [Qwen2.5-0.5B]",
          "+    seeds: 1",
          "+    status: planned",
          "+    registry_id:",
          "+      - exp_001_sft_d100_qc_only",
          "+    data_script: exp001/prepare_qc_only_data.py",
          "+",
          "   - id: exp-007",
          "     name: scale_bridging_7b",
          "     claim: [1]"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 45_

完成。产出总结：

**脚本** — `/root/contamcal-irt-calibration/exp001/prepare_qc_only_data.py`
- 从 `prepare_sft_data.py` 复用格式化函数，加 QC 过滤逻辑
- 支持 `--dry-run` 和 `--help`
- 输出 `sft_dosage_100_qc_only.jsonl` + 对应 contamination labels + `data_meta_qc_only.json`

**Dry-run QC 统计**：

| Benchmark | All | QC Pass | Pass% |
|-----------|-----|---------|-------|
| arc_challenge | 1,172 | 697 | 59.5% |
| gsm8k | 1,319 | 228 | 17.3% |
| humaneval | 164 | 26 | 15.8% |
| mmlu | 14,042 | 6,596 | 47.0% |
| **TOTAL** | **16,697** | **7,547** | **45.2%** |

QC-only 数据量约为 ALL 的 45%（7,547 vs 16,697 contamination items）。

**experiment_plan.yaml** — 新增 `exp-015 sft_d100_qc_only`（P1，依赖 exp-001）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "uuid": "63af4c5d-5004-4642-9a97-add8efce7383",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018ZnewQeg3VMeFAYj8SXfF9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 638,
      "cache_read_input_tokens": 45719,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 638
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

_source line 46_

完成。产出总结：

**脚本** — `/root/contamcal-irt-calibration/exp001/prepare_qc_only_data.py`
- 从 `prepare_sft_data.py` 复用格式化函数，加 QC 过滤逻辑
- 支持 `--dry-run` 和 `--help`
- 输出 `sft_dosage_100_qc_only.jsonl` + 对应 contamination labels + `data_meta_qc_only.json`

**Dry-run QC 统计**：

| Benchmark | All | QC Pass | Pass% |
|-----------|-----|---------|-------|
| arc_challenge | 1,172 | 697 | 59.5% |
| gsm8k | 1,319 | 228 | 17.3% |
| humaneval | 164 | 26 | 15.8% |
| mmlu | 14,042 | 6,596 | 47.0% |
| **TOTAL** | **16,697** | **7,547** | **45.2%** |

QC-only 数据量约为 ALL 的 45%（7,547 vs 16,697 contamination items）。

**experiment_plan.yaml** — 新增 `exp-015 sft_d100_qc_only`（P1，依赖 exp-001）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 123827,
  "duration_api_ms": 120193,
  "num_turns": 16,
  "stop_reason": "end_turn",
  "session_id": "e972a1b0-1d42-4970-b872-f8d7623a4fb8",
  "total_cost_usd": 0.5145244999999999,
  "usage": {
    "input_tokens": 13,
    "cache_creation_input_tokens": 34516,
    "cache_read_input_tokens": 292887,
    "output_tokens": 6001,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 34516,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 370,
        "cache_read_input_tokens": 45719,
        "cache_creation_input_tokens": 638,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 638
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2146,
      "outputTokens": 24,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002266,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 13,
      "outputTokens": 6001,
      "cacheReadInputTokens": 292887,
      "cacheCreationInputTokens": 34516,
      "webSearchRequests": 0,
      "costUSD": 0.5122585,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "cf66a0df-0e1c-420c-af96-675aa539008d"
}
```

</details>

---

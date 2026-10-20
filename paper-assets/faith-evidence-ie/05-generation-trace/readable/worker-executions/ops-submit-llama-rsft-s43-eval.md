# ops submit llama rsft s43 eval

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 65
- **Recorded user turns:** 0
- **Tool calls:** 21
- **Original source:** `logs/workers/worker_ops_submit_llama_rsft_s43_eval_20260519T201335.log`
- **Structured JSON:** [`b1611eb89670d508eb8a.json`](../../sessions/b1/b1611eb89670d508eb8a.json)

## Before a recorded user message

65 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
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
  "uuid": "19dbe6b7-97b5-40d4-a8f7-89b5e9799467",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/memory/"
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
    "resetsAt": 1779235200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "7b25f57b-6022-45a4-8464-329f955c6f7c",
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416"
}
```

---

### Assistant

_source line 4_

我来执行这个任务。先并行检查 adapter、base model、SFT adapter 的完整性，同时查 registry 获取 s42 eval 的命令参考。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "7514a101-94d2-4572-b991-801060269e87",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018K6jjSf8sjRKJFYHQCugPv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13235,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13235
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_014Gb4TSSbNqJdcVo8aG5y13`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__update_registry",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "defcec1e-159c-4f98-9214-0b527d263aa9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018K6jjSf8sjRKJFYHQCugPv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13235,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13235
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

_source line 6 · 2026-05-19T20:13:50.302Z_

<details><summary>↩ Tool result · `toolu_014Gb4TSSbNqJdcVo8aG5y13`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_registry"
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
  "tool_name": "mcp__agent-ml-research__update_registry"
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "823e75d8-3d34-432e-8609-8b1bb3034fa0",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__update_registry"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__update_registry",
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
Now let me run the parallel checks: adapter files, base model, SFT adapter, and registry lookup for s42 eval.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "c3b4766d-c883-4301-846e-1afb5f5aa973",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018joFir1HbfHpFHJD11i65X",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2175,
      "cache_read_input_tokens": 25076,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2175
      },
      "output_tokens": 26,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_019PcbD8Q4YRS49ayVWeZr86`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls -la /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "bb1be11e-24b5-46c8-b759-6fed6431833c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018joFir1HbfHpFHJD11i65X",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2175,
      "cache_read_input_tokens": 25076,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2175
      },
      "output_tokens": 26,
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

_source line 9 · 2026-05-19T20:13:55.528Z_

<details><summary>↩ Tool result · `toolu_019PcbD8Q4YRS49ayVWeZr86`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"total 672328\\ndrwxr-xr-x  4 root root      4096 May 18 20:39 .\\ndrwxr-xr-x 76 root root      8192 May 20 02:47 ..\\n-rw-r--r--  1 root root      1532 May 18 20:39 README.md\\n-rw-r--r--  1 root root      1132 May 18 20:39 adapter_config.json\\n-rw-r--r--  1 root root 671149168 May 18 20:39 adapter_model.safetensors\\n-rw-r--r--  1 root root       384 May 18 20:39 chat_template.jinja\\ndrwxr-xr-x  2 root root      4096 May 18 20:39 checkpoint-1100\\ndrwxr-xr-x  2 root root      4096 May 18 20:39 checkpoint-1107\\n-rw-r--r--  1 root root       335 May 18 20:39 special_tokens_map.json\\n-rw-r--r--  1 root root  17209920 May 18 20:39 tokenizer.json\\n-rw-r--r--  1 root root     50591 May 18 20:39 tokenizer_config.json\\n-rw-r--r--  1 root root      6353 May 18 20:39 training_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.03}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "10cff789-07c5-4357-a5ed-23edf92ad8a9",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"total 672328\\\\ndrwxr-xr-x  4 root root      4096 May 18 20:39 .\\\\ndrwxr-xr-x 76 root root      8192 May 20 02:47 ..\\\\n-rw-r--r--  1 root root      1532 May 18 20:39 README.md\\\\n-rw-r--r--  1 root root      1132 May 18 20:39 adapter_config.json\\\\n-rw-r--r--  1 root root 671149168 May 18 20:39 adapter_model.safetensors\\\\n-rw-r--r--  1 root root       384 May 18 20:39 chat_template.jinja\\\\ndrwxr-xr-x  2 root root      4096 May 18 20:39 checkpoint-1100\\\\ndrwxr-xr-x  2 root root      4096 May 18 20:39 checkpoint-1107\\\\n-rw-r--r--  1 root root       335 May 18 20:39 special_tokens_map.json\\\\n-rw-r--r--  1 root root  17209920 May 18 20:39 tokenizer.json\\\\n-rw-r--r--  1 root root     50591 May 18 20:39 tokenizer_config.json\\\\n-rw-r--r--  1 root root      6353 May 18 20:39 training_args.bin\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.03}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"total 672328\\ndrwxr-xr-x  4 root root      4096 May 18 20:39 .\\ndrwxr-xr-x 76 root root      8192 May 20 02:47 ..\\n-rw-r--r--  1 root root      1532 May 18 20:39 README.md\\n-rw-r--r--  1 root root      1132 May 18 20:39 adapter_config.json\\n-rw-r--r--  1 root root 671149168 May 18 20:39 adapter_model.safetensors\\n-rw-r--r--  1 root root       384 May 18 20:39 chat_template.jinja\\ndrwxr-xr-x  2 root root      4096 May 18 20:39 checkpoint-1100\\ndrwxr-xr-x  2 root root      4096 May 18 20:39 checkpoint-1107\\n-rw-r--r--  1 root root       335 May 18 20:39 special_tokens_map.json\\n-rw-r--r--  1 root root  17209920 May 18 20:39 tokenizer.json\\n-rw-r--r--  1 root root     50591 May 18 20:39 tokenizer_config.json\\n-rw-r--r--  1 root root      6353 May 18 20:39 training_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.03}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01LfQiPGmTyUJFjymzdwLD7u`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_model.safetensors /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_config.json /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/config.json /root/autodl-tmp/sft_output_llama_3_1_8b/adapter_config.json",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "a075c407-6c90-47e0-b02d-e56e492e5169",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018joFir1HbfHpFHJD11i65X",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2175,
      "cache_read_input_tokens": 25076,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2175
      },
      "output_tokens": 26,
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

_source line 11 · 2026-05-19T20:13:56.684Z_

<details><summary>↩ Tool result · `toolu_01LfQiPGmTyUJFjymzdwLD7u`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_config.json\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_model.safetensors\\n/root/autodl-tmp/sft_output_llama_3_1_8b/adapter_config.json\\n\", \"stderr\": \"ls: cannot access '/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/config.json': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "3023fe10-5abe-4fcc-82b9-0a52a7cfd6ec",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_config.json\\\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_model.safetensors\\\\n/root/autodl-tmp/sft_output_llama_3_1_8b/adapter_config.json\\\\n\\\", \\\"stderr\\\": \\\"ls: cannot access '/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/config.json': No such file or directory\\\\n\\\", \\\"return_code\\\": 2}, \\\"error\\\": \\\"exit code 2\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_config.json\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/adapter_model.safetensors\\n/root/autodl-tmp/sft_output_llama_3_1_8b/adapter_config.json\\n\", \"stderr\": \"ls: cannot access '/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/config.json': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 12_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01JBg7RHkkWqUdnimy8Zm6pE`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "exp_id": "eval_llama_rsft_k1_s42"
  },
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "ba9ced32-e77d-4e51-aebe-b16b7317422d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018joFir1HbfHpFHJD11i65X",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2175,
      "cache_read_input_tokens": 25076,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2175
      },
      "output_tokens": 26,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01X5ABcq3bWXN4HfhQbSFE2s`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "nvidia-smi --query-gpu=index,memory.used,memory.total --format=csv,noheader",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "8788b939-0180-477d-b400-3f19740b9e99",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018joFir1HbfHpFHJD11i65X",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2175,
      "cache_read_input_tokens": 25076,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2175
      },
      "output_tokens": 26,
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

_source line 14 · 2026-05-19T20:13:58.207Z_

<details><summary>↩ Tool result · `toolu_01JBg7RHkkWqUdnimy8Zm6pE`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.885}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "7e337e3d-f393-48a3-abd8-b203a2e8720e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.885}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.885}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-19T20:13:58.639Z_

<details><summary>↩ Tool result · `toolu_01X5ABcq3bWXN4HfhQbSFE2s`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"0, 17359 MiB, 32607 MiB\\n1, 2531 MiB, 32607 MiB\\n2, 19557 MiB, 32607 MiB\\n3, 0 MiB, 32607 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.42}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "296e222d-b222-4e2e-a998-e8e15e062887",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"0, 17359 MiB, 32607 MiB\\\\n1, 2531 MiB, 32607 MiB\\\\n2, 19557 MiB, 32607 MiB\\\\n3, 0 MiB, 32607 MiB\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.42}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"0, 17359 MiB, 32607 MiB\\n1, 2531 MiB, 32607 MiB\\n2, 19557 MiB, 32607 MiB\\n3, 0 MiB, 32607 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.42}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 16_

<details><summary>Logged reasoning block</summary>

```text
Key findings:
1. RSFT s43 adapter: OK (adapter_model.safetensors 671MB, adapter_config.json present)
2. Base model path `/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/config.json` does NOT exist
3. SFT adapter: OK
4. Registry has no `eval_llama_rsft_k1_s42` entry - need to search differently
5. GPU 3: 0 MiB used - perfect for eval (C001 satisfied)


6. Now I need to locate the actual base model and track down the s42 evaluation command.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "8da27e4a-bc53-4f15-a8db-ab1fd378d7e0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb7AvcNRxCkt5QSnsZqLHM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 27251,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1629
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

_source line 17_

RSFT s43 adapter 和 SFT adapter 都完整。cuda:3 空闲（0 MiB）。但 base model 路径不存在，registry 里没找到 `eval_llama_rsft_k1_s42`。搜索 base model 位置和 s42 相关 eval。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "302a3cb1-b957-4643-aac1-c59ef11daf34",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb7AvcNRxCkt5QSnsZqLHM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 27251,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1629
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

_source line 18_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01LjEjnChKm9XqHEjPMFyspN`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "find /root/autodl-tmp/models -maxdepth 2 -name \"config.json\" -path \"*llama*\" -o -name \"config.json\" -path \"*Llama*\"",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "ea308079-cab7-40c5-af2b-8750f4d4b682",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb7AvcNRxCkt5QSnsZqLHM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 27251,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1629
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

_source line 19 · 2026-05-19T20:14:06.801Z_

<details><summary>↩ Tool result · `toolu_01LjEjnChKm9XqHEjPMFyspN`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "c484e1da-c289-49ad-8534-1f791d91c4e4",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_012hffrKpWn2YSKSgt3EzpM6`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "status",
    "hypothesis",
    "spec"
  ],
  "limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "1a7d1ffe-aa37-47ca-aefa-755575f6cab6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb7AvcNRxCkt5QSnsZqLHM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 27251,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1629
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

_source line 21 · 2026-05-19T20:14:08.022Z_

<details><summary>↩ Tool result · `toolu_012hffrKpWn2YSKSgt3EzpM6`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"status\": \"DONE\", \"hypothesis\": \"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"checkpoint_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\"}}, \"seed_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"log_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\"}}, \"d112_rsft_no_evidence_eval_r3\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\"}}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}}, \"plan019_8b_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\"}}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95}}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/autodl-tmp/logs/d112_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}}, \"plan019_8b_sft_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\"1.7B RSFT surpasses 8B SFT\\\" claim (Claim 3) 的统计力。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\"}}, \"d112_rsft_s44_eval_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"693535\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\", \"submitted_at\": \"2026-05-19T13:04:26.957Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"wall_clock_seconds\": 14854.9, \"gpu_hours\": 4.13}}, \"plan019_1_7b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 679713, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"kill_reason\": \"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\"}, \"hypothesis\": \"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\"}, \"plan019_8b_sft_s43\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 683937, \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\", \"submitted_at\": \"2026-05-19T12:04:30.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"wall_clock_seconds\": 6919.9, \"gpu_hours\": 1.92, \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_8b_s43\"}, \"hypothesis\": \"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\"}, \"plan017_14b_sft_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 633106, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\"}}, \"d112_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\", \"submitted_at\": \"2026-05-19T13:41:48.326Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21.2, \"gpu_hours\": 0.01}}, \"plan019_8b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"695127\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:14:41.563Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"kill_reason\": \"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\", \"wall_clock_seconds\": 1795.1, \"gpu_hours\": 0.5}}, \"d112_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:39:39.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 17.2, \"gpu_hours\": 0.0}}, \"d112_rsft_s44_train_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 675161, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\"}}, \"plan017_14b_sft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 633190, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"d112_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash scripts/d112/step4_eval.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 627505, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s44_r2_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 632051, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\"}}, \"d112_rsft_s44_train\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\", \"spec\": {\"command\": \"bash scripts/d112/step3_k1_filter_and_train.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 613075, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/root/autodl-tmp/logs/d112_rsft_s44_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44\"}}, \"plan017_14b_sft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 626093, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan017_14b_sft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 626175, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s43_r2_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 620725, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\"}}, \"plan017_14b_sft\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/\", \"log_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\"}, \"hypothesis\": \"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\"}, \"plan019_1_7b_rsft_s44_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 615557, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training run, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:1\", \"pid\": 602749, \"tmux_session\": \"rsft_1_7b_s44\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 44, \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"final_loss\": 0.5539, \"final_token_accuracy\": 0.8707, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:2\", \"pid\": 601718, \"tmux_session\": \"plan019_1_7b_rsft_s43\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment)\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\", \"final_loss\": 0.5526, \"final_token_accuracy\": 0.869, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\", \"submitted_at\": \"2026-05-19T03:52:55.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4365.6, \"gpu_hours\": 1.21, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"eval_output\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\"}}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"579965\", \"log_path\": \"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s42\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s42\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\"}}}, \"count\": 30, \"total\": 255, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.833}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "a47e432a-2e72-4117-ac72-234f28a413d2",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan019_1_7b_rsft_no_evidence_eval_2048\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\\\"}}, \\\"seed_llama_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\\\"}}, \\\"d112_rsft_no_evidence_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\\\"}}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"516711\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:33.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5362.4, \\\"gpu_hours\\\": 1.49}}, \\\"plan019_8b_rsft_no_evidence_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\\\"}}, \\\"d112_rsft_s44_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\\\", \\\"spec\\\": {\\\"command\\\": \\\"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 584466, \\\"tmux_session\\\": \\\"d112_rsft_s44_generate\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\", \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"top_p\\\": 0.95}}, \\\"d112_rsft_s44_ced_score\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 604576, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-base\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/logs/d112_ced_score.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"output_samples\\\": 3014, \\\"note\\\": \\\"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\\\"}}, \\\"plan019_8b_sft_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\\\\\"1.7B RSFT surpasses 8B SFT\\\\\\\" claim (Claim 3) 的统计力。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\\\"}}, \\\"d112_rsft_s44_eval_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"693535\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:04:26.957Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\\\", \\\"wall_clock_seconds\\\": 14854.9, \\\"gpu_hours\\\": 4.13}}, \\\"plan019_1_7b_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 679713, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"kill_reason\\\": \\\"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\\\"}, \\\"hypothesis\\\": \\\"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\\\"}, \\\"plan019_8b_sft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 683937, \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T12:04:30.528Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"wall_clock_seconds\\\": 6919.9, \\\"gpu_hours\\\": 1.92, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_qwen3_8b_s43\\\"}, \\\"hypothesis\\\": \\\"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\\\"}, \\\"plan017_14b_sft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 633106, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\\\"}}, \\\"d112_rsft_no_evidence_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:41:48.326Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 21.2, \\\"gpu_hours\\\": 0.01}}, \\\"plan019_8b_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"695127\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:14:41.563Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"kill_reason\\\": \\\"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\\\", \\\"wall_clock_seconds\\\": 1795.1, \\\"gpu_hours\\\": 0.5}}, \\\"d112_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:39:39.027Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 17.2, \\\"gpu_hours\\\": 0.0}}, \\\"d112_rsft_s44_train_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 675161, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\\\", \\\"data_count\\\": 3014, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\\\"}}, \\\"plan017_14b_sft_no_evidence_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 633190, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"d112_rsft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/d112/step4_eval.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 627505, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan019_1_7b_rsft_s44_r2_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 632051, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\\\"}}, \\\"d112_rsft_s44_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/d112/step3_k1_filter_and_train.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 613075, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\\\", \\\"data_count\\\": 3014, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/logs/d112_rsft_s44_train.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44\\\"}}, \\\"plan017_14b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 626093, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan017_14b_sft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 626175, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan019_1_7b_rsft_s43_r2_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 620725, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\\\"}}, \\\"plan017_14b_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\\\"}, \\\"hypothesis\\\": \\\"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\\\"}, \\\"plan019_1_7b_rsft_s44_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\\\"}}, \\\"plan019_1_7b_rsft_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 615557, \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training run, not eval)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\\\"}}, \\\"plan019_1_7b_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_id\\\": \\\"cuda:1\\\", \\\"pid\\\": 602749, \\\"tmux_session\\\": \\\"rsft_1_7b_s44\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 44, \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training experiment, not eval)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\\\", \\\"final_loss\\\": 0.5539, \\\"final_token_accuracy\\\": 0.8707, \\\"total_steps\\\": 567, \\\"epochs_completed\\\": 3, \\\"failure_reason\\\": \\\"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\\\"}}, \\\"plan019_1_7b_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_id\\\": \\\"cuda:2\\\", \\\"pid\\\": 601718, \\\"tmux_session\\\": \\\"plan019_1_7b_rsft_s43\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training experiment)\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\\\", \\\"final_loss\\\": 0.5526, \\\"final_token_accuracy\\\": 0.869, \\\"total_steps\\\": 567, \\\"epochs_completed\\\": 3, \\\"failure_reason\\\": \\\"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\\\"}}, \\\"plan019_8b_rsft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T03:52:55.245Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 4365.6, \\\"gpu_hours\\\": 1.21, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\\\", \\\"eval_output\\\": \\\"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\\\"}}, \\\"d111_4b_sft_s42_reeval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"579965\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT-s42\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_sft_4b_s42\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\\\"}}}, \\\"count\\\": 30, \\\"total\\\": 255, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.833}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"status\": \"DONE\", \"hypothesis\": \"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"checkpoint_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\"}}, \"seed_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"log_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\"}}, \"d112_rsft_no_evidence_eval_r3\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\"}}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}}, \"plan019_8b_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\"}}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95}}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/autodl-tmp/logs/d112_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}}, \"plan019_8b_sft_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\"1.7B RSFT surpasses 8B SFT\\\" claim (Claim 3) 的统计力。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\"}}, \"d112_rsft_s44_eval_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"693535\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\", \"submitted_at\": \"2026-05-19T13:04:26.957Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"wall_clock_seconds\": 14854.9, \"gpu_hours\": 4.13}}, \"plan019_1_7b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 679713, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"kill_reason\": \"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\"}, \"hypothesis\": \"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\"}, \"plan019_8b_sft_s43\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 683937, \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\", \"submitted_at\": \"2026-05-19T12:04:30.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"wall_clock_seconds\": 6919.9, \"gpu_hours\": 1.92, \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_8b_s43\"}, \"hypothesis\": \"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\"}, \"plan017_14b_sft_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 633106, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\"}}, \"d112_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\", \"submitted_at\": \"2026-05-19T13:41:48.326Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21.2, \"gpu_hours\": 0.01}}, \"plan019_8b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"695127\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:14:41.563Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"kill_reason\": \"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\", \"wall_clock_seconds\": 1795.1, \"gpu_hours\": 0.5}}, \"d112_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:39:39.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 17.2, \"gpu_hours\": 0.0}}, \"d112_rsft_s44_train_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 675161, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\"}}, \"plan017_14b_sft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 633190, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"d112_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash scripts/d112/step4_eval.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 627505, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s44_r2_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 632051, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\"}}, \"d112_rsft_s44_train\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\", \"spec\": {\"command\": \"bash scripts/d112/step3_k1_filter_and_train.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 613075, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/root/autodl-tmp/logs/d112_rsft_s44_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44\"}}, \"plan017_14b_sft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 626093, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan017_14b_sft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 626175, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s43_r2_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 620725, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\"}}, \"plan017_14b_sft\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/\", \"log_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\"}, \"hypothesis\": \"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\"}, \"plan019_1_7b_rsft_s44_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 615557, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training run, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:1\", \"pid\": 602749, \"tmux_session\": \"rsft_1_7b_s44\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 44, \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"final_loss\": 0.5539, \"final_token_accuracy\": 0.8707, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:2\", \"pid\": 601718, \"tmux_session\": \"plan019_1_7b_rsft_s43\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment)\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\", \"final_loss\": 0.5526, \"final_token_accuracy\": 0.869, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\", \"submitted_at\": \"2026-05-19T03:52:55.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4365.6, \"gpu_hours\": 1.21, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"eval_output\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\"}}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"579965\", \"log_path\": \"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s42\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s42\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\"}}}, \"count\": 30, \"total\": 255, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.833}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 22_

<details><summary>Logged reasoning block</summary>

```text
Key findings:
1. RSFT s43 adapter is complete (adapter_model.safetensors, adapter_config.json present)
2. Base model path `/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/config.json` does NOT exist
3. SFT adapter at `/root/autodl-tmp/sft_output_llama_3_1_8b/adapter_config.json` is OK
4. cuda:3 is free (0 MiB)


5. The registry search for `eval_llama_rsft_k1_s42` isn't returning results - I'm getting Qwen experiments instead. I need to search with a different query to find the LLaMA experiments and locate the actual base model path.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "abac03c2-3974-4c15-97ab-72d4fc3fc19c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RzhmPW2JHfLzt9UhJdMqEp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12074,
      "cache_read_input_tokens": 28880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12074
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

_source line 23_

Base model 路径不对，registry 里也没找到 LLaMA eval。搜索 LLaMA 模型位置和 LLaMA 相关 registry 条目。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "151a2d30-38f3-4939-8799-29e6f945da16",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RzhmPW2JHfLzt9UhJdMqEp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12074,
      "cache_read_input_tokens": 28880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12074
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01KdFG7rbD5FRQaq3p538CF2`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "find /root/autodl-tmp/models -maxdepth 3 -name \"config.json\" -path \"*lama*\" -o -name \"config.json\" -path \"*Lama*\" -o -name \"config.json\" -path \"*LLAMA*\" -o -name \"config.json\" -path \"*llama*\"",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "72817a8d-3221-412b-898a-a0e7f94c2dde",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RzhmPW2JHfLzt9UhJdMqEp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12074,
      "cache_read_input_tokens": 28880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12074
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

_source line 25 · 2026-05-19T20:14:19.161Z_

<details><summary>↩ Tool result · `toolu_01KdFG7rbD5FRQaq3p538CF2`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B/config.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "ae5dd325-9d38-4baf-9814-f7b603013f08",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B/config.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B/config.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 26_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01DAm6B1zzyNEcwpzvQCwH3A`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "hypothesis",
    "spec"
  ],
  "limit": 50
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "c1b3ff59-9d02-477c-9e07-9fcb59827952",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RzhmPW2JHfLzt9UhJdMqEp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12074,
      "cache_read_input_tokens": 28880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12074
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

_source line 27 · 2026-05-19T20:14:20.367Z_

<details><summary>↩ Tool result · `toolu_01DAm6B1zzyNEcwpzvQCwH3A`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"hypothesis\": \"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"checkpoint_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\"}}, \"seed_llama_rsft_k1_s43\": {\"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"log_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\"}}, \"d112_rsft_no_evidence_eval_r3\": {\"hypothesis\": \"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\"}}, \"d102_8b_rsft_k1_s43\": {\"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}}, \"plan019_8b_rsft_no_evidence_eval_r2\": {\"hypothesis\": \"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\"}}, \"d112_rsft_s44_generate\": {\"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95}}, \"d112_rsft_s44_ced_score\": {\"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/autodl-tmp/logs/d112_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}}, \"plan019_8b_sft_s43_eval\": {\"hypothesis\": \"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\"1.7B RSFT surpasses 8B SFT\\\" claim (Claim 3) 的统计力。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\"}}, \"d112_rsft_s44_eval_bf16\": {\"hypothesis\": \"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"693535\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\", \"submitted_at\": \"2026-05-19T13:04:26.957Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"wall_clock_seconds\": 14854.9, \"gpu_hours\": 4.13}}, \"plan019_1_7b_rsft_no_evidence_eval\": {\"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 679713, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"kill_reason\": \"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\"}, \"hypothesis\": \"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\"}, \"plan019_8b_sft_s43\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 683937, \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\", \"submitted_at\": \"2026-05-19T12:04:30.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"wall_clock_seconds\": 6919.9, \"gpu_hours\": 1.92, \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_8b_s43\"}, \"hypothesis\": \"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\"}, \"plan017_14b_sft_eval_r2\": {\"hypothesis\": \"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 633106, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\"}}, \"d112_rsft_no_evidence_eval_r2\": {\"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\", \"submitted_at\": \"2026-05-19T13:41:48.326Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21.2, \"gpu_hours\": 0.01}}, \"plan019_8b_rsft_no_evidence_eval\": {\"hypothesis\": \"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"695127\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:14:41.563Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"kill_reason\": \"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\", \"wall_clock_seconds\": 1795.1, \"gpu_hours\": 0.5}}, \"d112_rsft_no_evidence_eval\": {\"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:39:39.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 17.2, \"gpu_hours\": 0.0}}, \"d112_rsft_s44_train_bf16\": {\"hypothesis\": \"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 675161, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\"}}, \"plan017_14b_sft_no_evidence_eval_r2\": {\"hypothesis\": \"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 633190, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"d112_rsft_s44_eval\": {\"hypothesis\": \"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash scripts/d112/step4_eval.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 627505, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s44_r2_eval\": {\"hypothesis\": \"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 632051, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\"}}, \"d112_rsft_s44_train\": {\"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\", \"spec\": {\"command\": \"bash scripts/d112/step3_k1_filter_and_train.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 613075, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/root/autodl-tmp/logs/d112_rsft_s44_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44\"}}, \"plan017_14b_sft_eval\": {\"hypothesis\": \"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 626093, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan017_14b_sft_no_evidence_eval\": {\"hypothesis\": \"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 626175, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s43_r2_eval\": {\"hypothesis\": \"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 620725, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\"}}, \"plan017_14b_sft\": {\"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/\", \"log_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\"}, \"hypothesis\": \"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\"}, \"plan019_1_7b_rsft_s44_r2\": {\"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s43_r2\": {\"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 615557, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training run, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s44\": {\"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:1\", \"pid\": 602749, \"tmux_session\": \"rsft_1_7b_s44\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 44, \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"final_loss\": 0.5539, \"final_token_accuracy\": 0.8707, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_1_7b_rsft_s43\": {\"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:2\", \"pid\": 601718, \"tmux_session\": \"plan019_1_7b_rsft_s43\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment)\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\", \"final_loss\": 0.5526, \"final_token_accuracy\": 0.869, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_8b_rsft_s44_eval\": {\"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\", \"submitted_at\": \"2026-05-19T03:52:55.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4365.6, \"gpu_hours\": 1.21, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"eval_output\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\"}}, \"d111_4b_sft_s42_reeval\": {\"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"579965\", \"log_path\": \"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s42\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s42\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\"}}, \"d112_rsft_s44_gen_shard3\": {\"hypothesis\": \"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 SHARD=3 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 759, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 590568, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_3/\", \"log_path\": \"N/A (generation job, output in checkpoint_path)\"}}, \"d112_rsft_s44_gen_shard1\": {\"hypothesis\": \"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 SHARD=1 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"model_name\": \"4b_sft_s44\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 756, \"seed\": 44, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_1/generations.jsonl\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard1.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\"}}, \"d112_rsft_s44_gen_shard2\": {\"hypothesis\": \"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_2/generations.jsonl\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard2.log\"}}, \"d112_rsft_s44_gen_shard0\": {\"hypothesis\": \"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 SHARD=0 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 756, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 590423}}, \"plan019_8b_rsft_s44\": {\"hypothesis\": \"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\", \"spec\": {\"command\": \"bash scripts/seed_expansion/train_8b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:1\"], \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"model_name\": \"Qwen3-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_bf16\", \"pid\": 581524, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_s44.log\"}}, \"plan019_8b_sft_s44_eval\": {\"hypothesis\": \"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_s44 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"577861\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_s44\", \"eval_data\": \"docred-dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s44_eval.log\"}}, \"grpo_bf16_g4_ckpt200_eval\": {\"hypothesis\": \"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-200 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"571115\", \"log_path\": \"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt200_eval.log\", \"submitted_at\": \"2026-05-18T20:06:10.622Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt200\", \"seed\": 42, \"checkpoint_source\": \"wave1_grpo_bf16_g4\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\", \"wall_clock_seconds\": 11428.6, \"gpu_hours\": 3.17}}, \"random_rsft_k1_baseline\": {\"hypothesis\": \"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_random_k1/\", \"log_path\": \"/root/autodl-tmp/rsft_output_random_k1/training.log\"}}, \"plan019_1_7b_sft_s44\": {\"hypothesis\": \"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/\", \"log_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/training.log\"}}, \"wave1_sft_4b_s44_eval_r2\": {\"hypothesis\": \"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"571192\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval_r2.log\", \"submitted_at\": \"2026-05-18T20:06:13.257Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s44\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s44\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\", \"wall_clock_seconds\": 7136.7, \"gpu_hours\": 1.98}}, \"plan019_1_7b_sft_s43_eval\": {\"hypothesis\": \"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_1_7b_sft_s43_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"573657\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_eval.log\", \"submitted_at\": \"2026-05-18T20:33:17Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/\", \"eval_data\": \"docred-dev\", \"wall_clock_seconds\": 5403.8, \"gpu_hours\": 1.5}}, \"wave1_sft_4b_s43_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s43_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"568649\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s43_eval_r2.log\", \"submitted_at\": \"2026-05-18T19:29:27.427Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s43\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s43\", \"eval_data\": \"DocRED dev\", \"wall_clock_seconds\": 7498.5, \"gpu_hours\": 2.08}, \"hypothesis\": \"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\"}, \"plan019_8b_sft_s44\": {\"hypothesis\": \"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_8b_s44.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"567982\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s44.log\", \"submitted_at\": \"2026-05-18T19:24:19.125Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 44, \"wall_clock_seconds\": 4067.4, \"gpu_hours\": 1.13}}, \"plan019_1_7b_sft_s43_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_1_7b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"569109\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_r2.log\", \"submitted_at\": \"2026-05-18T19:31:32.289Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"wall_clock_seconds\": 2981.6, \"gpu_hours\": 0.83}, \"hypothesis\": \"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\"}, \"wave1_grpo_bf16_g4\": {\"hypothesis\": \"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d102_next_batch/grpo_bf16_g4.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": 542121, \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"output_dir\": \"/root/autodl-tmp/grpo_bf16_g4\", \"log_path\": \"/root/autodl-tmp/grpo_bf16_g4.log\", \"method\": \"GRPO bf16 no-quantize\", \"num_generations\": 4, \"gradient_accumulation_steps\": 16, \"max_steps\": 200, \"kl_coef\": 0, \"reward_weights\": {\"format\": 0.3, \"f1\": 3, \"ced\": 1}, \"plan_id\": \"plan_015\"}}, \"random_rsft_k1_eval\": {\"hypothesis\": \"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_random_k1/checkpoint-1020 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/random_rsft_k1_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"558320\", \"log_path\": \"~/runs/faith-evidence-ie/random_rsft_k1_eval.log\", \"submitted_at\": \"2026-05-18T16:35:12.562Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + Random-RSFT-k1\", \"seed\": 42, \"checkpoint_source\": \"random_rsft_k1_baseline\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/random_rsft_k1_eval\", \"wall_clock_seconds\": 12819.8, \"gpu_hours\": 3.56}}, \"grpo_bf16_g4_ckpt100_eval\": {\"hypothesis\": \"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-100 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"558467\", \"log_path\": \"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt100_eval.log\", \"submitted_at\": \"2026-05-18T16:35:15.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt100\", \"seed\": 42, \"checkpoint_source\": \"wave1_grpo_bf16_g4\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\", \"wall_clock_seconds\": 12814.3, \"gpu_hours\": 3.56}}, \"plan019_1_7b_sft_s44_eval\": {\"hypothesis\": \"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_1_7b_sft_s44_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s44_eval.log\"}}, \"plan019_1_7b_sft_s43\": {\"hypothesis\": \"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_1_7b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"554962\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43.log\", \"submitted_at\": \"2026-05-18T15:41:52.784Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"wall_clock_seconds\": 2714.9, \"gpu_hours\": 0.75}}, \"wave1_sft_4b_s44_eval\": {\"hypothesis\": \"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_seed44/ --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/sft_4b_s44_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"548407\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval.log\", \"submitted_at\": \"2026-05-18T14:02:17.363Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s44\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s44\", \"eval_data\": \"DocRED dev\", \"failure_reason\": \"Same inference.py adapter validation bug as s43 eval\", \"wall_clock_seconds\": 6076.2, \"gpu_hours\": 1.69}}}, \"count\": 50, \"total\": 255, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7294}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "77c9ff6b-d43c-4b10-b81e-ed085c410de0",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan019_1_7b_rsft_no_evidence_eval_2048\\\": {\\\"hypothesis\\\": \\\"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\\\"}}, \\\"seed_llama_rsft_k1_s43\\\": {\\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\\\"}}, \\\"d112_rsft_no_evidence_eval_r3\\\": {\\\"hypothesis\\\": \\\"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\\\"}}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"516711\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:33.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5362.4, \\\"gpu_hours\\\": 1.49}}, \\\"plan019_8b_rsft_no_evidence_eval_r2\\\": {\\\"hypothesis\\\": \\\"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\\\"}}, \\\"d112_rsft_s44_generate\\\": {\\\"hypothesis\\\": \\\"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\\\", \\\"spec\\\": {\\\"command\\\": \\\"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 584466, \\\"tmux_session\\\": \\\"d112_rsft_s44_generate\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\", \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"top_p\\\": 0.95}}, \\\"d112_rsft_s44_ced_score\\\": {\\\"hypothesis\\\": \\\"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 604576, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-base\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/logs/d112_ced_score.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"output_samples\\\": 3014, \\\"note\\\": \\\"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\\\"}}, \\\"plan019_8b_sft_s43_eval\\\": {\\\"hypothesis\\\": \\\"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\\\\\"1.7B RSFT surpasses 8B SFT\\\\\\\" claim (Claim 3) 的统计力。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\\\"}}, \\\"d112_rsft_s44_eval_bf16\\\": {\\\"hypothesis\\\": \\\"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"693535\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:04:26.957Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\\\", \\\"wall_clock_seconds\\\": 14854.9, \\\"gpu_hours\\\": 4.13}}, \\\"plan019_1_7b_rsft_no_evidence_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 679713, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"kill_reason\\\": \\\"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\\\"}, \\\"hypothesis\\\": \\\"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\\\"}, \\\"plan019_8b_sft_s43\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 683937, \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T12:04:30.528Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"wall_clock_seconds\\\": 6919.9, \\\"gpu_hours\\\": 1.92, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_qwen3_8b_s43\\\"}, \\\"hypothesis\\\": \\\"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\\\"}, \\\"plan017_14b_sft_eval_r2\\\": {\\\"hypothesis\\\": \\\"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 633106, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\\\"}}, \\\"d112_rsft_no_evidence_eval_r2\\\": {\\\"hypothesis\\\": \\\"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:41:48.326Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 21.2, \\\"gpu_hours\\\": 0.01}}, \\\"plan019_8b_rsft_no_evidence_eval\\\": {\\\"hypothesis\\\": \\\"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"695127\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:14:41.563Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"kill_reason\\\": \\\"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\\\", \\\"wall_clock_seconds\\\": 1795.1, \\\"gpu_hours\\\": 0.5}}, \\\"d112_rsft_no_evidence_eval\\\": {\\\"hypothesis\\\": \\\"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:39:39.027Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 17.2, \\\"gpu_hours\\\": 0.0}}, \\\"d112_rsft_s44_train_bf16\\\": {\\\"hypothesis\\\": \\\"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 675161, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\\\", \\\"data_count\\\": 3014, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\\\"}}, \\\"plan017_14b_sft_no_evidence_eval_r2\\\": {\\\"hypothesis\\\": \\\"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 633190, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"d112_rsft_s44_eval\\\": {\\\"hypothesis\\\": \\\"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/d112/step4_eval.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 627505, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan019_1_7b_rsft_s44_r2_eval\\\": {\\\"hypothesis\\\": \\\"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 632051, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\\\"}}, \\\"d112_rsft_s44_train\\\": {\\\"hypothesis\\\": \\\"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/d112/step3_k1_filter_and_train.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 613075, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\\\", \\\"data_count\\\": 3014, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/logs/d112_rsft_s44_train.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44\\\"}}, \\\"plan017_14b_sft_eval\\\": {\\\"hypothesis\\\": \\\"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 626093, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan017_14b_sft_no_evidence_eval\\\": {\\\"hypothesis\\\": \\\"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 626175, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan019_1_7b_rsft_s43_r2_eval\\\": {\\\"hypothesis\\\": \\\"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 620725, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\\\"}}, \\\"plan017_14b_sft\\\": {\\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\\\"}, \\\"hypothesis\\\": \\\"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\\\"}, \\\"plan019_1_7b_rsft_s44_r2\\\": {\\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\\\"}}, \\\"plan019_1_7b_rsft_s43_r2\\\": {\\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 615557, \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training run, not eval)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\\\"}}, \\\"plan019_1_7b_rsft_s44\\\": {\\\"hypothesis\\\": \\\"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_id\\\": \\\"cuda:1\\\", \\\"pid\\\": 602749, \\\"tmux_session\\\": \\\"rsft_1_7b_s44\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 44, \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training experiment, not eval)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\\\", \\\"final_loss\\\": 0.5539, \\\"final_token_accuracy\\\": 0.8707, \\\"total_steps\\\": 567, \\\"epochs_completed\\\": 3, \\\"failure_reason\\\": \\\"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\\\"}}, \\\"plan019_1_7b_rsft_s43\\\": {\\\"hypothesis\\\": \\\"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_id\\\": \\\"cuda:2\\\", \\\"pid\\\": 601718, \\\"tmux_session\\\": \\\"plan019_1_7b_rsft_s43\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training experiment)\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\\\", \\\"final_loss\\\": 0.5526, \\\"final_token_accuracy\\\": 0.869, \\\"total_steps\\\": 567, \\\"epochs_completed\\\": 3, \\\"failure_reason\\\": \\\"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\\\"}}, \\\"plan019_8b_rsft_s44_eval\\\": {\\\"hypothesis\\\": \\\"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T03:52:55.245Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 4365.6, \\\"gpu_hours\\\": 1.21, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\\\", \\\"eval_output\\\": \\\"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\\\"}}, \\\"d111_4b_sft_s42_reeval\\\": {\\\"hypothesis\\\": \\\"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"579965\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT-s42\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_sft_4b_s42\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\\\"}}, \\\"d112_rsft_s44_gen_shard3\\\": {\\\"hypothesis\\\": \\\"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 SHARD=3 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:0\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 759, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 590568, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_3/\\\", \\\"log_path\\\": \\\"N/A (generation job, output in checkpoint_path)\\\"}}, \\\"d112_rsft_s44_gen_shard1\\\": {\\\"hypothesis\\\": \\\"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=1 SHARD=1 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"model_name\\\": \\\"4b_sft_s44\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 756, \\\"seed\\\": 44, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_1/generations.jsonl\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard1.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\"}}, \\\"d112_rsft_s44_gen_shard2\\\": {\\\"hypothesis\\\": \\\"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_2/generations.jsonl\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard2.log\\\"}}, \\\"d112_rsft_s44_gen_shard0\\\": {\\\"hypothesis\\\": \\\"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 SHARD=0 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 756, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 590423}}, \\\"plan019_8b_rsft_s44\\\": {\\\"hypothesis\\\": \\\"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/seed_expansion/train_8b_s44.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:1\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_8b_bf16\\\", \\\"pid\\\": 581524, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_s44.log\\\"}}, \\\"plan019_8b_sft_s44_eval\\\": {\\\"hypothesis\\\": \\\"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_s44 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"577861\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_8b_s44\\\", \\\"eval_data\\\": \\\"docred-dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s44_eval.log\\\"}}, \\\"grpo_bf16_g4_ckpt200_eval\\\": {\\\"hypothesis\\\": \\\"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-200 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"571115\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt200_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T20:06:10.622Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt200\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_grpo_bf16_g4\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\\\", \\\"wall_clock_seconds\\\": 11428.6, \\\"gpu_hours\\\": 3.17}}, \\\"random_rsft_k1_baseline\\\": {\\\"hypothesis\\\": \\\"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_random_k1/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_random_k1/training.log\\\"}}, \\\"plan019_1_7b_sft_s44\\\": {\\\"hypothesis\\\": \\\"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/training.log\\\"}}, \\\"wave1_sft_4b_s44_eval_r2\\\": {\\\"hypothesis\\\": \\\"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"571192\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T20:06:13.257Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT-s44\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_sft_4b_s44\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\\\", \\\"wall_clock_seconds\\\": 7136.7, \\\"gpu_hours\\\": 1.98}}, \\\"plan019_1_7b_sft_s43_eval\\\": {\\\"hypothesis\\\": \\\"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_1_7b_sft_s43_eval\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"573657\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T20:33:17Z\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/\\\", \\\"eval_data\\\": \\\"docred-dev\\\", \\\"wall_clock_seconds\\\": 5403.8, \\\"gpu_hours\\\": 1.5}}, \\\"wave1_sft_4b_s43_eval_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s43_eval_r2\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"568649\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/wave1_sft_4b_s43_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T19:29:27.427Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT-s43\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_sft_4b_s43\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"wall_clock_seconds\\\": 7498.5, \\\"gpu_hours\\\": 2.08}, \\\"hypothesis\\\": \\\"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\\\"}, \\\"plan019_8b_sft_s44\\\": {\\\"hypothesis\\\": \\\"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_8b_s44.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"567982\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s44.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T19:24:19.125Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 44, \\\"wall_clock_seconds\\\": 4067.4, \\\"gpu_hours\\\": 1.13}}, \\\"plan019_1_7b_sft_s43_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_1_7b_s43.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"569109\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T19:31:32.289Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"wall_clock_seconds\\\": 2981.6, \\\"gpu_hours\\\": 0.83}, \\\"hypothesis\\\": \\\"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\\\"}, \\\"wave1_grpo_bf16_g4\\\": {\\\"hypothesis\\\": \\\"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/d102_next_batch/grpo_bf16_g4.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": 542121, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/grpo_bf16_g4\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/grpo_bf16_g4.log\\\", \\\"method\\\": \\\"GRPO bf16 no-quantize\\\", \\\"num_generations\\\": 4, \\\"gradient_accumulation_steps\\\": 16, \\\"max_steps\\\": 200, \\\"kl_coef\\\": 0, \\\"reward_weights\\\": {\\\"format\\\": 0.3, \\\"f1\\\": 3, \\\"ced\\\": 1}, \\\"plan_id\\\": \\\"plan_015\\\"}}, \\\"random_rsft_k1_eval\\\": {\\\"hypothesis\\\": \\\"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_random_k1/checkpoint-1020 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/random_rsft_k1_eval\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"558320\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/random_rsft_k1_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T16:35:12.562Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT + Random-RSFT-k1\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"random_rsft_k1_baseline\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/random_rsft_k1_eval\\\", \\\"wall_clock_seconds\\\": 12819.8, \\\"gpu_hours\\\": 3.56}}, \\\"grpo_bf16_g4_ckpt100_eval\\\": {\\\"hypothesis\\\": \\\"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-100 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"558467\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt100_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T16:35:15.818Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt100\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_grpo_bf16_g4\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\\\", \\\"wall_clock_seconds\\\": 12814.3, \\\"gpu_hours\\\": 3.56}}, \\\"plan019_1_7b_sft_s44_eval\\\": {\\\"hypothesis\\\": \\\"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_1_7b_sft_s44_eval\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_1_7b_sft_s44_eval.log\\\"}}, \\\"plan019_1_7b_sft_s43\\\": {\\\"hypothesis\\\": \\\"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_1_7b_s43.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"554962\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T15:41:52.784Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"wall_clock_seconds\\\": 2714.9, \\\"gpu_hours\\\": 0.75}}, \\\"wave1_sft_4b_s44_eval\\\": {\\\"hypothesis\\\": \\\"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_seed44/ --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/sft_4b_s44_eval\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"548407\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T14:02:17.363Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT-s44\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_sft_4b_s44\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"failure_reason\\\": \\\"Same inference.py adapter validation bug as s43 eval\\\", \\\"wall_clock_seconds\\\": 6076.2, \\\"gpu_hours\\\": 1.69}}}, \\\"count\\\": 50, \\\"total\\\": 255, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.7294}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"hypothesis\": \"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"checkpoint_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\"}}, \"seed_llama_rsft_k1_s43\": {\"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"log_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\"}}, \"d112_rsft_no_evidence_eval_r3\": {\"hypothesis\": \"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\"}}, \"d102_8b_rsft_k1_s43\": {\"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}}, \"plan019_8b_rsft_no_evidence_eval_r2\": {\"hypothesis\": \"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\"}}, \"d112_rsft_s44_generate\": {\"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95}}, \"d112_rsft_s44_ced_score\": {\"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/autodl-tmp/logs/d112_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}}, \"plan019_8b_sft_s43_eval\": {\"hypothesis\": \"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\"1.7B RSFT surpasses 8B SFT\\\" claim (Claim 3) 的统计力。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\"}}, \"d112_rsft_s44_eval_bf16\": {\"hypothesis\": \"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"693535\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\", \"submitted_at\": \"2026-05-19T13:04:26.957Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"wall_clock_seconds\": 14854.9, \"gpu_hours\": 4.13}}, \"plan019_1_7b_rsft_no_evidence_eval\": {\"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 679713, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"kill_reason\": \"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\"}, \"hypothesis\": \"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\"}, \"plan019_8b_sft_s43\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 683937, \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\", \"submitted_at\": \"2026-05-19T12:04:30.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"wall_clock_seconds\": 6919.9, \"gpu_hours\": 1.92, \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_8b_s43\"}, \"hypothesis\": \"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\"}, \"plan017_14b_sft_eval_r2\": {\"hypothesis\": \"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 633106, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\"}}, \"d112_rsft_no_evidence_eval_r2\": {\"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\", \"submitted_at\": \"2026-05-19T13:41:48.326Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21.2, \"gpu_hours\": 0.01}}, \"plan019_8b_rsft_no_evidence_eval\": {\"hypothesis\": \"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"695127\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:14:41.563Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"kill_reason\": \"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\", \"wall_clock_seconds\": 1795.1, \"gpu_hours\": 0.5}}, \"d112_rsft_no_evidence_eval\": {\"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:39:39.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 17.2, \"gpu_hours\": 0.0}}, \"d112_rsft_s44_train_bf16\": {\"hypothesis\": \"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 675161, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\"}}, \"plan017_14b_sft_no_evidence_eval_r2\": {\"hypothesis\": \"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 633190, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"d112_rsft_s44_eval\": {\"hypothesis\": \"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash scripts/d112/step4_eval.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 627505, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s44_r2_eval\": {\"hypothesis\": \"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 632051, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\"}}, \"d112_rsft_s44_train\": {\"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\", \"spec\": {\"command\": \"bash scripts/d112/step3_k1_filter_and_train.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 613075, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/root/autodl-tmp/logs/d112_rsft_s44_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44\"}}, \"plan017_14b_sft_eval\": {\"hypothesis\": \"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 626093, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan017_14b_sft_no_evidence_eval\": {\"hypothesis\": \"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 626175, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s43_r2_eval\": {\"hypothesis\": \"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 620725, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\"}}, \"plan017_14b_sft\": {\"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/\", \"log_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\"}, \"hypothesis\": \"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\"}, \"plan019_1_7b_rsft_s44_r2\": {\"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s43_r2\": {\"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 615557, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training run, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s44\": {\"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:1\", \"pid\": 602749, \"tmux_session\": \"rsft_1_7b_s44\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 44, \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"final_loss\": 0.5539, \"final_token_accuracy\": 0.8707, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_1_7b_rsft_s43\": {\"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:2\", \"pid\": 601718, \"tmux_session\": \"plan019_1_7b_rsft_s43\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment)\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\", \"final_loss\": 0.5526, \"final_token_accuracy\": 0.869, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_8b_rsft_s44_eval\": {\"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\", \"submitted_at\": \"2026-05-19T03:52:55.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4365.6, \"gpu_hours\": 1.21, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"eval_output\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\"}}, \"d111_4b_sft_s42_reeval\": {\"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"579965\", \"log_path\": \"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s42\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s42\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\"}}, \"d112_rsft_s44_gen_shard3\": {\"hypothesis\": \"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 SHARD=3 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 759, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 590568, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_3/\", \"log_path\": \"N/A (generation job, output in checkpoint_path)\"}}, \"d112_rsft_s44_gen_shard1\": {\"hypothesis\": \"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 SHARD=1 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"model_name\": \"4b_sft_s44\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 756, \"seed\": 44, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_1/generations.jsonl\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard1.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\"}}, \"d112_rsft_s44_gen_shard2\": {\"hypothesis\": \"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_2/generations.jsonl\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard2.log\"}}, \"d112_rsft_s44_gen_shard0\": {\"hypothesis\": \"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 SHARD=0 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 756, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 590423}}, \"plan019_8b_rsft_s44\": {\"hypothesis\": \"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\", \"spec\": {\"command\": \"bash scripts/seed_expansion/train_8b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:1\"], \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"model_name\": \"Qwen3-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_bf16\", \"pid\": 581524, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_s44.log\"}}, \"plan019_8b_sft_s44_eval\": {\"hypothesis\": \"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_s44 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"577861\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_s44\", \"eval_data\": \"docred-dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s44_eval.log\"}}, \"grpo_bf16_g4_ckpt200_eval\": {\"hypothesis\": \"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-200 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"571115\", \"log_path\": \"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt200_eval.log\", \"submitted_at\": \"2026-05-18T20:06:10.622Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt200\", \"seed\": 42, \"checkpoint_source\": \"wave1_grpo_bf16_g4\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\", \"wall_clock_seconds\": 11428.6, \"gpu_hours\": 3.17}}, \"random_rsft_k1_baseline\": {\"hypothesis\": \"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_random_k1/\", \"log_path\": \"/root/autodl-tmp/rsft_output_random_k1/training.log\"}}, \"plan019_1_7b_sft_s44\": {\"hypothesis\": \"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/\", \"log_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/training.log\"}}, \"wave1_sft_4b_s44_eval_r2\": {\"hypothesis\": \"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"571192\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval_r2.log\", \"submitted_at\": \"2026-05-18T20:06:13.257Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s44\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s44\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\", \"wall_clock_seconds\": 7136.7, \"gpu_hours\": 1.98}}, \"plan019_1_7b_sft_s43_eval\": {\"hypothesis\": \"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_1_7b_sft_s43_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"573657\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_eval.log\", \"submitted_at\": \"2026-05-18T20:33:17Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/\", \"eval_data\": \"docred-dev\", \"wall_clock_seconds\": 5403.8, \"gpu_hours\": 1.5}}, \"wave1_sft_4b_s43_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s43_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"568649\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s43_eval_r2.log\", \"submitted_at\": \"2026-05-18T19:29:27.427Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s43\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s43\", \"eval_data\": \"DocRED dev\", \"wall_clock_seconds\": 7498.5, \"gpu_hours\": 2.08}, \"hypothesis\": \"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\"}, \"plan019_8b_sft_s44\": {\"hypothesis\": \"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_8b_s44.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"567982\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s44.log\", \"submitted_at\": \"2026-05-18T19:24:19.125Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 44, \"wall_clock_seconds\": 4067.4, \"gpu_hours\": 1.13}}, \"plan019_1_7b_sft_s43_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_1_7b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"569109\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_r2.log\", \"submitted_at\": \"2026-05-18T19:31:32.289Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"wall_clock_seconds\": 2981.6, \"gpu_hours\": 0.83}, \"hypothesis\": \"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\"}, \"wave1_grpo_bf16_g4\": {\"hypothesis\": \"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d102_next_batch/grpo_bf16_g4.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": 542121, \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"output_dir\": \"/root/autodl-tmp/grpo_bf16_g4\", \"log_path\": \"/root/autodl-tmp/grpo_bf16_g4.log\", \"method\": \"GRPO bf16 no-quantize\", \"num_generations\": 4, \"gradient_accumulation_steps\": 16, \"max_steps\": 200, \"kl_coef\": 0, \"reward_weights\": {\"format\": 0.3, \"f1\": 3, \"ced\": 1}, \"plan_id\": \"plan_015\"}}, \"random_rsft_k1_eval\": {\"hypothesis\": \"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_random_k1/checkpoint-1020 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/random_rsft_k1_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"558320\", \"log_path\": \"~/runs/faith-evidence-ie/random_rsft_k1_eval.log\", \"submitted_at\": \"2026-05-18T16:35:12.562Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + Random-RSFT-k1\", \"seed\": 42, \"checkpoint_source\": \"random_rsft_k1_baseline\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/random_rsft_k1_eval\", \"wall_clock_seconds\": 12819.8, \"gpu_hours\": 3.56}}, \"grpo_bf16_g4_ckpt100_eval\": {\"hypothesis\": \"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-100 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"558467\", \"log_path\": \"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt100_eval.log\", \"submitted_at\": \"2026-05-18T16:35:15.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt100\", \"seed\": 42, \"checkpoint_source\": \"wave1_grpo_bf16_g4\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\", \"wall_clock_seconds\": 12814.3, \"gpu_hours\": 3.56}}, \"plan019_1_7b_sft_s44_eval\": {\"hypothesis\": \"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_1_7b_sft_s44_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s44_eval.log\"}}, \"plan019_1_7b_sft_s43\": {\"hypothesis\": \"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_1_7b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"554962\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43.log\", \"submitted_at\": \"2026-05-18T15:41:52.784Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"wall_clock_seconds\": 2714.9, \"gpu_hours\": 0.75}}, \"wave1_sft_4b_s44_eval\": {\"hypothesis\": \"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_seed44/ --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/sft_4b_s44_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"548407\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval.log\", \"submitted_at\": \"2026-05-18T14:02:17.363Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s44\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s44\", \"eval_data\": \"DocRED dev\", \"failure_reason\": \"Same inference.py adapter validation bug as s43 eval\", \"wall_clock_seconds\": 6076.2, \"gpu_hours\": 1.69}}}, \"count\": 50, \"total\": 255, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7294}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 28_

<details><summary>Logged reasoning block</summary>

```text
Found:
1. Base model path: `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B/config.json` — note it's `Meta-Llama-3.1-8B` not `Meta-Llama-3.1-8B-Instruct`
2. No LLaMA RSFT eval exists in registry yet. Let me search for LLaMA-specific experiments.

I still need to find how the LLaMA RSFT s42 eval was done. 

Now I'm searching the registry for any LLaMA-related entries.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "8db504c1-a026-46f4-992c-482c719d402d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017FAK6irH2XqpatkBV1mTMG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19689,
      "cache_read_input_tokens": 40954,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19689
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

_source line 29_

Base model 在 `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B/`。Registry 里没找到 LLaMA eval。搜索含 "llama" 的 registry 条目。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "92c7c6c2-bb0b-4113-83ad-b44ddf762387",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017FAK6irH2XqpatkBV1mTMG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19689,
      "cache_read_input_tokens": 40954,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19689
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

_source line 30_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01MxbbumguR8oL2PvcpT15k2`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {},
  "fields": [
    "exp_id",
    "status",
    "hypothesis",
    "spec"
  ],
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "a2e6492c-286e-4d21-a4b9-08b585a14142",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017FAK6irH2XqpatkBV1mTMG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19689,
      "cache_read_input_tokens": 40954,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19689
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

_source line 31 · 2026-05-19T20:14:29.058Z_

<details><summary>↩ Tool result · `toolu_01MxbbumguR8oL2PvcpT15k2`</summary>

```text
Error: result (106,057 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/mcp-agent-ml-research-read_registry-1779221669042.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/mcp-agent-ml-research-read_registry-1779221669042.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "8a721cb7-972e-4be6-888b-178d819f1c70",
  "tool_use_result": {
    "content": "Error: result (106,057 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/mcp-agent-ml-research-read_registry-1779221669042.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/mcp-agent-ml-research-read_registry-1779221669042.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"status\": \"DONE\", \"hypothesis\": \"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"checkpoint_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\"}}, \"plan010_nli_large_ablation\": {\"status\": \"RUNNING\", \"hypothesis\": \"NLI model ablation: 用 DeBERTa-v3-large 替代 v3-base 作为 CED scorer，测试更强 NLI 模型是否提升 RSFT 质量。Baseline: v3-base scored RSFT ign_f1=0.4517 (CED s42)。全流程: v3-large scoring → k=1 filter → RSFT train → D076 eval。三种结果均有论文价值: large更好=当前有提升空间 / 持平=NLI选择鲁棒 / 更差=over-confident scoring引入噪声。Claim 1, 应对 RC 关于 NLI model 选择的潜在质疑。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan010/nli_large_ablation.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"717138\", \"log_path\": \"~/runs/faith-evidence-ie/plan010_nli_large_ablation.log\", \"submitted_at\": \"2026-05-19T18:47:20.191Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_generations\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-large + Qwen3-4B\", \"seed\": 42, \"gpu_ids\": [\"cuda:1\"], \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_nli_large\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"docred-dev\"}}, \"seed_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"log_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\"}}, \"d112_rsft_no_evidence_eval_r3\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\"}}, \"plan017_14b_rsft_generate\": {\"status\": \"RUNNING\", \"hypothesis\": \"14B RSFT Step 1: 用 14B SFT adapter (ign_f1=0.5507) 在 DocRED 训练集上生成 N=8 RSFT 候选。验证 RSFT pipeline 在第 4 尺度档 (14B) 的有效性，补齐 scaling table 最后一行。D112 已确认 RSFT pipeline 从强 SFT base 出发可提升 +4.18pp (4B)。\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}}, \"plan019_8b_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\"}}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95}}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/autodl-tmp/logs/d112_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}}, \"plan019_8b_sft_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\"1.7B RSFT surpasses 8B SFT\\\" claim (Claim 3) 的统计力。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\"}}, \"d112_rsft_s44_eval_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"693535\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\", \"submitted_at\": \"2026-05-19T13:04:26.957Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\", \"wall_clock_seconds\": 14854.9, \"gpu_hours\": 4.13}}, \"plan019_1_7b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 679713, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"kill_reason\": \"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\"}, \"hypothesis\": \"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\"}, \"plan019_8b_sft_s43\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 683937, \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\", \"submitted_at\": \"2026-05-19T12:04:30.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"wall_clock_seconds\": 6919.9, \"gpu_hours\": 1.92, \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_8b_s43\"}, \"hypothesis\": \"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\"}, \"plan017_14b_sft_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 633106, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\"}}, \"d112_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\", \"submitted_at\": \"2026-05-19T13:41:48.326Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21.2, \"gpu_hours\": 0.01}}, \"plan019_8b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"695127\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:14:41.563Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"kill_reason\": \"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\", \"wall_clock_seconds\": 1795.1, \"gpu_hours\": 0.5}}, \"d112_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\", \"submitted_at\": \"2026-05-19T13:39:39.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 17.2, \"gpu_hours\": 0.0}}, \"d112_rsft_s44_train_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\", \"spec\": {\"command\": \"bash -c \\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 675161, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\", \"log_path\": \"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\"}}, \"plan017_14b_sft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 633190, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"d112_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\", \"spec\": {\"command\": \"bash scripts/d112/step4_eval.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 627505, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_4b_sft_s44/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s44_r2_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 632051, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\"}}, \"d112_rsft_s44_train\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\", \"spec\": {\"command\": \"bash scripts/d112/step3_k1_filter_and_train.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 613075, \"data_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\", \"data_count\": 3014, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/root/autodl-tmp/logs/d112_rsft_s44_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_4b_sft_s44\"}}, \"plan017_14b_sft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 626093, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan017_14b_sft_no_evidence_eval\": {\"status\": \"DONE\", \"hypothesis\": \"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\", \"spec\": {\"command\": \"bash scripts/14b/eval_14b_sft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 626175, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"plan019_1_7b_rsft_s43_r2_eval\": {\"status\": \"DONE\", \"hypothesis\": \"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 620725, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\"}}, \"plan017_14b_sft\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/\", \"log_path\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\"}, \"hypothesis\": \"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\"}, \"plan019_1_7b_rsft_s44_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 615557, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training run, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\"}}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:1\", \"pid\": 602749, \"tmux_session\": \"rsft_1_7b_s44\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 44, \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\", \"final_loss\": 0.5539, \"final_token_accuracy\": 0.8707, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:2\", \"pid\": 601718, \"tmux_session\": \"plan019_1_7b_rsft_s43\", \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A (training experiment)\", \"log_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\", \"final_loss\": 0.5526, \"final_token_accuracy\": 0.869, \"total_steps\": 567, \"epochs_completed\": 3, \"failure_reason\": \"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\"}}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\", \"submitted_at\": \"2026-05-19T03:52:55.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4365.6, \"gpu_hours\": 1.21, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"eval_output\": \"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\"}}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"579965\", \"log_path\": \"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s42\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s42\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\"}}, \"d112_rsft_s44_gen_shard3\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 SHARD=3 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 759, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 590568, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_3/\", \"log_path\": \"N/A (generation job, output in checkpoint_path)\"}}, \"d112_rsft_s44_gen_shard1\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 SHARD=1 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"model_name\": \"4b_sft_s44\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 756, \"seed\": 44, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_1/generations.jsonl\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard1.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\"}}, \"d112_rsft_s44_gen_shard2\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_2/generations.jsonl\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard2.log\"}}, \"d112_rsft_s44_gen_shard0\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 SHARD=0 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 756, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 590423}}, \"plan019_8b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\", \"spec\": {\"command\": \"bash scripts/seed_expansion/train_8b_s44.sh\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:1\"], \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"model_name\": \"Qwen3-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_bf16\", \"pid\": 581524, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_rsft_s44.log\"}}, \"plan019_8b_sft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_s44 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"577861\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_s44\", \"eval_data\": \"docred-dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_8b_sft_s44_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s44_eval.log\"}}, \"grpo_bf16_g4_ckpt200_eval\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-200 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"571115\", \"log_path\": \"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt200_eval.log\", \"submitted_at\": \"2026-05-18T20:06:10.622Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt200\", \"seed\": 42, \"checkpoint_source\": \"wave1_grpo_bf16_g4\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt200_eval\", \"wall_clock_seconds\": 11428.6, \"gpu_hours\": 3.17}}, \"random_rsft_k1_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_random_k1/\", \"log_path\": \"/root/autodl-tmp/rsft_output_random_k1/training.log\"}}, \"plan019_1_7b_sft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/\", \"log_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed44/training.log\"}}, \"wave1_sft_4b_s44_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"571192\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval_r2.log\", \"submitted_at\": \"2026-05-18T20:06:13.257Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s44\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s44\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/wave1_sft_4b_s44_eval_r2\", \"wall_clock_seconds\": 7136.7, \"gpu_hours\": 1.98}}, \"plan019_1_7b_sft_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan019_1_7b_sft_s43_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"573657\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_eval.log\", \"submitted_at\": \"2026-05-18T20:33:17Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16_seed43/\", \"eval_data\": \"docred-dev\", \"wall_clock_seconds\": 5403.8, \"gpu_hours\": 1.5}}, \"wave1_sft_4b_s43_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed43/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/wave1_sft_4b_s43_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"568649\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s43_eval_r2.log\", \"submitted_at\": \"2026-05-18T19:29:27.427Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s43\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s43\", \"eval_data\": \"DocRED dev\", \"wall_clock_seconds\": 7498.5, \"gpu_hours\": 2.08}, \"hypothesis\": \"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\"}, \"plan019_8b_sft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_8b_s44.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"567982\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_8b_sft_s44.log\", \"submitted_at\": \"2026-05-18T19:24:19.125Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 44, \"wall_clock_seconds\": 4067.4, \"gpu_hours\": 1.13}}, \"plan019_1_7b_sft_s43_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_1_7b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"569109\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43_r2.log\", \"submitted_at\": \"2026-05-18T19:31:32.289Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"wall_clock_seconds\": 2981.6, \"gpu_hours\": 0.83}, \"hypothesis\": \"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\"}, \"wave1_grpo_bf16_g4\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d102_next_batch/grpo_bf16_g4.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": 542121, \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"output_dir\": \"/root/autodl-tmp/grpo_bf16_g4\", \"log_path\": \"/root/autodl-tmp/grpo_bf16_g4.log\", \"method\": \"GRPO bf16 no-quantize\", \"num_generations\": 4, \"gradient_accumulation_steps\": 16, \"max_steps\": 200, \"kl_coef\": 0, \"reward_weights\": {\"format\": 0.3, \"f1\": 3, \"ced\": 1}, \"plan_id\": \"plan_015\"}}, \"random_rsft_k1_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_random_k1/checkpoint-1020 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/random_rsft_k1_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"558320\", \"log_path\": \"~/runs/faith-evidence-ie/random_rsft_k1_eval.log\", \"submitted_at\": \"2026-05-18T16:35:12.562Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + Random-RSFT-k1\", \"seed\": 42, \"checkpoint_source\": \"random_rsft_k1_baseline\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/random_rsft_k1_eval\", \"wall_clock_seconds\": 12819.8, \"gpu_hours\": 3.56}}, \"grpo_bf16_g4_ckpt100_eval\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_bf16_g4/checkpoint-100 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"558467\", \"log_path\": \"~/runs/faith-evidence-ie/grpo_bf16_g4_ckpt100_eval.log\", \"submitted_at\": \"2026-05-18T16:35:15.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-bf16-G4-ckpt100\", \"seed\": 42, \"checkpoint_source\": \"wave1_grpo_bf16_g4\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_bf16_g4_ckpt100_eval\", \"wall_clock_seconds\": 12814.3, \"gpu_hours\": 3.56}}, \"plan019_1_7b_sft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan019_1_7b_sft_s44_eval\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s44_eval.log\"}}, \"plan019_1_7b_sft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/sft_1_7b_s43.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"554962\", \"log_path\": \"~/runs/faith-evidence-ie/plan019_1_7b_sft_s43.log\", \"submitted_at\": \"2026-05-18T15:41:52.784Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"wall_clock_seconds\": 2714.9, \"gpu_hours\": 0.75}}, \"wave1_sft_4b_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_seed44/ --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/sft_4b_s44_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"548407\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s44_eval.log\", \"submitted_at\": \"2026-05-18T14:02:17.363Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s44\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s44\", \"eval_data\": \"DocRED dev\", \"failure_reason\": \"Same inference.py adapter validation bug as s43 eval\", \"wall_clock_seconds\": 6076.2, \"gpu_hours\": 1.69}}, \"wave1_sft_4b_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"SFT 4B seed43 eval (D076 protocol): baseline SFT performance for seed43. Paired with s44 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_seed43/ --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/sft_4b_s43_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"548328\", \"log_path\": \"~/runs/faith-evidence-ie/wave1_sft_4b_s43_eval.log\", \"submitted_at\": \"2026-05-18T14:02:15.167Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT-s43\", \"seed\": 42, \"checkpoint_source\": \"wave1_sft_4b_s43\", \"eval_data\": \"DocRED dev\", \"failure_reason\": \"inference.py adapter validation bug: detects LoRA adapter_config.json and requires --sft_adapter, but SFT adapter as model_path should not trigger this. Fix: use --model_path=base_model --sft_adapter=adapter_path\", \"wall_clock_seconds\": 6074.9, \"gpu_hours\": 1.69}}, \"seed_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"cuda:3\", \"pid\": \"541954\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT-k1-s43\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107\", \"eval_data\": \"DocRED dev\", \"log_path\": \"/root/autodl-tmp/eval_results/d102_llama_k1_s43.log\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d102_llama_k1_s43\", \"ign_f1\": 0.5662, \"f1\": 0.578, \"evi_f1\": 0.4644, \"evi_f1_tp\": 0.8287, \"EDCR\": 0.5783, \"truncated\": 173, \"predictions\": 14967, \"inference_time_s\": 9017}}, \"wave1_sft_4b_s44\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline for Qwen3-4B seed44: second seed for SFT baseline. Paired with seed43 for mean±std reporting. Expected rel_f1 similar to seed43 (~50.5±1pp).\", \"spec\": {\"command\": \"bash /root/autodl-tmp/freige/scripts/d102_next_batch/sft_seed44.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": 1, \"pid\": 540984, \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"plan_id\": \"plan_w3_sft_seeds\", \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen3-4B\", \"log_path\": \"/root/autodl-tmp/sft_output_seed44/training.log\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_seed44/\", \"train_loss\": 0.7008, \"eval_loss\": 0.7478, \"train_steps\": 144, \"epochs\": 3, \"eval_mean_token_accuracy\": 0.8299}}, \"wave1_sft_4b_s43\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline for Qwen3-4B seed43: standard SFT without CED filtering. Paired with RSFT to measure CED filtering gain. Expected rel_f1 ~50.5 based on prior 8B SFT results scaled down.\", \"spec\": {\"command\": \"bash scripts/d102_next_batch/sft_seed43.sh\", \"server\": \"rtx5090-4x\", \"gpu_id\": 0, \"pid\": 540777, \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"output_dir\": \"/root/autodl-tmp/sft_output_seed43\", \"plan_id\": \"plan_w3_sft_seeds\", \"wandb_run_name\": \"sft-4b-seed43\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_seed43/\", \"log_path\": \"/root/autodl-tmp/sft_output_seed43/training.log\", \"train_loss\": 0.7011, \"eval_loss\": 0.7482, \"train_steps\": 144, \"epochs\": 3, \"eval_mean_token_accuracy\": 0.83}}, \"d102_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT-k1-s43\", \"seed\": 43, \"checkpoint_source\": \"rsft_llama_k1_s43_train\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/d102_llama_k1_s43\", \"log_path\": \"/root/autodl-tmp/eval_results/d102_llama_k1_s43.log\"}}, \"rsft_llama_k1_s43_train\": {\"status\": \"DONE\", \"spec\": {\"command\": \"GPU=3 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_llama_s43.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"537136\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_llama_k1_s43_train.log\", \"submitted_at\": \"2026-05-18T11:42:54.203Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b_k1/rsft_train.jsonl\", \"data_count\": 2952, \"wall_clock_seconds\": 3855.5, \"gpu_hours\": 1.07}, \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。\"}, \"d102_8b_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3018 samples vs 9041），预期 rel_f1 与 k=3 相当或略有变化，验证 k=1 在 8B 上同样有效。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}}, \"d102_llama_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name llama_8b_rsft_ced_k1_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_llama_3_1_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"517259\", \"log_path\": \"~/runs/faith-evidence-ie/d102_llama_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:41.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b_k1/rsft_train.jsonl\", \"data_count\": 2952, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1/checkpoint-1107\", \"wall_clock_seconds\": 5347.6, \"gpu_hours\": 1.49}}, \"d102_1_7b_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：1.7B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3021 samples vs 9042），在最小模型上验证 k=1 RSFT 效果。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --rsft_data_path /root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_1_7b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_1_7b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_1_7b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"517006\", \"log_path\": \"~/runs/faith-evidence-ie/d102_1_7b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:37.265Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\", \"data_count\": 3021, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1/checkpoint-567\", \"wall_clock_seconds\": 5348.9, \"gpu_hours\": 1.49}}, \"seed_comparison_prep\": {\"status\": \"DONE\", \"spec\": {\"checkpoint_path\": \"N/A - killed\", \"log_path\": \"N/A\"}}, \"plan006_1_7b_rsft_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python3 -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_qwen3_1_7b --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"420013\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-17T06:10:39.457Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A - killed\", \"wall_clock_seconds\": 61675.9, \"gpu_hours\": 17.13}}, \"rsft_s43_dev_eval_preds\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/freige && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s43/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/rsft_s43_dev_eval_preds\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"431303\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_s43_dev_eval_preds.log\", \"submitted_at\": \"2026-05-17T08:38:45.685Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT-s43(CED)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_ced_s43/checkpoint-510\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/rsft_s43_dev_eval_preds\", \"wall_clock_seconds\": 52757.5, \"gpu_hours\": 14.65}, \"hypothesis\": \"Eval RSFT-s43 (CED-scored) on DocRED dev with predictions saved. Prerequisite for Lead 1 CED evidence filtering: per-sentence NLI scoring requires full prediction outputs.\"}, \"plan_006_qwen3_1_7b_rsft_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/freige && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_qwen3_1_7b/checkpoint-1698 --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"431380\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_rsft_eval_r2.log\", \"submitted_at\": \"2026-05-17T08:38:48.805Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen/Qwen3-1.7B + SFT + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b/checkpoint-1698\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_eval_r2\", \"wall_clock_seconds\": 52752.4, \"gpu_hours\": 14.65}, \"hypothesis\": \"Evaluate 1.7B RSFT model (checkpoint-1698) on DocRED dev. Retry after disk-full crash. Validates CED-filtered RSFT at smallest model scale in scaling study.\"}, \"plan_006_llama_rsft_r3_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/freige && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_r3/checkpoint-3312 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_r3_eval\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"432665\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_llama_rsft_r3_eval.log\", \"submitted_at\": \"2026-05-17T08:40:35.462Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"LLaMA-3.1-8B-Instruct + SFT + RSFT-r3\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_r3/checkpoint-3312\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan_006_llama_rsft_r3_eval\", \"wall_clock_seconds\": 52643.9, \"gpu_hours\": 14.62}, \"hypothesis\": \"Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.\"}, \"plan_006_qwen3_8b_rsft_train_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/freige && python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b --num_epochs 3 --bf16 --per_device_batch_size 1 --gradient_accumulation_steps 8 --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b/checkpoint-750\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"431780\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_8b_rsft_train_r2.log\", \"submitted_at\": \"2026-05-17T08:38:54.918Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b/rsft_train.jsonl\", \"data_count\": 9041, \"model_name\": \"Qwen/Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_bf16\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b/checkpoint-3393\", \"wall_clock_seconds\": 52742.5, \"gpu_hours\": 14.65}, \"hypothesis\": \"RSFT with CED-scored data (9041 samples) on Qwen3-8B, resume from checkpoint-750 after disk-full crash. At 8B scale, CED-filtered RSFT should achieve highest absolute performance in scaling study.\"}, \"plan_006_qwen3_1_7b_rsft_seed43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5219. If seed 43 gives similar result (±1pp, i.e., 0.51-0.53), the 1.7B scaling study datapoint is robust.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_qwen3_1_7b_seed43/checkpoint-1698 --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_seed43_eval\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 998, \"model_name\": \"Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"plan_006_qwen3_1_7b_rsft_seed43\", \"eval_data\": \"docred-dev\", \"pid\": 455632, \"gpu\": \"cuda:2\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_seed43_eval\", \"log_path\": \"/root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_seed43_eval.log\"}}, \"plan_006_qwen3_1_7b_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate 1.7B RSFT test set predictions for CodaLab submission. 1.7B RSFT dev rel_f1=0.5219, expect similar performance on test.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=2 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_qwen3_1_7b/checkpoint-1698 --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --data_path /root/autodl-tmp/data/docred --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_test\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"466508\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_rsft_test.log\", \"submitted_at\": \"2026-05-17T16:51:35.716Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": \"1000 (DocRED test)\", \"model_name\": \"Qwen3-1.7B RSFT checkpoint-1698\", \"seed\": 42, \"checkpoint_source\": \"plan_006_qwen3_1_7b_rsft_eval_r2\", \"eval_data\": \"DocRED test\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_test\", \"wall_clock_seconds\": 11092.7, \"gpu_hours\": 3.08}}, \"plan_006_qwen3_8b_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate 8B RSFT test set predictions for CodaLab submission. 8B RSFT dev rel_f1=0.5606, expect similar performance on test.\", \"spec\": {\"command\": \"python inference.py --model_path /root/autodl-tmp/freige/rsft_output_qwen3_8b/checkpoint-3393 --base_model /root/autodl-tmp/models/Qwen3-8B --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_8b_rsft_test --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"1\", \"pid\": 460585, \"data_path\": \"DocRED test set\", \"model_name\": \"Qwen3-8B RSFT checkpoint-3393\", \"seed\": 42, \"checkpoint_source\": \"plan_006_qwen3_8b_rsft_train_r2\", \"eval_data\": \"DocRED test\", \"checkpoint_path\": \"N/A - test predictions\", \"log_path\": \"/root/autodl-tmp/eval_results/plan_006_qwen3_8b_rsft_test.log\"}}, \"plan_006_llama_rsft_seed43_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust against seed variance.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"463080\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_llama_rsft_seed43_eval_r2.log\", \"submitted_at\": \"2026-05-17T16:03:52.701Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": \"985 (DocRED dev)\", \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT-seed43\", \"seed\": 43, \"checkpoint_source\": \"plan_006_llama_rsft_seed43\", \"eval_data\": \"DocRED dev\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval_r2\", \"wall_clock_seconds\": 9576.6, \"gpu_hours\": 2.66}}, \"plan_006_llama_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.\", \"spec\": {\"command\": \"python inference.py --model_path /root/autodl-tmp/freige/rsft_output_llama_3_1_8b_r3/checkpoint-3312 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_test --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize\", \"server\": \"rtx5090-4x\", \"gpu_id\": \"3\", \"pid\": 460159, \"data_path\": \"DocRED test set\", \"model_name\": \"LLaMA-3.1-8B RSFT checkpoint-3312\", \"seed\": 42, \"checkpoint_source\": \"plan_006_llama_rsft_r3_train\", \"eval_data\": \"DocRED test\", \"checkpoint_path\": \"N/A - test predictions\", \"log_path\": \"/root/autodl-tmp/eval_results/plan_006_llama_rsft_test.log\"}}, \"plan_006_llama_rsft_seed43\": {\"status\": \"DONE\", \"hypothesis\": \"Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed variance.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43 --per_device_batch_size 1 --gradient_accumulation_steps 8 --seed 43 --bf16 --wandb_run_name plan_006_llama_rsft_seed43\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl\", \"data_count\": 8829, \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_llama_rsft_seed43.log\", \"gpu\": \"cuda:0\", \"pid\": 450239, \"submitted_at\": \"2026-05-17T21:07:00Z\", \"backend\": \"tmux\", \"account\": \"root\", \"bf16\": true, \"quantize\": false, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 8, \"effective_batch_size\": 8, \"total_steps\": 3312, \"eval_data\": \"N/A - training experiment\", \"final_loss\": 0.3715, \"mean_token_accuracy\": 0.9418, \"train_runtime_seconds\": 10136, \"epochs\": 3}}, \"plan_006_llama_rsft_seed43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"462707\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_llama_rsft_seed43_eval.log\", \"submitted_at\": \"2026-05-17T16:00:21.066Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": \"docred-dev-full\", \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT-seed43\", \"seed\": 43, \"checkpoint_source\": \"plan_006_llama_rsft_seed43\", \"eval_data\": \"docred-dev\", \"checkpoint_path\": \"N/A (failed)\", \"wall_clock_seconds\": 2885.7, \"gpu_hours\": 0.8}}, \"lead2_ckpt20_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate GRPO checkpoint-20 from RSFT base (lead2_rsft_grpo_ced_r2) on DocRED dev. If RSFT→GRPO preserves/improves rel_f1 over RSFT baseline (0.4601), it validates the RSFT→GRPO training pipeline as viable.\", \"spec\": {\"server\": \"rtx5090-4x\", \"gpu\": 1, \"command\": \"CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_from_rsft_lead2_r2/checkpoint-20 --base_model /root/autodl-tmp/merged_sft_rsft_ced_s43 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_outputs/lead2_ckpt20_eval\", \"model_name\": \"Qwen3-4B (SFT+RSFT_CED_s43 merged + GRPO ckpt-20)\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_from_rsft_lead2_r2/checkpoint-20\", \"eval_data\": \"docred_dev\", \"pid\": 446829, \"log_path\": \"/root/autodl-tmp/logs/lead2_ckpt20_eval.log\"}}, \"plan_006_qwen3_8b_rsft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate Qwen3-8B RSFT (CED-scored data, 9041 samples) on DocRED dev. At 8B scale with near-zero evidence tax, CED-RSFT should achieve highest absolute Ign-F1 in the scaling study.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_qwen3_8b/checkpoint-3393 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_8b_rsft_eval\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"eval_data\": \"DocRED dev\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_8b/checkpoint-3393\", \"pid\": 442383, \"gpu\": \"cuda:3\"}}, \"plan_006_qwen3_1_7b_rsft_seed43\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with seed 43 on Qwen3-1.7B will produce comparable performance to other seeds, validating seed robustness for the scaling study\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --rsft_data_path /root/autodl-tmp/freige/outputs/rsft_scored_1_7b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_1_7b_seed43 --num_epochs 3 --seed 43 --bf16 --wandb_run_name plan_006_qwen3_1_7b_rsft_seed43\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 449282, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b/rsft_train.jsonl\", \"data_count\": 9042, \"model_name\": \"Qwen/Qwen3-1.7B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"N/A - training experiment (seed variance replication)\", \"log_path\": \"/root/runs/faith-evidence-ie/plan_006_qwen3_1_7b_rsft_seed43.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_seed43\"}}, \"post_hoc_bm25_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Post-hoc BM25 evidence retrieval on SFT-no-evidence predictions: if retrieving evidence after RE produces comparable joint Evi-F1 and EDCR to jointly trained RSFT, then joint generation is unnecessary. Expect RSFT to have better evidence quality (lower EDCR) due to training-time evidence grounding.\", \"spec\": {\"command\": \"python -m freige.eval.post_hoc_retrieval --predictions_dir /root/autodl-tmp/eval_results/reeval_sft_baseline_d076 --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/post_hoc_bm25\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"BM25 retrieval on SFT-no-evidence predictions\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/post_hoc_bm25/\", \"log_path\": \"/root/autodl-tmp/eval_results/post_hoc_bm25/\", \"checkpoint_source\": \"reeval_sft_baseline_d076\", \"eval_data\": \"docred_dev\"}}, \"lead1_ced_evidence_filter\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m eval.ced_evidence_filter --predictions_path /root/autodl-tmp/eval_results/rsft_s43_dev_eval_preds/predictions.json --tau_values 0.3 0.5 0.7 --output_dir /root/autodl-tmp/lead1_ced_filter_results\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"441954\", \"log_path\": \"/root/autodl-tmp/lead1_ced_filter_results/summary.json\", \"submitted_at\": \"2026-05-17T11:54:49.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"rsft_s43_dev_eval_preds\", \"checkpoint_path\": \"/root/autodl-tmp/lead1_ced_filter_results/\", \"model_name\": \"NLI-filter-on-rsft_s43\", \"data_path\": \"/root/autodl-tmp/eval_results/rsft_s43_dev_eval_preds/predictions.json\", \"data_count\": 14976, \"seed\": 42, \"wall_clock_seconds\": 3664.6, \"gpu_hours\": 1.02}, \"hypothesis\": \"Post-hoc CED-based evidence filtering on RSFT predictions: removing low-NLI-score evidence sentences at inference time should improve Evi-F1 and EDCR by eliminating distractor citations, without affecting rel_f1.\"}, \"plan_006_qwen3_8b_rsft_train\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m freige.training.rsft_trainer --base_model Qwen3-8B --sft_adapter sft_output_qwen3_8b_bf16 --rsft_data_path rsft_scored_qwen3_8b/rsft_train.jsonl --num_epochs 3 --bf16 --gradient_checkpointing --per_device_batch_size 1 --gradient_accumulation_steps 8\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 418278, \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_8b_rsft_train.log\", \"submitted_at\": \"2026-05-17T05:57:56.172Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b/rsft_train.jsonl\", \"data_count\": 9041, \"model_name\": \"Qwen/Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_8b_bf16\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b/checkpoint-1000\", \"failure_reason\": \"Disk full - RuntimeError unexpected pos at step 1000/3393\", \"wall_clock_seconds\": 8850.0, \"gpu_hours\": 2.46}, \"hypothesis\": \"RSFT with CED-scored data (9041 samples) on Qwen3-8B will improve rel_f1 over SFT baseline. At 8B scale with near-zero evidence tax, CED-filtered RSFT should achieve the highest absolute performance in the model scaling study.\"}, \"plan_006_qwen3_1_7b_rsft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT model on DocRED dev to measure rel_f1 improvement over SFT baseline. Validates that CED-filtered RSFT generalizes to smallest model scale (1.7B) in the scaling study.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_qwen3_1_7b --base_model /root/autodl-tmp/models/Qwen/Qwen3-1.7B --sft_adapter /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_qwen3_1_7b_rsft_eval\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 420013, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen/Qwen3-1.7B + SFT + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"N/A (eval)\", \"log_path\": \"N/A\", \"failure_reason\": \"Disk full - EXIT_CODE=124 at 74% progress\"}}, \"rsft_s44_dev_eval_preds\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s44/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/rsft_s44_dev_with_preds\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 414832, \"log_path\": \"~/runs/faith-evidence-ie/rsft_s44_dev_eval_preds.log\", \"submitted_at\": \"2026-05-17T05:02:50.357Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT-s44\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_s44/checkpoint-510\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"N/A (eval)\", \"failure_reason\": \"Disk full - EXIT_CODE=124 timeout at 97% progress\", \"wall_clock_seconds\": 12152.5, \"gpu_hours\": 3.38}, \"hypothesis\": \"Re-run RSFT s44 dev eval with predictions saved, as prerequisite for CED evidence filtering experiment (线索1: inference-time distractor citation removal). Predictions needed for per-sentence NLI scoring.\"}, \"lead2_rsft_grpo_ced_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --model_name merged_sft_rsft_ced_s43 --data_dir /root/autodl-tmp/data/docred --stage 3 --max_steps 50 --lr 1e-6 --G 8 --kl 0.01 --bf16 --ced=1.0 --f1=0.0 --format=0.5 --save_steps 10\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 421806, \"log_path\": \"~/runs/faith-evidence-ie/lead2_rsft_grpo_ced_r2.log\", \"submitted_at\": \"2026-05-17T06:24:47.600Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B (merged SFT+RSFT-s43)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/merged_sft_rsft_ced_s43\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_from_rsft_lead2/checkpoint-30\", \"failure_reason\": \"No space left on device at step 30/50 during checkpoint save\", \"wall_clock_seconds\": 7232.9, \"gpu_hours\": 2.01}, \"hypothesis\": \"RSFT→bf16 GRPO two-stage (retry with --data_dir fix): starting from merged RSFT-s43 checkpoint (rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should improve evidence quality (EDCR) while preserving rel_f1.\"}, \"plan_016_llama_rsft_train_r3\": {\"status\": \"DONE\", \"hypothesis\": \"bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues seen in r1/r2 attempts\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_r3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --seed 42 --bf16 --wandb_run_name plan_016_llama_rsft_train_r3\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 409565, \"data_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl\", \"data_count\": 8829, \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"sft_output_llama_3_1_8b (SFT LoRA adapter from plan_016 stage 1)\", \"eval_data\": \"N/A - this is a training experiment (retry of r2 with bf16 instead of QLoRA)\", \"mode\": \"bf16 + gradient_checkpointing\", \"effective_batch_size\": 8, \"total_steps\": 3312, \"log_path\": \"/root/runs/faith-evidence-ie/plan_016_llama_rsft_train_r3.log\", \"bf16\": true, \"gradient_checkpointing\": true, \"quantize\": false, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_r3\"}}, \"lead2_rsft_grpo_ced\": {\"status\": \"DONE\", \"spec\": {\"command\": \"merge_sft_rsft.py then grpo_trainer --model_name merged_sft_rsft_ced_s43 --stage 3 --max_steps 50 --lr 1e-6 --G 8 --kl 0.01 --bf16 --ced=1.0 --f1=0.0 --format=0.5 --save_steps 10\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 418198, \"log_path\": \"~/runs/faith-evidence-ie/lead2_rsft_grpo_ced.log\", \"submitted_at\": \"2026-05-17T05:57:53.332Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B (merged SFT+RSFT-s43)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/merged_sft_rsft_ced_s43\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A\", \"failure_reason\": \"docred_processor.py:129 load_dataset('thunlp/docred') failed - server offline\", \"wall_clock_seconds\": 522.8, \"gpu_hours\": 0.15}, \"hypothesis\": \"RSFT→bf16 GRPO two-stage: starting from RSFT best checkpoint (s43, rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should further improve evidence quality (EDCR) while preserving rel_f1, because RSFT provides stable base preventing catastrophic forgetting seen in SFT→GRPO.\"}, \"plan_006_qwen3_8b_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring on Qwen3-8B RSFT candidates (24216 gens from 3027 docs) will produce high-quality filtered training data. At 8B scale with near-zero evidence tax, CED-filtered RSFT should yield further gains over an already strong SFT baseline.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/freige/outputs/rsft_candidates_8b --output_path /root/autodl-tmp/rsft_scored_qwen3_8b --nli_model_path /root/autodl-tmp/.hf_cache/models--cross-encoder--nli-deberta-v3-base/snapshots/6c749ce3425cd33b46d187e45b92bbf96ee12ec7 --nli_device cuda:0 --scoring_mode ced --tau 0.5 --selection_strategy top_k --top_k 3\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_8b\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"rsft_candidates_8b (Qwen3-8B generations)\", \"eval_data\": \"24216 candidates from 3027 docs\", \"pid\": 411027, \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b\", \"log_path\": \"N/A\"}}, \"plan_006_qwen3_1_7b_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data on Qwen3-1.7B will improve relation extraction F1 over SFT baseline by selectively reinforcing high-quality extraction patterns, similar to gains seen on 4B model\", \"spec\": {\"command\": \"python -m freige.training.rsft_trainer --base_model Qwen3-1.7B --sft_adapter sft_output_qwen3_1_7b_bf16 --rsft_data_path rsft_scored_1_7b/rsft_train.jsonl --output_dir rsft_output_qwen3_1_7b --num_epochs 3 --seed 42 --bf16\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 406515, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b/rsft_train.jsonl\", \"data_count\": 9042, \"model_name\": \"Qwen/Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_rsft_train.log\"}}, \"plan_002_test_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT-CED s44 (best dev config, rel_f1=0.4655) maintains improvement over SFT on held-out test set, confirming CED-filtered rejection sampling gains are not dev-set overfitting. Test Ign-F1 should exceed SFT test baseline.\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s44/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_002_test_rsft_s44\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"396333\", \"log_path\": \"~/runs/faith-evidence-ie/plan_002_test_rsft_s44.log\", \"submitted_at\": \"2026-05-17T01:06:16.686Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 0, \"model_name\": \"Qwen3-4B + SFT + RSFT-s44\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_s44/checkpoint-510\", \"eval_data\": \"docred_test\", \"loading_mode\": \"3-param (base→SFT→RSFT)\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/plan_002_test_rsft_s44\", \"metrics_note\": \"Test set - no local gold labels. 1000 docs, 26925 predictions, 626 truncated, format_ok=99.6%. Needs CodaLab submission for official scores.\", \"inference_time_s\": 12494, \"wall_clock_seconds\": 13869.2, \"gpu_hours\": 3.85}}, \"plan_006_qwen3_8b_rsft_candidates_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Resuming 8B candidate generation from idx 2701 will complete the full RSFT candidate set needed for reward-based filtering and RSFT training\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --num_generations 8 --temperature 0.7 --batch_size 1 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/freige/outputs/rsft_candidates_8b --start_idx 2701\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": 400132, \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 326, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/plan_006_qwen3_8b_rsft_candidates_r2.log\"}}, \"plan_016_llama_rsft_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b --seed 42 --quantize --bf16 --per_device_batch_size 2 --gradient_accumulation_steps 8 --wandb_project faith-evidence-ie --wandb_run_name plan_016_llama_rsft_train_r2\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": 405397, \"log_path\": \"/root/runs/faith-evidence-ie/plan_016_llama_rsft_train_r2.log\", \"data_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl\", \"data_count\": 8829, \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"rsft_scored_llama_3_1_8b\", \"fix\": \"added --quantize --bf16 --per_device_batch_size 2 --gradient_accumulation_steps 8 (R1 OOM due to fp32 loading without quantize flag)\", \"total_steps\": 1656, \"estimated_hours\": 4.4}}, \"plan_016_llama_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families (Qwen→LLaMA).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b --seed 42 --wandb_run_name plan_016_llama_rsft_train\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": 404050, \"data_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b\", \"data_count\": 8829, \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"rsft_scored_llama_3_1_8b\"}}, \"plan_016_llama_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=2 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_candidates_llama_3_1_8b --output_path /root/autodl-tmp/rsft_scored_llama_3_1_8b --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --scoring_mode ced --tau 0.5 --selection_strategy top_k --top_k 3\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"398949\", \"data_path\": \"/root/autodl-tmp/rsft_candidates_llama_3_1_8b\", \"data_count\": 23704, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/plan_016_llama_ced_scoring.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_llama_3_1_8b\", \"checkpoint_source\": \"/root/autodl-tmp/rsft_candidates_llama_3_1_8b\", \"eval_data\": \"docred_train_candidates_llama_8b\"}}, \"plan_006_qwen3_1_7b_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring (NLI contrastive discrimination) can effectively filter 1.7B model candidates despite lower generation quality: NLI-based selection should identify high-quality evidence samples even from a capacity-limited generator.\", \"spec\": {\"command\": \"python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/freige/outputs/rsft_candidates_1_7b --output_path /root/autodl-tmp/freige/outputs/rsft_scored_1_7b --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --scoring_mode ced --tau 0.5 --selection_strategy top_k --top_k 3\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 395619, \"data_path\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_1_7b\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_1_7b\", \"eval_data\": \"docred train candidates\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_ced_scoring.log\", \"checkpoint_path\": \"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b\"}}, \"plan_007_redocred_rsft_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/rsft_output_ced_s43/checkpoint-510 --data_path /root/autodl-tmp/data/re-docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_007_redocred_rsft_eval_r2\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 363317, \"data_path\": \"/root/autodl-tmp/data/re-docred\", \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_ced_s43/checkpoint-510\", \"eval_data\": \"re-docred/dev\", \"hypothesis\": \"Re-DocRED RSFT eval r2: verify CED-RSFT improvement transfers cross-dataset. Compare vs SFT baseline Ign-F1=0.3659 (D080).\", \"plan_id\": \"plan_007\", \"parent\": \"plan_007_redocred_4b_sft_eval_r2\", \"log_path\": \"/tmp/plan_007_redocred_rsft_eval_r2.log\"}, \"hypothesis\": \"CED-RSFT improvements on DocRED should transfer to Re-DocRED: RSFT model should outperform SFT baseline on Re-DocRED Ign-F1, demonstrating cross-dataset generalization of rejection sampling gains.\"}, \"plan_006_qwen3_1_7b_rsft_candidates\": {\"status\": \"DONE\", \"hypothesis\": \"Qwen3-1.7B RSFT candidate generation (N=8, T=0.7). Scale ablation: smallest model RSFT candidates for CED scoring. plan_006 claim=3.\", \"spec\": {\"model_name\": \"Qwen3-1.7B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"seed\": 42, \"output_dir\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_1_7b\", \"config\": {\"num_generations\": 8, \"temperature\": 0.7, \"batch_size\": 1, \"split\": \"train\"}, \"command\": \"RSFT candidate generation N=8, T=0.7 for Qwen3-1.7B\", \"server\": \"rtx5090-4x\", \"checkpoint_path\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_1_7b\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_rsft_candidates.log\"}}, \"plan_002_test_eval_s44_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s44/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/test_rsft_ced_s44 --no-quantize\", \"server\": \"rtx5090-4x\", \"gpu_id\": 1, \"pid\": 319632, \"data_path\": \"/root/autodl-tmp/data/docred/test.json\", \"data_count\": 1000, \"model_name\": \"Qwen3-4B + SFT + RSFT-CED-s44-ckpt510\", \"seed\": 42, \"hypothesis\": \"DocRED test set evaluation with RSFT CED s44 (best config). D076 协议. plan_id=plan_002, claim=1.\", \"parent\": \"mvp2_rsft_train_r1_s44\", \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_s44/checkpoint-510\", \"eval_data\": \"/root/autodl-tmp/data/docred/test.json\", \"log_path\": \"/root/autodl-tmp/eval_results/test_rsft_ced_s44/eval.log\", \"metrics\": {\"n_documents\": 1000, \"n_predictions\": 26925, \"n_codalab_entries\": 25553, \"format_ok_rate\": 0.996, \"n_truncated\": 626, \"inference_time_s\": 13850.5}, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/test_rsft_ced_s44\", \"notes\": \"Test set eval complete. No local F1 (need CodaLab submission). File: codalab_submission.json (25553 entries).\"}, \"hypothesis\": \"DocRED test set evaluation for RSFT-CED s44 (best dev config). Final benchmark numbers for paper submission; test set performance confirms dev set gains are not overfitting artifacts.\"}, \"plan_006_qwen3_8b_no_evidence_sft\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.sft_trainer --model_name /root/autodl-tmp/models/Qwen/Qwen3-8B --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/sft_output_qwen3_8b_no_evidence --no_evidence --no-quantize --seed 42 --wandb_run_name qwen3_8b_no_evidence_sft\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"plan_id\": \"plan_006\", \"hypothesis\": \"8B no-evidence SFT ablation (bf16 LoRA). 与 plan_006_qwen3_8b_sft_bf16 对比量化 evidence generation cost on 8B model. claim=1.\", \"quantize\": \"none (bf16 LoRA)\", \"lora_rank\": 64, \"lora_alpha\": 128, \"output_dir\": \"/root/autodl-tmp/sft_output_qwen3_8b_no_evidence\", \"log_path\": \"/root/autodl-tmp/logs/plan_006_qwen3_8b_no_evidence_sft.log\", \"pid\": 325491, \"wandb_run_name\": \"qwen3_8b_no_evidence_sft\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_8b_no_evidence\"}, \"hypothesis\": \"Qwen3-8B no-evidence SFT baseline for evidence tax measurement at 8B scale. If 8B no-evi rel_f1 ≈ 8B evidence-SFT rel_f1, confirms that 8B absorbs evidence cost (tax≈0).\"}, \"plan_006_qwen3_1_7b_no_evidence_sft\": {\"status\": \"DONE\", \"spec\": {\"hypothesis\": \"Qwen3-1.7B no-evidence SFT ablation（复现 plan_014），验证 evidence generation 代价在小模型上是否成立。plan_id=plan_006, claim=1。\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=2 HF_HOME=/root/autodl-tmp/.hf_cache PYTHONUNBUFFERED=1 python -m freige.training.sft_trainer --model_name /root/autodl-tmp/models/Qwen/Qwen3-1.7B --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/sft_output_qwen3_1_7b_no_evidence --seed 42 --wandb_run_name qwen3_1_7b_no_evidence_sft --no-quantize --no_evidence\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"account\": \"root\", \"model_name\": \"Qwen3-1.7B\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"seed\": 42, \"plan_id\": \"plan_006\", \"lora_rank\": 64, \"lora_alpha\": 128, \"quantize\": \"none (bf16 LoRA)\", \"num_epochs\": 3, \"batch_size\": 1, \"gradient_accumulation_steps\": 16, \"learning_rate\": 0.0002, \"output_dir\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_no_evidence_sft.log\", \"pid\": \"321094\", \"backend\": \"nohup\", \"notes\": \"r1 (PID 317798) 完成 570 steps，最终模型保存于 16:32:46。r2 (PID 321094/321100) 冗余重复，已 kill 释放 cuda:2\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_no_evidence\"}, \"hypothesis\": \"Qwen3-1.7B no-evidence SFT baseline for evidence tax measurement at 1.7B scale. Paired with evidence-SFT to quantify whether evidence generation constrains or helps small model RE performance.\"}, \"plan_006_qwen3_1_7b_sft_bf16\": {\"status\": \"DONE\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache PYTHONUNBUFFERED=1 python -m freige.training.sft_trainer --model_name /root/autodl-tmp/models/Qwen/Qwen3-1.7B --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/sft_output_qwen3_1_7b_bf16 --seed 42 --wandb_run_name qwen3_1_7b_sft_bf16 --no-quantize\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"pid\": \"310381\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_1_7b_sft_bf16.log\", \"backend\": \"tmux\", \"account\": \"root\", \"lora_rank\": 64, \"lora_alpha\": 128, \"target_modules\": 7, \"quantize\": \"none (bf16 LoRA)\", \"trainable_params\": \"69.7M / 1.79B (3.89%)\", \"num_epochs\": 3, \"batch_size\": 1, \"gradient_accumulation_steps\": 16, \"learning_rate\": 0.0002, \"output_dir\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\", \"hypothesis\": \"Model size ablation: Qwen3-1.7B bf16 LoRA SFT（与 4B 训练 regime 一致），验证 evidence tax 在小模型上的表现。plan_id=plan_006, claim=1。\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16/checkpoint-570\"}, \"hypothesis\": \"Qwen3-1.7B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: smallest model expected to show highest evidence tax due to capacity-constrained multi-task optimization.\"}, \"plan_006_qwen3_8b_sft_bf16\": {\"status\": \"DONE\", \"spec\": {\"hypothesis\": \"Model size ablation: Qwen3-8B bf16 LoRA SFT（与 4B/1.7B 训练 regime 一致），验证 evidence generation pipeline 在大模型上的表现。plan_id=plan_006, claim=1。\", \"model_name\": \"Qwen3-8B\", \"server\": \"rtx5090-4x\", \"plan_id\": \"plan_006\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache PYTHONUNBUFFERED=1 python -m freige.training.sft_trainer --model_name /root/autodl-tmp/models/Qwen/Qwen3-8B --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/sft_output_qwen3_8b_bf16 --no-quantize --seed 42 --wandb_run_name qwen3_8b_sft_bf16\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"seed\": 42, \"pid\": \"317310\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/faith-evidence-ie/plan_006_qwen3_8b_sft_bf16.log\", \"backend\": \"tmux\", \"account\": \"root\", \"lora_rank\": 64, \"lora_alpha\": 128, \"target_modules\": 7, \"quantize\": \"none (bf16 LoRA)\", \"trainable_params\": \"174.6M / 8.37B (2.09%)\", \"num_epochs\": 3, \"batch_size\": 1, \"gradient_accumulation_steps\": 16, \"learning_rate\": 0.0002, \"output_dir\": \"/root/autodl-tmp/sft_output_qwen3_8b_bf16\", \"checkpoint_path\": \"N/A\"}, \"hypothesis\": \"Qwen3-8B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: larger model should achieve higher rel_f1 than 4B (0.4057) and 1.7B baselines, with lower evidence tax due to greater capacity.\"}}, \"count\": 100, \"total\": 257, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7066}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 32_

<details><summary>Logged reasoning block</summary>

```text
The result is too large. Let me just grep the file for "llama" entries to find the relevant experiment.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "0a963d43-19a6-4fa4-b55b-c600f987becd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013NkmZ6G9zcKSsDn7kXceZh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 711,
      "cache_read_input_tokens": 60643,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 711
      },
      "output_tokens": 9,
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

_source line 33_

<details open><summary>🔧 Tool call — Bash · `toolu_018HeouRR5DXKYS9f1Ccjdo9`</summary>

```json
{
  "command": "grep -i \"llama\" /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/mcp-agent-ml-research-read_registry-1779221669042.txt | head -60",
  "description": "Search for LLaMA-related registry entries"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "75dd1ac7-7bad-4a76-82ea-835cea39db21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013NkmZ6G9zcKSsDn7kXceZh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 711,
      "cache_read_input_tokens": 60643,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 711
      },
      "output_tokens": 9,
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

_source line 34 · 2026-05-19T20:14:32.946Z_

<details><summary>↩ Tool result · `toolu_018HeouRR5DXKYS9f1Ccjdo9`</summary>

```text
&lt;persisted-output>
Output too large (105.8KB). Full output saved to: /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/b3xfwhr6o.txt

Preview (first 2KB):
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"status\": \"DONE\", \"hypothesis\": \"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"checkpoint_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\", \"log_path\": \"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\"}}, \"plan010_nli_large_ablation\": {\"status\": \"RUNNING\", \"hypothesis\": \"NLI model ablation: 用 DeBERTa-v3-large 替代 v3-base 作为 CED scorer，测试更强 NLI 模型是否提升 RSFT 质量。Baseline: v3-base scored RSFT ign_f1=0.4517 (CED s42)。全流程: v3-large scoring → k=1 filter → RSFT train → D076 eval。三种结果均有论文价值: large更好=当前有提升空间 / 持平=NLI选择鲁棒 / 更差=over-confident scoring引入噪声。Claim 1, 应对 RC 关于 NLI model 选择的潜在质疑。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan010/nli_large_ablation.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"717138\", \"log_path\": \"~/runs/faith-evidence-ie/plan010_nli_large_ablation.log\", \"submitted_at\": \"2026-05-19T18:47:20.191Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_generations\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-large + Qwen3-4B\", \"seed\": 42, \"gpu_ids\": [\"cuda:1\"], \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_nli
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "9b28e4e3-5588-4df0-9a81-f3febbec7405",
  "tool_use_result": {
    "stdout": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan019_1_7b_rsft_no_evidence_eval_2048\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"排除截断混淆后验证 1.7B RSFT negative evidence tax (-7.7pp) 是真实效应还是截断 artifact。原实验 max_new_tokens=1024 截断率 59.2% (583/985)，改用 2048 排除截断伪影。来源: Reviewer warning on plan019_1_7b_rsft_no_evidence_eval。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 bash scripts/seed_expansion/eval_1_7b_no_evidence_2048.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_1_7b_rsft_no_evidence_2048.log\\\"}}, \\\"plan010_nli_large_ablation\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"NLI model ablation: 用 DeBERTa-v3-large 替代 v3-base 作为 CED scorer，测试更强 NLI 模型是否提升 RSFT 质量。Baseline: v3-base scored RSFT ign_f1=0.4517 (CED s42)。全流程: v3-large scoring → k=1 filter → RSFT train → D076 eval。三种结果均有论文价值: large更好=当前有提升空间 / 持平=NLI选择鲁棒 / 更差=over-confident scoring引入噪声。Claim 1, 应对 RC 关于 NLI model 选择的潜在质疑。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan010/nli_large_ablation.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"717138\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan010_nli_large_ablation.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T18:47:20.191Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-large + Qwen3-4B\\\", \\\"seed\\\": 42, \\\"gpu_ids\\\": [\\\"cuda:1\\\"], \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_nli_large\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output\\\", \\\"eval_data\\\": \\\"docred-dev\\\"}}, \\\"seed_llama_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/training.log\\\"}}, \\\"d112_rsft_no_evidence_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B RSFT no-evidence eval r3 (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 D112 RSFT ign_f1。r1/r2 因脚本路径错误失败 (EXIT_CODE=127)，r3 使用正确路径 scripts/seed_expansion/eval_4b_rsft_no_evidence.sh。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/d112_rsft_no_evidence_eval_r3\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r3.log\\\"}}, \\\"plan017_14b_rsft_generate\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"14B RSFT Step 1: 用 14B SFT adapter (ign_f1=0.5507) 在 DocRED 训练集上生成 N=8 RSFT 候选。验证 RSFT pipeline 在第 4 尺度档 (14B) 的有效性，补齐 scaling table 最后一行。D112 已确认 RSFT pipeline 从强 SFT base 出发可提升 +4.18pp (4B)。\\\", \\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\", \\\"cuda:2\\\"], \\\"pid\\\": \\\"712685\\\"}}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"516711\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:33.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5362.4, \\\"gpu_hours\\\": 1.49}}, \\\"plan019_8b_rsft_no_evidence_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT no-evidence eval r2: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。修正 r1 的 cuda:2 冲突问题，改用 cuda:0。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_rsft_no_evidence_eval_r2\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval_r2.log\\\"}}, \\\"d112_rsft_s44_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\\\", \\\"spec\\\": {\\\"command\\\": \\\"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 584466, \\\"tmux_session\\\": \\\"d112_rsft_s44_generate\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\", \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"top_p\\\": 0.95}}, \\\"d112_rsft_s44_ced_score\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 604576, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-base\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/logs/d112_ced_score.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"output_samples\\\": 3014, \\\"note\\\": \\\"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\\\"}}, \\\"plan019_8b_sft_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 8B SFT s43. 补齐第 3 个 8B SFT seed 的 eval 结果。8B SFT s42 ign_f1=0.5128, s44 ign_f1=0.4604. 3-seed mean 将决定 \\\\\\\"1.7B RSFT surpasses 8B SFT\\\\\\\" claim (Claim 3) 的统计力。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/plan019_8b_sft_s43_eval\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s43_eval.log\\\"}}, \\\"d112_rsft_s44_eval_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 4 bf16: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data (bf16 LoRA). 修正原 d112_rsft_s44_eval 的 QLoRA confound。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/d112/eval_d112_rsft_bf16.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"693535\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_s44_eval_bf16.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:04:26.957Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16\\\", \\\"wall_clock_seconds\\\": 14854.9, \\\"gpu_hours\\\": 4.13}}, \\\"plan019_1_7b_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 679713, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"kill_reason\\\": \\\"截断率 59.2% (583/985) 混淆 evidence tax 计算，需 max_new_tokens=2048 重跑\\\"}, \\\"hypothesis\\\": \\\"Removing evidence output at inference time should improve RE ign_f1 above 0.5122 (with-evidence baseline) for 1.7B RSFT, indicating an evidence tax where generating evidence hurts relation extraction performance\\\"}, \\\"plan019_8b_sft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && bash scripts/seed_expansion/sft_8b_s43.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 683937, \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_sft_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T12:04:30.528Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"wall_clock_seconds\\\": 6919.9, \\\"gpu_hours\\\": 1.92, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_qwen3_8b_s43\\\"}, \\\"hypothesis\\\": \\\"8B SFT seed=43: 补齐第 3 seed 改善 '1.7B RSFT surpasses 8B SFT' claim 统计力（当前 p≈0.20，瓶颈在 8B SFT 仅 2 seeds）。Reviewer 建议，对应 plan_019 Claim 3。\\\"}, \\\"plan017_14b_sft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 14B SFT baseline (bf16, --no-quantize). 修正 r1 的 D076 违规（r1 用了 int8 量化）。14B 是第 4 个 scale 档，SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 633106, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_outputs/eval_14b_sft/metrics.json\\\"}}, \\\"d112_rsft_no_evidence_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:41:48.326Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 21.2, \\\"gpu_hours\\\": 0.01}}, \\\"plan019_8b_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT no-evidence eval: 移除 evidence 输出后测量 8B RSFT 的 evidence tax。8B RSFT with-evidence mean ign_f1=0.5414 (s42=0.5376, s44=0.5451)。若 no-evidence ign_f1 > with-evidence，证实 evidence 生成对 8B RE 的性能代价；与 1.7B/4B/14B evidence tax 配合构建跨尺度 scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=2 bash scripts/seed_expansion/eval_8b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"695127\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan019_8b_rsft_no_evidence_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:14:41.563Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"kill_reason\\\": \\\"cuda:2 冲突拖慢 D112 eval 54%+, 移到 cuda:0 重提交\\\", \\\"wall_clock_seconds\\\": 1795.1, \\\"gpu_hours\\\": 0.5}}, \\\"d112_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B RSFT no-evidence eval (D112 bf16 SFT s44 base): 移除 evidence 输出后测量 4B RSFT 的 evidence tax。对比 with-evidence 的 canonical 4B RSFT ign_f1，验证 evidence 生成对 4B RE 性能的代价。与 1.7B/8B/14B no-evidence eval 配合构建跨尺度 evidence tax scaling curve (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && GPU=0 bash scripts/d112/eval_4b_rsft_no_evidence.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_no_evidence_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T13:39:39.027Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 17.2, \\\"gpu_hours\\\": 0.0}}, \\\"d112_rsft_s44_train_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 3 bf16 重跑：RSFT training on SFT s44 base using CED k=1 scored data，使用 bf16 LoRA（非 QLoRA）与其他所有 RSFT 实验一致。修正原 d112_rsft_s44_train 的 QLoRA confound（--quantize 导致 adapter 适应 4-bit 量化误差，bf16 eval 下 ign_f1=0.2181 灾难性崩溃）。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"bash /root/autodl-tmp/scripts/d112/step3_k1_filter_and_train_bf16.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 675161, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\\\", \\\"data_count\\\": 3014, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_ced_score (CED k=1 scored samples, bf16 LoRA rerun)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44_bf16/checkpoint-567\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d112_rsft_s44_train_bf16.log\\\"}}, \\\"plan017_14b_sft_no_evidence_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"14B SFT no-evidence eval (bf16, --no-quantize). 修正 r1 的 D076 违规。测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 633190, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"d112_rsft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 4: D076 eval for RSFT trained on SFT s44 base with CED k=1 scored data. 验证 RSFT 在最强 SFT seed (s44, ign_f1=0.4734) 上的泛化效果。预期 ign_f1 > 0.4734 (SFT s44 baseline)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/d112/step4_eval.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 627505, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan019_1_7b_rsft_s44_r2_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 1.7B RSFT s44_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=44). 预期 ign_f1 接近 s42 (0.5122) 和 s43 (0.5109)，完成 1.7B 3-seed RSFT 统计。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/eval_1_7b_s44_r2.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 632051, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_1_7b_s44_r2_eval/metrics.json\\\"}}, \\\"d112_rsft_s44_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/d112/step3_k1_filter_and_train.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 613075, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/rsft_train.jsonl\\\", \\\"data_count\\\": 3014, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_ced_score (3014 CED k=1 scored samples)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/logs/d112_rsft_s44_train.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_4b_sft_s44\\\"}}, \\\"plan017_14b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 14B SFT baseline. 14B 是第 4 个 scale 档（1.7B/4B/8B/14B），SFT baseline 用于计算 RSFT 增益和 evidence tax。预期 ign_f1 高于 8B SFT mean (0.4866)。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 626093, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan017_14b_sft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"14B SFT no-evidence eval: 测量 14B SFT 在不提供 evidence 时的 ign_f1，用于计算 evidence tax (Claim 3)。与 4B evidence tax (D107: 47.21% vs 39.74%) 对比，验证 scale-dependent evidence tax 趋势。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/14b/eval_14b_sft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 626175, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"plan019_1_7b_rsft_s43_r2_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D076 eval for 1.7B RSFT s43_r2 (Method A: s42 SFT adapter + s42 CED k=1 data, RSFT seed=43). 预期 ign_f1 接近 s42 RSFT (0.5122)，验证 1.7B RSFT 跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash freige/scripts/seed_expansion/eval_1_7b_s43_r2.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 620725, \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 998, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_1_7b_s43_r2_eval/metrics.json\\\"}}, \\\"plan017_14b_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144/trainer_state.json\\\"}, \\\"hypothesis\\\": \\\"Scaling from Qwen3-8B to Qwen3-14B with LoRA SFT on the same DocRED faith-evidence IE data will improve extraction quality because the larger model has greater capacity to learn complex relation extraction patterns with evidence grounding.\\\"}, \\\"plan019_1_7b_rsft_s44_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/checkpoint-567/trainer_state.json\\\"}}, \\\"plan019_1_7b_rsft_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash freige/scripts/seed_expansion/train_1_7b_s43.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 615557, \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training run, not eval)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/checkpoint-567/trainer_state.json\\\"}}, \\\"plan019_1_7b_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"GPU=1 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s44.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_id\\\": \\\"cuda:1\\\", \\\"pid\\\": 602749, \\\"tmux_session\\\": \\\"rsft_1_7b_s44\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 44, \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/trainer_state.json\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training experiment, not eval)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s44/\\\", \\\"final_loss\\\": 0.5539, \\\"final_token_accuracy\\\": 0.8707, \\\"total_steps\\\": 567, \\\"epochs_completed\\\": 3, \\\"failure_reason\\\": \\\"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\\\"}}, \\\"plan019_1_7b_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash /root/autodl-tmp/freige/scripts/seed_expansion/train_1_7b_s43.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_id\\\": \\\"cuda:2\\\", \\\"pid\\\": 601718, \\\"tmux_session\\\": \\\"plan019_1_7b_rsft_s43\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/freige/outputs/rsft_scored_1_7b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3021, \\\"model_name\\\": \\\"Qwen3-1.7B\\\", \\\"seed\\\": 43, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_qwen3_1_7b_bf16\\\", \\\"eval_data\\\": \\\"N/A (training experiment)\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_1_7b_k1_s43/trainer_state.json\\\", \\\"final_loss\\\": 0.5526, \\\"final_token_accuracy\\\": 0.869, \\\"total_steps\\\": 567, \\\"epochs_completed\\\": 3, \\\"failure_reason\\\": \\\"D114: 原始训练结果有效（Method A, s42 adapter 正确），但被 Worker B 误判为 bug 并删除输出。需重跑。\\\"}}, \\\"plan019_8b_rsft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && GPU=0 bash scripts/seed_expansion/eval_8b_s44.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"unknown\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-19T03:52:55.245Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 4365.6, \\\"gpu_hours\\\": 1.21, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s44/\\\", \\\"eval_output\\\": \\\"/root/autodl-tmp/eval_results/rsft_8b_k1_s44_eval/\\\"}}, \\\"d111_4b_sft_s42_reeval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output/ --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"579965\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d111_4b_sft_s42_reeval.log\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-4B + SFT-s42\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"wave1_sft_4b_s42\\\", \\\"eval_data\\\": \\\"DocRED dev\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/d111_4b_sft_s42_reeval\\\"}}, \\\"d112_rsft_s44_gen_shard3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 SHARD=3 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:0\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 759, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 590568, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_3/\\\", \\\"log_path\\\": \\\"N/A (generation job, output in checkpoint_path)\\\"}}, \\\"d112_rsft_s44_gen_shard1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=1 SHARD=1 bash /root/autodl-tmp/scripts/d112/step1_generate_candidates.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"model_name\\\": \\\"4b_sft_s44\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 756, \\\"seed\\\": 44, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/shard_1/generations.jsonl\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_gen_shard1.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\"}}, \\\"d112_rsft_s44_gen_shard2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/auto",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false,
    "persistedOutputPath": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/b3xfwhr6o.txt",
    "persistedOutputSize": 108326
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Bash · `toolu_011f4fQes5Lm8EWkQQMtX3p6`</summary>

```json
{
  "command": "python3 -c \"\nimport json\ndata = json.loads(open('/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/2f65d705-fda0-493a-a477-120726f9c416/tool-results/mcp-agent-ml-research-read_registry-1779221669042.txt').read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\nfor k, v in exps.items():\n    if 'llama' in k.lower() or 'llama' in str(v.get('hypothesis','')).lower() or 'llama' in str(v.get('spec',{}).get('command','')).lower():\n        print(f'=== {k} (status={v.get(\\\"status\\\")}) ===')\n        if v.get('spec',{}).get('command'):\n            print(f'  command: {v[\\\"spec\\\"][\\\"command\\\"]}')\n        print(f'  hypothesis: {v.get(\\\"hypothesis\\\",\\\"N/A\\\")[:200]}')\n        print()\n\"\n",
  "description": "Extract LLaMA-related registry entries"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "d83b0351-b09c-4fb4-830f-82744bc6b4a3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TfrVZYHALJd757UpC5X28A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1273,
      "cache_read_input_tokens": 61354,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1273
      },
      "output_tokens": 52,
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

_source line 36 · 2026-05-19T20:14:39.028Z_

<details><summary>↩ Tool result · `toolu_011f4fQes5Lm8EWkQQMtX3p6`</summary>

```text
=== seed_llama_rsft_k1_s43 (status=DONE) ===
  hypothesis: N/A

=== seed_llama_rsft_k1_s43_eval (status=DONE) ===
  command: source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43
  hypothesis: LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.

=== d102_llama_rsft_k1_s43_eval (status=DONE) ===
  command: source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43
  hypothesis: LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.

=== rsft_llama_k1_s43_train (status=DONE) ===
  command: GPU=3 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_llama_s43.sh
  hypothesis: LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。

=== d102_llama_rsft_k1_s42 (status=DONE) ===
  command: bash -c "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name llama_8b_rsft_ced_k1_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_llama_3_1_8b_k1/checkpoint-250"
  hypothesis: D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。

=== plan_006_llama_rsft_r3_eval (status=DONE) ===
  command: bash -c "source /root/miniconda3/bin/activate && cd /root/autodl-tmp/freige && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_r3/checkpoint-3312 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_r3_eval"
  hypothesis: Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.

=== plan_006_llama_rsft_seed43_eval_r2 (status=DONE) ===
  command: bash -c "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval_r2"
  hypothesis: Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust aga

=== plan_006_llama_rsft_test (status=DONE) ===
  command: python inference.py --model_path /root/autodl-tmp/freige/rsft_output_llama_3_1_8b_r3/checkpoint-3312 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_test --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize
  hypothesis: Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.

=== plan_006_llama_rsft_seed43 (status=DONE) ===
  command: CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43 --per_device_batch_size 1 --gradient_accumulation_steps 8 --seed 43 --bf16 --wandb_run_name plan_006_llama_rsft_seed43
  hypothesis: Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed 

=== plan_006_llama_rsft_seed43_eval (status=DONE) ===
  command: python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval
  hypothesis: Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.

=== plan_016_llama_rsft_train_r3 (status=DONE) ===
  command: CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_r3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --seed 42 --bf16 --wandb_run_name plan_016_llama_rsft_train_r3
  hypothesis: bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues see

=== plan_016_llama_rsft_train_r2 (status=DONE) ===
  command: CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b --seed 42 --quantize --bf16 --per_device_batch_size 2 --gradient_accumulation_steps 8 --wandb_project faith-evidence-ie --wandb_run_name plan_016_llama_rsft_train_r2
  hypothesis: LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.

=== plan_016_llama_rsft_train (status=DONE) ===
  command: CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b --seed 42 --wandb_run_name plan_016_llama_rsft_train
  hypothesis: LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families 

=== plan_016_llama_ced_scoring (status=DONE) ===
  command: bash -c "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=2 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_candidates_llama_3_1_8b --output_path /root/autodl-tmp/rsft_scored_llama_3_1_8b --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --scoring_mode ced --tau 0.5 --selection_strategy top_k --top_k 3"
  hypothesis: CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "72492b57-01b0-46f2-a5a8-495a39c3eb38",
  "tool_use_result": {
    "stdout": "=== seed_llama_rsft_k1_s43 (status=DONE) ===\n  hypothesis: N/A\n\n=== seed_llama_rsft_k1_s43_eval (status=DONE) ===\n  command: source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43\n  hypothesis: LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\n\n=== d102_llama_rsft_k1_s43_eval (status=DONE) ===\n  command: source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43\n  hypothesis: LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\n\n=== rsft_llama_k1_s43_train (status=DONE) ===\n  command: GPU=3 bash /root/autodl-tmp/freige/scripts/seed_expansion/train_llama_s43.sh\n  hypothesis: LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。\n\n=== d102_llama_rsft_k1_s42 (status=DONE) ===\n  command: bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name llama_8b_rsft_ced_k1_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_llama_3_1_8b_k1/checkpoint-250\"\n  hypothesis: D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。\n\n=== plan_006_llama_rsft_r3_eval (status=DONE) ===\n  command: bash -c \"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/freige && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_r3/checkpoint-3312 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_r3_eval\"\n  hypothesis: Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.\n\n=== plan_006_llama_rsft_seed43_eval_r2 (status=DONE) ===\n  command: bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval_r2\"\n  hypothesis: Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust aga\n\n=== plan_006_llama_rsft_test (status=DONE) ===\n  command: python inference.py --model_path /root/autodl-tmp/freige/rsft_output_llama_3_1_8b_r3/checkpoint-3312 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_test --split test --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize\n  hypothesis: Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.\n\n=== plan_006_llama_rsft_seed43 (status=DONE) ===\n  command: CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43 --per_device_batch_size 1 --gradient_accumulation_steps 8 --seed 43 --bf16 --wandb_run_name plan_006_llama_rsft_seed43\n  hypothesis: Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed \n\n=== plan_006_llama_rsft_seed43_eval (status=DONE) ===\n  command: python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_seed43/checkpoint-3312 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/plan_006_llama_rsft_seed43_eval\n  hypothesis: Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.\n\n=== plan_016_llama_rsft_train_r3 (status=DONE) ===\n  command: CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b_r3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --seed 42 --bf16 --wandb_run_name plan_016_llama_rsft_train_r3\n  hypothesis: bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues see\n\n=== plan_016_llama_rsft_train_r2 (status=DONE) ===\n  command: CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b --seed 42 --quantize --bf16 --per_device_batch_size 2 --gradient_accumulation_steps 8 --wandb_project faith-evidence-ie --wandb_run_name plan_016_llama_rsft_train_r2\n  hypothesis: LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.\n\n=== plan_016_llama_rsft_train (status=DONE) ===\n  command: CUDA_VISIBLE_DEVICES=2 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --rsft_data_path /root/autodl-tmp/rsft_scored_llama_3_1_8b/rsft_train.jsonl --num_epochs 3 --output_dir /root/autodl-tmp/rsft_output_llama_3_1_8b --seed 42 --wandb_run_name plan_016_llama_rsft_train\n  hypothesis: LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families \n\n=== plan_016_llama_ced_scoring (status=DONE) ===\n  command: bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=2 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_candidates_llama_3_1_8b --output_path /root/autodl-tmp/rsft_scored_llama_3_1_8b --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --scoring_mode ced --tau 0.5 --selection_strategy top_k --top_k 3\"\n  hypothesis: CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 37_

<details><summary>Logged reasoning block</summary>

````text
Found the key reference. Looking at `seed_llama_rsft_k1_s43_eval` and `d102_llama_rsft_k1_s43_eval`:

```
command: source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43/checkpoint-1107 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 

4 --max_new_tokens 1024 --seed 43 --no-quantize --output_dir /root/autodl-tmp/eval_results/d102_llama_k1_s43
```

Wait, both `seed_llama_rsft_k1_s43_eval` and `d102_llama_rsft_k1_s43_eval` are pointing to the same checkpoint - these are already evaluations for s43. But the user asked me to submit s43 eval, so either it's already been done or I'm misunderstanding what they're asking for.

Let me check the status of those existing eval entries - they show DONE, so they might already have results. The user specifically mentioned needing eval for the completed s43 training, but I'm seeing these entries already exist. I should verify whether these are successful evaluations or if they failed and need to be rerun. Looking at the existing eval entries, both `seed_llama_rsft_k1_s43_eval` and `d102_llama_rsft_k1_s43_eval` are already completed and used checkpoint-1107. The user is asking for a new eval run, so I should just follow their instructions and create `eval_llama_rsft_k1_s43` as requested.

The final adapter in the root directory appears to be the same as checkpoint-1107 based on the timestamps, since HuggingFace Trainer saves the final model to the root output directory at training completion. I'll use the D076 protocol and set up the eval command to run on cuda:3.

Building the inference command... I need to verify the correct parameter name—the existing eval commands used `--model_path` rather than `--adapter_path`, so I should stick with that proven format. Looking at the seed values across similar evaluations, most D076 protocols standardize on seed=42 for eval runs, though there are a few exceptions like the k1_s43 variant that used seed=43. I need to decide between using the root directory or checkpoint-1107 for the adapter path. The root directory contains the final adapter_model.safetensors that the trainer saves at the end, which should be identical to the last checkpoint, so I'll go with the root directory as the user specified.

Now I'm constructing the evaluation command following the existing reference pattern, setting up the CUDA device, model paths, adapter paths, and data configuration with the dev split and batch size.

Adding command parameters...

I need to reconcile the template parameters with what actually worked before—the previous successful eval used checkpoint-1107 and seed 43, but the D076 protocol specifies seed 42. I'm going to stick with checkpoint-1107 since that's proven, though I should verify whether the inference code expects `--adapter_path` or `--model_path` for the adapter specification.

Actually, all the existing successful evals use `--model_path`, so I'll go with that established pattern rather than the template suggestion. Before submitting, I should check if the existing eval runs for this checkpoint are already complete, but since the user explicitly asked me to submit this, I'll proceed with creating the registry entry and submitting the job.

Looking through the available tools, I don't see `submit_training_job` listed anywhere - not in the standard tools or the deferred tools list. I need to find the right tool to actually submit this evaluation.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "6dab5bff-0b1e-40fc-8ad2-c70c6056816b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U9mS2j7JktsHH9deeqdfS6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4354,
      "cache_read_input_tokens": 62627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4354
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

_source line 38_

找到了参考命令。`d102_llama_rsft_k1_s43_eval` 和 `seed_llama_rsft_k1_s43_eval` 都已 DONE，使用了相同的命令格式。但用户要求新建 `eval_llama_rsft_k1_s43`，我继续执行。

关键参数确认：
- Base model: `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B`
- SFT adapter: `/root/autodl-tmp/sft_output_llama_3_1_8b`
- RSFT adapter: `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43`（根目录有最终 adapter）
- 参考命令用 `--model_path` + `--base_model` + `--sft_adapter`

先搜索 `submit_training_job` 工具，同时创建 registry 条目。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "953f40a9-6ae0-4121-8cc1-6fbc31b551fc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U9mS2j7JktsHH9deeqdfS6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4354,
      "cache_read_input_tokens": 62627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4354
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

_source line 39_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01J1vPo7uEKWjoDt5PQvAEdR`</summary>

```json
{
  "query": "submit_training_job",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "e5f02b82-22df-4a78-9754-839aa8b928ca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U9mS2j7JktsHH9deeqdfS6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4354,
      "cache_read_input_tokens": 62627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4354
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

_source line 40 · 2026-05-19T20:15:38.274Z_

<details><summary>↩ Tool result · `toolu_01J1vPo7uEKWjoDt5PQvAEdR`</summary>

```text
No matching deferred tools found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "e211cecb-053c-483e-b1db-84e7511b6f34",
  "tool_use_result": {
    "matches": [],
    "query": "submit_training_job",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01Gn9DzpXo2BJsV6xtMmE8ZZ`</summary>

```json
{
  "exp_id": "eval_llama_rsft_k1_s43",
  "field": "hypothesis",
  "value": "LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。",
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "a9f320c1-c51d-4355-a2f1-0efe7287e1c3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U9mS2j7JktsHH9deeqdfS6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4354,
      "cache_read_input_tokens": 62627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4354
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

_source line 42 · 2026-05-19T20:15:42.525Z_

<details><summary>↩ Tool result · `toolu_01Gn9DzpXo2BJsV6xtMmE8ZZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:15:41.671Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.0383}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "819151eb-2f6c-43d3-b4bc-44947b19da67",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_k1_s43\\\", \\\"experiment\\\": {\\\"status\\\": \\\"PREPARING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-19T20:15:41.671Z\\\", \\\"updated_at\\\": \\\"2026-05-19T20:15:41.671Z\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 2.0383}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:15:41.671Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.0383}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 43_

<details><summary>Logged reasoning block</summary>

````text
`submit_training_job` tool not found. I need to set parent and then transition to RUNNING with the proper spec, and use `ssh_execute` to submit. Let me set parent and prepare the command.

The eval command, based on the proven reference:
```bash
source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_

size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43
```

The user mentioned using `submit_training_job`, but that tool doesn't seem to exist. Looking at the registry entries though, I'm seeing references to `"submitted_via": "submit_training_job"` across multiple entries, which suggests it might be available in the system even if it's not immediately visible. Let me search more thoroughly for this tool.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "59aea0a9-29f9-409d-9bc8-cd80dcc15b47",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RWboH2rQKLk9u7jb9A52Mj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4053,
      "cache_read_input_tokens": 66981,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4053
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

_source line 44_

`submit_training_job` 工具不在可用列表中。让我用 `ssh_execute` 直接提交（通过 nohup + tmux）。先设置 parent 字段。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "35286c1e-b0dc-4591-bb3b-a18c0cbaf9b7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RWboH2rQKLk9u7jb9A52Mj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4053,
      "cache_read_input_tokens": 66981,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4053
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

_source line 45_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01B52WwNg9jFJ59NKRmourUD`</summary>

```json
{
  "exp_id": "eval_llama_rsft_k1_s43",
  "field": "parent",
  "value": "seed_llama_rsft_k1_s43",
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "47fe43a8-0593-4021-b26f-d3aef6bc003c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RWboH2rQKLk9u7jb9A52Mj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4053,
      "cache_read_input_tokens": 66981,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4053
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

_source line 46 · 2026-05-19T20:15:53.772Z_

<details><summary>↩ Tool result · `toolu_01B52WwNg9jFJ59NKRmourUD`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:15:53.247Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\", \"parent\": \"seed_llama_rsft_k1_s43\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.359}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "f81e283b-432e-44c2-8506-de11cb31d73c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_k1_s43\\\", \\\"experiment\\\": {\\\"status\\\": \\\"PREPARING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-19T20:15:41.671Z\\\", \\\"updated_at\\\": \\\"2026-05-19T20:15:53.247Z\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\\\", \\\"parent\\\": \\\"seed_llama_rsft_k1_s43\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.359}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:15:53.247Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\", \"parent\": \"seed_llama_rsft_k1_s43\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.359}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 47_

<details><summary>Logged reasoning block</summary>

````text
Now I need to submit the eval job. The command will be:

```bash
source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl

-tmp/eval_results/eval_llama_rsft_k1_s43
```

I'll wrap this in a tmux session so it runs persistently in the background.

```bash
tmux new-session -d -s eval_llama_rsft_k1_s43 'bash -c "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43 2>&1 | tee ~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log"'
```

I've confirmed that GPU 3 is available with no memory in use, and I'm setting CUDA_VISIBLE_DEVICES to isolate it for this job. Ready to submit.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "d18ca6bc-b201-4627-9a26-aadd466521d6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UwdDRUjFSiZH2sEyeJ6A9D",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 826,
      "cache_read_input_tokens": 71034,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 826
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

_source line 48_

cuda:3 已确认空闲（0 MiB），C001 满足。现在用 tmux 提交 eval 到 cuda:3。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "aafcbcdd-f482-4cae-ad96-e0ac1a115bc6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UwdDRUjFSiZH2sEyeJ6A9D",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 826,
      "cache_read_input_tokens": 71034,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 826
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

_source line 49_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_013PWHfQTxcjSMPHsJWWxYr5`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "mkdir -p ~/runs/faith-evidence-ie /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43 && tmux new-session -d -s eval_llama_rsft_k1_s43 'bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43 2>&1 | tee ~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log\"' && echo \"TMUX_OK\" && sleep 3 && tmux list-sessions | grep eval_llama",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "6a1f9af6-f8ac-44da-82d9-28a521eb13c8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UwdDRUjFSiZH2sEyeJ6A9D",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 826,
      "cache_read_input_tokens": 71034,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 826
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

_source line 50 · 2026-05-19T20:16:12.492Z_

<details><summary>↩ Tool result · `toolu_013PWHfQTxcjSMPHsJWWxYr5`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"TMUX_OK\\neval_llama_rsft_k1_s43: 1 windows (created Wed May 20 04:16:09 2026)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 3.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "3e364885-96dc-4df6-9b62-95e7cb1f1869",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"TMUX_OK\\\\neval_llama_rsft_k1_s43: 1 windows (created Wed May 20 04:16:09 2026)\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 3.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"TMUX_OK\\neval_llama_rsft_k1_s43: 1 windows (created Wed May 20 04:16:09 2026)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 3.31}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 51_

<details><summary>Logged reasoning block</summary>

```text
Tmux session started. Let me verify the process is running and get the PID, then update registry to RUNNING.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "4a9ed35c-7837-438b-a29d-cb200b7e8ea3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FkZFZ8xF2ji2eiM3ey2yaX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1316,
      "cache_read_input_tokens": 71860,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1316
      },
      "output_tokens": 28,
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

_source line 52_

Tmux session 已启动。确认进程和 GPU 占用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "bc9f6606-513b-44be-aa88-702a61268b3e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FkZFZ8xF2ji2eiM3ey2yaX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1316,
      "cache_read_input_tokens": 71860,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1316
      },
      "output_tokens": 28,
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

_source line 53_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_019BrR6H8Jc2KLrhEfLrW54y`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ps aux --no-headers -o pid,command -w -w | grep \"eval.inference.*eval_llama_rsft_k1_s43\" | grep -v grep",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "0645956d-802a-4cf4-9a23-0ff08eed6e85",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FkZFZ8xF2ji2eiM3ey2yaX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1316,
      "cache_read_input_tokens": 71860,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1316
      },
      "output_tokens": 28,
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

_source line 54 · 2026-05-19T20:16:18.317Z_

<details><summary>↩ Tool result · `toolu_019BrR6H8Jc2KLrhEfLrW54y`</summary>

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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "c2a4c63e-6653-4b94-a7bb-0d54bee5f220",
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

_source line 55_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01EueFFoHdVpC9R9vSMstJ1b`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "tail -5 /root/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log",
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
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "3a18a176-05ab-4602-85ca-40aa953d36cc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014xLZjw65dhacWw8sb3Rq3p",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 299,
      "cache_read_input_tokens": 73176,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 299
      },
      "output_tokens": 65,
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

_source line 56 · 2026-05-19T20:16:22.229Z_

<details><summary>↩ Tool result · `toolu_01EueFFoHdVpC9R9vSMstJ1b`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"2026-05-20 04:16:14,508 INFO Loading model: /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\n`torch_dtype` is deprecated! Use `dtype` instead!\\n2026-05-20 04:16:14,739 INFO We will use 90% of the memory on device 0 for storing the model, and 10% for the buffer to avoid OOM. You can set `max_memory` in to a higher value to use more memory (at your own risk).\\n\\rLoading checkpoint shards:   0%|          | 0/4 [00:00<?, ?it/s]\\rLoading checkpoint shards:  25%|██▌       | 1/4 [00:01<00:05,  1.93s/it]\\rLoading checkpoint shards:  50%|█████     | 2/4 [00:03<00:03,  1.94s/it]\\rLoading checkpoint shards:  75%|███████▌  | 3/4 [00:06<00:02,  2.03s/it]\\rLoading checkpoint shards: 100%|██████████| 4/4 [00:06<00:00,  1.42s/it]\\rLoading checkpoint shards: 100%|██████████| 4/4 [00:06<00:00,  1.63s/it]\\n2026-05-20 04:16:21,279 INFO Loading & merging SFT adapter: /root/autodl-tmp/sft_output_llama_3_1_8b\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.64}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "7993d9b2-38fa-46ec-8d50-6c99bfeba260",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"2026-05-20 04:16:14,508 INFO Loading model: /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\\n`torch_dtype` is deprecated! Use `dtype` instead!\\\\n2026-05-20 04:16:14,739 INFO We will use 90% of the memory on device 0 for storing the model, and 10% for the buffer to avoid OOM. You can set `max_memory` in to a higher value to use more memory (at your own risk).\\\\n\\\\rLoading checkpoint shards:   0%|          | 0/4 [00:00<?, ?it/s]\\\\rLoading checkpoint shards:  25%|██▌       | 1/4 [00:01<00:05,  1.93s/it]\\\\rLoading checkpoint shards:  50%|█████     | 2/4 [00:03<00:03,  1.94s/it]\\\\rLoading checkpoint shards:  75%|███████▌  | 3/4 [00:06<00:02,  2.03s/it]\\\\rLoading checkpoint shards: 100%|██████████| 4/4 [00:06<00:00,  1.42s/it]\\\\rLoading checkpoint shards: 100%|██████████| 4/4 [00:06<00:00,  1.63s/it]\\\\n2026-05-20 04:16:21,279 INFO Loading & merging SFT adapter: /root/autodl-tmp/sft_output_llama_3_1_8b\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.64}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"2026-05-20 04:16:14,508 INFO Loading model: /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\n`torch_dtype` is deprecated! Use `dtype` instead!\\n2026-05-20 04:16:14,739 INFO We will use 90% of the memory on device 0 for storing the model, and 10% for the buffer to avoid OOM. You can set `max_memory` in to a higher value to use more memory (at your own risk).\\n\\rLoading checkpoint shards:   0%|          | 0/4 [00:00<?, ?it/s]\\rLoading checkpoint shards:  25%|██▌       | 1/4 [00:01<00:05,  1.93s/it]\\rLoading checkpoint shards:  50%|█████     | 2/4 [00:03<00:03,  1.94s/it]\\rLoading checkpoint shards:  75%|███████▌  | 3/4 [00:06<00:02,  2.03s/it]\\rLoading checkpoint shards: 100%|██████████| 4/4 [00:06<00:00,  1.42s/it]\\rLoading checkpoint shards: 100%|██████████| 4/4 [00:06<00:00,  1.63s/it]\\n2026-05-20 04:16:21,279 INFO Loading & merging SFT adapter: /root/autodl-tmp/sft_output_llama_3_1_8b\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.64}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 57_

进程正在加载模型，工作正常。更新 registry 到 RUNNING。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "c9074ac2-1140-4438-8e92-87f6dcdac000",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MdPPihbZmAE5xWjuxpTLEe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 616,
      "cache_read_input_tokens": 73475,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 616
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

_source line 58_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_013pZNXnDmwhxv7L2mw6k1oC`</summary>

```json
{
  "exp_id": "eval_llama_rsft_k1_s43",
  "field": "status",
  "value": "RUNNING",
  "project": "faith-evidence-ie",
  "spec": {
    "command": "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43",
    "server": "rtx5090-4x",
    "gpu": [
      "cuda:3"
    ],
    "log_path": "~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/data/docred",
    "data_count": 985,
    "model_name": "LLaMA-3.1-8B",
    "seed": 42,
    "checkpoint_source": "/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43",
    "eval_data": "/root/autodl-tmp/data/docred/dev.json"
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "bc04708b-de3b-492c-9cfc-2cf83c3024fe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MdPPihbZmAE5xWjuxpTLEe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 616,
      "cache_read_input_tokens": 73475,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 616
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

_source line 59 · 2026-05-19T20:16:31.159Z_

<details><summary>↩ Tool result · `toolu_013pZNXnDmwhxv7L2mw6k1oC`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"Invalid transition: PREPARING → RUNNING. Allowed: ['PENDING', 'QUEUED']\", \"metadata\": {\"elapsed_seconds\": 0.6858}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "ab795637-4752-4f62-84ea-4ac2d84dac7c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"Invalid transition: PREPARING → RUNNING. Allowed: ['PENDING', 'QUEUED']\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.6858}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"Invalid transition: PREPARING → RUNNING. Allowed: ['PENDING', 'QUEUED']\", \"metadata\": {\"elapsed_seconds\": 0.6858}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 60_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_018zLLX6hQmHwvztcRxKtU5c`</summary>

```json
{
  "exp_id": "eval_llama_rsft_k1_s43",
  "field": "status",
  "value": "QUEUED",
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "ba587597-d46c-49cc-b1b9-52b413893afd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017CxFg9UW6ygiPGovC2c82J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 644,
      "cache_read_input_tokens": 74091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 644
      },
      "output_tokens": 69,
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

_source line 61 · 2026-05-19T20:16:36.448Z_

<details><summary>↩ Tool result · `toolu_018zLLX6hQmHwvztcRxKtU5c`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:16:34.977Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\", \"parent\": \"seed_llama_rsft_k1_s43\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.1685}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "152e642e-16da-412b-8fce-20062e707750",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_k1_s43\\\", \\\"experiment\\\": {\\\"status\\\": \\\"QUEUED\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-19T20:15:41.671Z\\\", \\\"updated_at\\\": \\\"2026-05-19T20:16:34.977Z\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\\\", \\\"parent\\\": \\\"seed_llama_rsft_k1_s43\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 2.1685}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:16:34.977Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\", \"parent\": \"seed_llama_rsft_k1_s43\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.1685}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 62_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01SqKRiYHCxXiGuQ1QsCXeQw`</summary>

```json
{
  "exp_id": "eval_llama_rsft_k1_s43",
  "field": "status",
  "value": "RUNNING",
  "project": "faith-evidence-ie",
  "spec": {
    "command": "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43",
    "server": "rtx5090-4x",
    "gpu": [
      "cuda:3"
    ],
    "log_path": "~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/data/docred",
    "data_count": 985,
    "model_name": "LLaMA-3.1-8B",
    "seed": 42,
    "checkpoint_source": "/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43",
    "eval_data": "/root/autodl-tmp/data/docred/dev.json"
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "75746f0a-510e-42bf-a5b0-23e8f7ea68b3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YTokTCg2orE9fkkJ22WhXq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 376,
      "cache_read_input_tokens": 74735,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 376
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

_source line 63 · 2026-05-19T20:16:44.796Z_

<details><summary>↩ Tool result · `toolu_01SqKRiYHCxXiGuQ1QsCXeQw`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:16:43.239Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\", \"parent\": \"seed_llama_rsft_k1_s43\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"LLaMA-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.2262}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "6290cb38-a6d1-46c8-9d9f-79669062f03e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_k1_s43\\\", \\\"experiment\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-19T20:15:41.671Z\\\", \\\"updated_at\\\": \\\"2026-05-19T20:16:43.239Z\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\\\", \\\"parent\\\": \\\"seed_llama_rsft_k1_s43\\\", \\\"spec\\\": {\\\"command\\\": \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"LLaMA-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 2.2262}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_k1_s43\", \"experiment\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:15:41.671Z\", \"updated_at\": \"2026-05-19T20:16:43.239Z\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 s43 eval: 验证 LLaMA RSFT seed robustness。Baseline: s42 ign_f1=0.5839, SFT ign_f1=0.5514。\", \"parent\": \"seed_llama_rsft_k1_s43\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"LLaMA-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.2262}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 64_

已提交。汇总：

**eval_llama_rsft_k1_s43** — RUNNING on cuda:3

| 项 | 值 |
|---|---|
| tmux session | `eval_llama_rsft_k1_s43` |
| GPU | cuda:3 (确认空闲 0 MiB) |
| base model | `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B` |
| SFT adapter | `/root/autodl-tmp/sft_output_llama_3_1_8b` |
| RSFT adapter | `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43` |
| output | `/root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43` |
| log | `~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log` |
| D076 参数 | `--no-quantize --batch_size 4 --max_new_tokens 1024 --seed 42` |

日志确认模型已开始加载（base model shards loaded, SFT adapter merging）。

注：`submit_training_job` 工具不在当前可用工具列表中，改用 `ssh_execute` + tmux 直接提交。命令格式参考 `d102_llama_rsft_k1_s43_eval` 的已验证命令。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "uuid": "e0efc2ef-42e9-48af-87c2-53d46f1db79d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017yeUqBQHKFUM8Heb9PHJXU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1213,
      "cache_read_input_tokens": 75111,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1213
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

_source line 65_

已提交。汇总：

**eval_llama_rsft_k1_s43** — RUNNING on cuda:3

| 项 | 值 |
|---|---|
| tmux session | `eval_llama_rsft_k1_s43` |
| GPU | cuda:3 (确认空闲 0 MiB) |
| base model | `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B` |
| SFT adapter | `/root/autodl-tmp/sft_output_llama_3_1_8b` |
| RSFT adapter | `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43` |
| output | `/root/autodl-tmp/eval_results/eval_llama_rsft_k1_s43` |
| log | `~/runs/faith-evidence-ie/eval_llama_rsft_k1_s43.log` |
| D076 参数 | `--no-quantize --batch_size 4 --max_new_tokens 1024 --seed 42` |

日志确认模型已开始加载（base model shards loaded, SFT adapter merging）。

注：`submit_training_job` 工具不在当前可用工具列表中，改用 `ssh_execute` + tmux 直接提交。命令格式参考 `d102_llama_rsft_k1_s43_eval` 的已验证命令。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 188226,
  "duration_api_ms": 174013,
  "num_turns": 22,
  "stop_reason": "end_turn",
  "session_id": "2f65d705-fda0-493a-a477-120726f9c416",
  "total_cost_usd": 1.11273125,
  "usage": {
    "input_tokens": 20,
    "cache_creation_input_tokens": 64483,
    "cache_read_input_tokens": 899089,
    "output_tokens": 10299,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 64483,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 396,
        "cache_read_input_tokens": 75111,
        "cache_creation_input_tokens": 1213,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 1213
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2478,
      "outputTokens": 23,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0025930000000000003,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 20,
      "outputTokens": 10299,
      "cacheReadInputTokens": 899089,
      "cacheCreationInputTokens": 64483,
      "webSearchRequests": 0,
      "costUSD": 1.1101382499999999,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "3ea3a97c-b8b0-456a-b3d2-8e568ef1fea7"
}
```

</details>

---

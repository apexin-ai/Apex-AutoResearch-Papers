# analysis vanilla per operator

**When Does Unpaired Error Injection Help LLM Agents? Hypotheses from a Failed Transfer to Embodied Planning** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 44
- **Recorded user turns:** 0
- **Tool calls:** 14
- **Original source:** `logs/workers/worker_analysis_vanilla-per-operator_20260515T032830.log`
- **Structured JSON:** [`7e6023b2aed87a5cbd12.json`](../../sessions/7e/7e6023b2aed87a5cbd12.json)

## Before a recorded user message

44 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
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
  "uuid": "68326068-30ed-40c8-bc07-1e7220cc1a13",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/memory/"
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
    "resetsAt": 1778826600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "0839fe07-7c5d-447c-8bb7-e1553b715efe",
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684"
}
```

---

### Assistant

_source line 4_

I'll find the vanilla recovery eval results and extract per-operator breakdown. Let me start by loading the necessary tools and searching for the eval files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "d499e045-af1e-4054-b352-a1e348cfe483",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PaMbZ9cWTFjACzEHrPfktF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11478,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11478
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_014M7Sfd7jJa4qkKqhUhVeXX`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__register_artifact",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "017946ce-34a1-4f95-b829-185ef959a98b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PaMbZ9cWTFjACzEHrPfktF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11478,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11478
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

_source line 6 · 2026-05-15T03:28:42.557Z_

<details><summary>↩ Tool result · `toolu_014M7Sfd7jJa4qkKqhUhVeXX`</summary>

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
  "tool_name": "mcp__agent-ml-research__update_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "85198c27-2161-485e-9316-cd628181b783",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 29
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the current registry entry for v4-vanilla-recovery-eval and searching for the eval result files on the server.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "2a1d749b-036c-4f6a-b5d0-689d4e9c8f24",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BgD6bkwBEgP6zknTePJqn3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1825,
      "cache_read_input_tokens": 23319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1825
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

_source line 8_

Let me check the registry and find the eval files on the server simultaneously.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "98da34e0-d616-44a0-b057-02cb26f2f3ef",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BgD6bkwBEgP6zknTePJqn3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1825,
      "cache_read_input_tokens": 23319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1825
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

_source line 9_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_014dHFhgsr5d1Cp6hLRVjQWg`</summary>

```json
{
  "filters": {
    "exp_id": "v4-vanilla-recovery-eval"
  },
  "project": "tax_error_inject_agent",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "d47cd484-f8ed-4321-a11e-a87dc9f68b57",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BgD6bkwBEgP6zknTePJqn3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1825,
      "cache_read_input_tokens": 23319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1825
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

_source line 10 · 2026-05-15T03:28:47.185Z_

<details><summary>↩ Tool result · `toolu_014dHFhgsr5d1Cp6hLRVjQWg`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.1397}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "2ff4ba22-49ba-4469-926a-582fa5594ed1",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.1397}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.1397}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_0119vNHmpzgAnfHoekPPvt51`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/tax_error_inject_agent/eval_results/ -name \"*vanilla*recovery*\" -o -name \"*recovery*vanilla*\" 2>/dev/null",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "831b0e0d-69f4-4bbe-b3ed-ba27e7870028",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BgD6bkwBEgP6zknTePJqn3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1825,
      "cache_read_input_tokens": 23319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1825
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

_source line 12 · 2026-05-15T03:28:48.513Z_

<details><summary>↩ Tool result · `toolu_0119vNHmpzgAnfHoekPPvt51`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "9f80dc14-9f21-4edb-a8b6-564a27d36a2f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017FiKUHWanNasQ8z5WLjkfY`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/runs/tax_error_inject_agent/ -name \"*vanilla*recovery*\" -o -name \"*recovery*vanilla*\" 2>/dev/null",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "c54942f6-bd9b-4ffc-8595-f1f741b0c892",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BgD6bkwBEgP6zknTePJqn3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1825,
      "cache_read_input_tokens": 23319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1825
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

_source line 14 · 2026-05-15T03:28:49.435Z_

<details><summary>↩ Tool result · `toolu_017FiKUHWanNasQ8z5WLjkfY`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "69a9e5dd-c896-412f-ac87-d83b064a4e31",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
The `-o` flag in find is causing issues with the shell metacharacter detection. Let me try without `-o` and do separate finds. Also the registry returned 0 results for the filter - maybe the exp_id format is different. Let me search more broadly.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "58cc4ef3-81d9-4103-bdaa-ff56a7542f4a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UMFdjCvsRU7VJegwyWWpVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 25144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 16_

Registry filter returned 0 results — the exp_id might be different. Let me fix the search commands and broaden the registry query.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "c144f3c7-7e25-4276-808d-d5d233047978",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UMFdjCvsRU7VJegwyWWpVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 25144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 17_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01UDdxdiVHLXDQVxcnUNS6mh`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "fields": [
    "*"
  ],
  "limit": 20
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "77aa44dd-77bd-42e0-b933-c886f6609452",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UMFdjCvsRU7VJegwyWWpVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 25144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 18 · 2026-05-15T03:28:54.744Z_

<details><summary>↩ Tool result · `toolu_01UDdxdiVHLXDQVxcnUNS6mh`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:43:46.913Z\", \"updated_at\": \"2026-05-15T02:03:49.013Z\", \"hypothesis\": \"v4 Random 50% injection fixed-size eval — 47 tasks clean eval. 与 TaxEI 50% (51.1%) 对比。Random dose-response 最后一点。\", \"spec\": {\"gpu\": [\"cuda:3\"]}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:56:26.837Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:56:28.410747+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.574, \"eval_successes\": 27, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -4.3, \"vs_taxei_50_pp\": 6.3}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject50_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-eval.log\", \"completed_at\": \"2026-05-15T02:00:22.858Z\"}, \"v4-random-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:48:25.777Z\", \"updated_at\": \"2026-05-15T02:03:46.203Z\", \"hypothesis\": \"v4 Random 25% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 25% (48.9%) 对比。\", \"parent\": \"v4-random-fixed-inject25\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"parent\": \"v4-random-fixed-inject25\", \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_path\": \"eval/alfworld_47_clean\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject25)\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"pid\": \"112516\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -6.4, \"vs_taxei_25_pp\": 6.4}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject25_eval.json\", \"completed_at\": \"2026-05-15T01:59:41.894Z\"}, \"v4-random-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:45:08.375Z\", \"updated_at\": \"2026-05-15T02:02:45.338Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection (4,358 total = 2,179 clean + 2,179 injected). 与 TaxEI 50% 对比 taxonomy 标签在高注入比例下是否有差异。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/random_fixed_inject50/v0-20260515-084528/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:39:15.464Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:39:17.014804+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358, \"train_loss\": 0.4338, \"final_step_loss\": 0.2618, \"token_accuracy\": 0.91, \"train_duration_min\": 53.1, \"memory_gib\": 18, \"train_speed_s_per_it\": 1.95}, \"completed_at\": \"2026-05-15T01:43:35.237Z\"}, \"v4-random-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:44.436Z\", \"updated_at\": \"2026-05-15T01:48:07.606Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection (4,358 total). 与 TaxEI 25% (48.9%) 对比 taxonomy 标签在中等注入比例下是否有差异。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject25 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:1\", \"max_steps\": 1635, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:43:59.432Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:44:03.491274+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}, \"completed_at\": \"2026-05-15T01:48:05.171Z\"}, \"v4-random-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:17.994Z\", \"updated_at\": \"2026-05-15T01:42:40.302Z\", \"hypothesis\": \"v4 Random 10% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 10% (61.7%) 对比。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject10_eval.json --device cuda:2\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"110187\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"submitted_at\": \"2026-05-15T01:28:27.422Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10\", \"checkpoint_source\": \"v4-random-fixed-inject10\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_count\": 47, \"data_path\": \"eval/alfworld_47_clean\", \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10)\", \"seed\": 42, \"wall_clock_seconds\": 852.9, \"gpu_hours\": 0.24}, \"parent\": \"v4-random-fixed-inject10\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:42:40.303Z\"}, \"v4-taxei-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:14.823Z\", \"updated_at\": \"2026-05-15T01:38:54.383Z\", \"spec\": {\"command\": \"python eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_taxei_fixed_inject50_eval.json --device cuda:0 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (v4-taxei-fixed-inject50)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"eval_data\": \"ALFWorld valid_unseen 47 tasks clean eval\"}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection eval — 47 tasks clean eval. Dose-response 最后一个数据点。已有：0%=61.7%, 10%=61.7%, 25%=48.9%, 50%=待测。\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -10.6}, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"log_path\": \"/tmp/eval_inject50.log\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T01:37:38.792Z\"}, \"v4-random-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:41.996Z\", \"updated_at\": \"2026-05-15T01:31:01.715Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection (4,358 total). 与 TaxEI 10% (61.7%) 对比 taxonomy 标签在低注入比例下是否有差异。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=2 && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject10 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"104655\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T00:28:19.537Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"wall_clock_seconds\": 3546.1, \"gpu_hours\": 0.99}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:26:29.568Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:26:31.003606+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4226, \"final_step_loss\": 0.3079, \"token_accuracy\": 0.9, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 57}, \"completed_at\": \"2026-05-15T01:27:25.646Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\"}, \"v4-taxei-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:38.284Z\", \"updated_at\": \"2026-05-15T01:25:47.611Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio (4,358 total = 2,179 clean + 2,179 injected). Dose-response 最后一个点，完成后有完整曲线 0%→10%→25%→50%。\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --learning_rate 1e-4\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"104236\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50.log\", \"submitted_at\": \"2026-05-15T00:27:51.219Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"wall_clock_seconds\": 3476.4, \"gpu_hours\": 0.97}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:22:23.688Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:22:25.093365+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.259, \"token_accuracy\": 0.911, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 53.1}, \"completed_at\": \"2026-05-15T01:25:47.611Z\"}, \"v4-random-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:14:30.699Z\", \"updated_at\": \"2026-05-15T00:27:24.291Z\", \"hypothesis\": \"v4 Random SFT seed=123 eval — 47 tasks clean eval. Multi-seed: seed=42 66.0%, seed=0 55.3%, seed=123 待测。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=1 && cd /root/autodl-tmp/tax_error_inject_agent && python eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 102888, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"submitted_at\": \"2026-05-15T00:14:42.930Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"eval_data\": \"47 tasks clean eval (no injection)\", \"parent\": \"v4-random-seed123\", \"tmux_session\": \"v4-random-seed123-eval\", \"log_file\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"wall_clock_seconds\": 740.0, \"gpu_hours\": 0.21}, \"conclusion\": \"negative\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"completed_at\": \"2026-05-15T00:27:02.930Z\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-taxei-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:53.016Z\", \"updated_at\": \"2026-05-15T00:14:40.327Z\", \"hypothesis\": \"v4 TaxEI 25% injection fixed-size eval — 48.9% (23/47), 显著低于 vanilla baseline 65.3%（-16.4pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"checkpoint_source\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject25-r2\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject25)\", \"seed\": 42}, \"metrics\": {\"eval_success_rate\": 0.489, \"eval_successes\": 23, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 4, \"total\": 6, \"rate\": 0.667}, \"pick_and_place_simple\": {\"success\": 3, \"total\": 8, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject25_eval.json\", \"log_path\": \"/tmp/v4_taxei_fixed_inject25_eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:30.429Z\"}, \"v4-taxei-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:52.584Z\", \"updated_at\": \"2026-05-15T00:14:38.874Z\", \"hypothesis\": \"v4 TaxEI 10% injection fixed-size eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject10_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"tmux_session\": \"eval_inject10\", \"checkpoint_source\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject10\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10)\", \"seed\": 42, \"log_path\": \"/tmp/v4_taxei_fixed_inject10_eval.log\"}, \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject10_eval.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.992Z\"}, \"v4-taxei-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:07.489Z\", \"updated_at\": \"2026-05-15T00:14:37.513Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed123_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 100600, \"model_name\": \"Qwen3-8B + LoRA (taxei v4 seed=123)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed123\", \"checkpoint_path\": \"eval_results/v4_taxei_seed123_eval.json\", \"log_path\": \"/tmp/v4_taxei_seed123_eval.log\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47}, \"hypothesis\": \"v4 TaxEI SFT seed=123 eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。multi-seed verification, 9029 samples。\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.055Z\"}, \"v4-random-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.441Z\", \"updated_at\": \"2026-05-14T23:52:15.056Z\", \"hypothesis\": \"v4 Random SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 93477, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123.log\", \"submitted_at\": \"2026-05-14T21:59:16.545Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6778.5, \"gpu_hours\": 1.88}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:50:09.168Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:50:10.389568+00:00\"}]}, \"metrics\": {\"train_loss\": 0.35484016, \"final_loss\": 0.16766574, \"token_accuracy\": 0.94187103, \"avg_token_accuracy\": 0.90849673, \"train_steps\": 3387, \"train_epochs\": 3, \"train_runtime_sec\": 6609.3556, \"train_duration_min\": 110.2, \"train_samples_per_second\": 4.098, \"train_steps_per_second\": 0.512, \"train_speed_s_per_it\": 1.951, \"memory_gib\": 18.49}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:52:15.056Z\"}, \"v4-taxei-fixed-inject25-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:32:41.837Z\", \"updated_at\": \"2026-05-14T23:50:46.230Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio retry (4,358 total = 3,268 clean + 1,090 injected). 修复 CUDA_VISIBLE_DEVICES，显式设 =3。\", \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=3 && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --output_dir checkpoints/taxei_fixed_inject25 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 96835, \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"note\": \"manual tmux with explicit CUDA_VISIBLE_DEVICES=3, fixing r1 OOM\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.285, \"token_accuracy\": 0.893, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:46.230Z\"}, \"v4-taxei-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:52.707Z\", \"updated_at\": \"2026-05-14T23:50:45.829Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio (4,358 total = 3,922 clean + 436 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --output_dir output/v4-fixed-inject10 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"94635\", \"log_path\": \"/tmp/v4-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T06:12:34Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.308, \"token_accuracy\": 0.888, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:45.829Z\"}, \"v4-taxei-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:53.209Z\", \"updated_at\": \"2026-05-14T23:45:26.890Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio (4,358 total = 3,268 clean + 1,090 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject25.jsonl --output_dir output/v4-fixed-inject25 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"96835\", \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"submitted_at\": \"2026-05-15T06:31:44Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"note\": \"r1 (PID 95170) OOM on cuda:0 — submit_training_job failed to pass CUDA_VISIBLE_DEVICES. Resubmitted manually via tmux with explicit export CUDA_VISIBLE_DEVICES=3.\"}, \"conclusion\": \"failed\", \"failure_reason\": \"CUDA_VISIBLE_DEVICES 未生效，模型加载到 cuda:0 导致 OOM（与 seed123 训练冲突）\", \"completed_at\": \"2026-05-14T23:45:26.890Z\"}, \"v4-taxei-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.191Z\", \"updated_at\": \"2026-05-14T23:43:38.819Z\", \"hypothesis\": \"v4 TaxEI SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 92263, \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed123.log\", \"submitted_at\": \"2026-05-14T21:50:17.845Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6801.0, \"gpu_hours\": 1.89}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:41:32.774Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:41:33.984355+00:00\"}]}, \"metrics\": {\"final_loss\": 0.35506879, \"token_accuracy\": 0.89978214, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 109.2, \"train_runtime_sec\": 6549.432, \"train_speed_s_per_it\": 1.934, \"memory_gib\": 18.49}, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:43:38.819Z\"}, \"v4-fixed-inject25\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:23.317Z\", \"updated_at\": \"2026-05-14T22:29:19.308Z\", \"spec\": {\"hypothesis\": \"Fixed-size ablation: 25% injection ratio (4,358 total samples, ~1,090 injected + ~3,269 clean). Tests intermediate injection ratio. Combined with 10%/50% results, reveals dose-response curve. Addresses Reviewer Concern #5.\", \"parent\": \"v4-taxei-eval\", \"plan_id\": \"fixed-size-ablation\", \"reviewer_concern\": \"RC5\"}, \"conclusion\": \"killed\", \"failure_reason\": \"duplicate entry — active experiment is v4-taxei-fixed-inject25 (RUNNING)\"}, \"v4-fixed-inject10\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:21.673Z\", \"updated_at\": \"2026-05-14T22:29:18.354Z\", \"spec\": {\"hypothesis\": \"Fixed-size ablation: 10% injection ratio (4,358 total samples, ~436 injected + ~3,922 clean). Tests whether low injection ratio still harms clean performance. If yes → injection itself is harmful regardless of ratio. Addresses Reviewer Concern #5.\", \"parent\": \"v4-taxei-eval\", \"plan_id\": \"fixed-size-ablation\", \"reviewer_concern\": \"RC5\"}, \"conclusion\": \"killed\", \"failure_reason\": \"duplicate entry — active experiment is v4-taxei-fixed-inject10 (RUNNING)\"}, \"v4-random-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:04:57.591Z\", \"updated_at\": \"2026-05-14T22:00:43.285Z\", \"hypothesis\": \"v4 Random SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla/taxei recovery eval.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_recovery_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 90124, \"model_name\": \"Qwen3-8B + LoRA (random SFT v4)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387\", \"eval_data\": \"valid_unseen (47 episodes)\", \"log_path\": \"/tmp/v4_random_recovery_eval.log\", \"output_path\": \"eval_results/v4_random_recovery_eval.json\", \"data_path\": \"valid_unseen\", \"data_count\": 47}, \"conclusion\": \"success\", \"checkpoint_path\": \"eval_results/v4_random_recovery_eval.json\", \"completed_at\": \"2026-05-14T21:42:07.544Z\", \"metrics\": {\"recovery_rate\": 0.638, \"detection_rate\": 0, \"successes\": 30, \"total\": 47, \"source\": \"json-file-verified\", \"note\": \"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\"}}}, \"count\": 20, \"total\": 61, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.1479}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "778cc3e2-e952-4449-977f-8eb8f9ed2851",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"v4-random-fixed-inject50-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T01:43:46.913Z\\\", \\\"updated_at\\\": \\\"2026-05-15T02:03:49.013Z\\\", \\\"hypothesis\\\": \\\"v4 Random 50% injection fixed-size eval — 47 tasks clean eval. 与 TaxEI 50% (51.1%) 对比。Random dose-response 最后一点。\\\", \\\"spec\\\": {\\\"gpu\\\": [\\\"cuda:3\\\"]}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-15T01:56:26.837Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-15T01:56:28.410747+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.574, \\\"eval_successes\\\": 27, \\\"eval_total\\\": 47, \\\"vs_vanilla_seed42_pp\\\": -4.3, \\\"vs_taxei_50_pp\\\": 6.3}, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject50_eval.json\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-eval.log\\\", \\\"completed_at\\\": \\\"2026-05-15T02:00:22.858Z\\\"}, \\\"v4-random-fixed-inject25-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T01:48:25.777Z\\\", \\\"updated_at\\\": \\\"2026-05-15T02:03:46.203Z\\\", \\\"hypothesis\\\": \\\"v4 Random 25% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 25% (48.9%) 对比。\\\", \\\"parent\\\": \\\"v4-random-fixed-inject25\\\", \\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_eval.json --device cuda:0\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"parent\\\": \\\"v4-random-fixed-inject25\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean, no injection)\\\", \\\"data_path\\\": \\\"eval/alfworld_47_clean\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random fixed inject25)\\\", \\\"seed\\\": 42, \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"112516\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-eval.log\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.553, \\\"eval_successes\\\": 26, \\\"eval_total\\\": 47, \\\"vs_vanilla_seed42_pp\\\": -6.4, \\\"vs_taxei_25_pp\\\": 6.4}, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject25_eval.json\\\", \\\"completed_at\\\": \\\"2026-05-15T01:59:41.894Z\\\"}, \\\"v4-random-fixed-inject50\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T00:45:08.375Z\\\", \\\"updated_at\\\": \\\"2026-05-15T02:02:45.338Z\\\", \\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 50% injection (4,358 total = 2,179 clean + 2,179 injected). 与 TaxEI 50% 对比 taxonomy 标签在高注入比例下是否有差异。\\\", \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/random_fixed_inject50/v0-20260515-084528/checkpoint-1635\\\"}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-15T01:39:15.464Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-15T01:39:17.014804+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"data_count\\\": 4358, \\\"train_loss\\\": 0.4338, \\\"final_step_loss\\\": 0.2618, \\\"token_accuracy\\\": 0.91, \\\"train_duration_min\\\": 53.1, \\\"memory_gib\\\": 18, \\\"train_speed_s_per_it\\\": 1.95}, \\\"completed_at\\\": \\\"2026-05-15T01:43:35.237Z\\\"}, \\\"v4-random-fixed-inject25\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T00:25:44.436Z\\\", \\\"updated_at\\\": \\\"2026-05-15T01:48:07.606Z\\\", \\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 25% injection (4,358 total). 与 TaxEI 25% (48.9%) 对比 taxonomy 标签在中等注入比例下是否有差异。\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject25 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"gpu\\\": \\\"cuda:1\\\", \\\"max_steps\\\": 1635, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject25.log\\\"}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-15T01:43:59.432Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-15T01:44:03.491274+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"data_count\\\": 4358}, \\\"completed_at\\\": \\\"2026-05-15T01:48:05.171Z\\\"}, \\\"v4-random-fixed-inject10-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T01:28:17.994Z\\\", \\\"updated_at\\\": \\\"2026-05-15T01:42:40.302Z\\\", \\\"hypothesis\\\": \\\"v4 Random 10% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 10% (61.7%) 对比。\\\", \\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject10_eval.json --device cuda:2\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"110187\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T01:28:27.422Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-random-fixed-inject10\\\", \\\"checkpoint_source\\\": \\\"v4-random-fixed-inject10\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean, no injection)\\\", \\\"data_count\\\": 47, \\\"data_path\\\": \\\"eval/alfworld_47_clean\\\", \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random fixed inject10)\\\", \\\"seed\\\": 42, \\\"wall_clock_seconds\\\": 852.9, \\\"gpu_hours\\\": 0.24}, \\\"parent\\\": \\\"v4-random-fixed-inject10\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.681, \\\"eval_successes\\\": 32, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 6, \\\"rate\\\": 0.545}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 7, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 5, \\\"rate\\\": 0.714}}}, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_eval.json\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-15T01:42:40.303Z\\\"}, \\\"v4-taxei-fixed-inject50-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T01:28:14.823Z\\\", \\\"updated_at\\\": \\\"2026-05-15T01:38:54.383Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"python eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_taxei_fixed_inject50_eval.json --device cuda:0 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"ALFWorld valid_unseen\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (v4-taxei-fixed-inject50)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\\\", \\\"eval_data\\\": \\\"ALFWorld valid_unseen 47 tasks clean eval\\\"}, \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 50% injection eval — 47 tasks clean eval. Dose-response 最后一个数据点。已有：0%=61.7%, 10%=61.7%, 25%=48.9%, 50%=待测。\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.511, \\\"eval_successes\\\": 24, \\\"eval_total\\\": 47, \\\"vs_vanilla_seed42_pp\\\": -10.6}, \\\"checkpoint_path\\\": \\\"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\\\", \\\"log_path\\\": \\\"/tmp/eval_inject50.log\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"completed_at\\\": \\\"2026-05-15T01:37:38.792Z\\\"}, \\\"v4-random-fixed-inject10\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T00:25:41.996Z\\\", \\\"updated_at\\\": \\\"2026-05-15T01:31:01.715Z\\\", \\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 10% injection (4,358 total). 与 TaxEI 10% (61.7%) 对比 taxonomy 标签在低注入比例下是否有差异。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=2 && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject10 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"104655\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T00:28:19.537Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_path\\\": \\\"checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\\\", \\\"wall_clock_seconds\\\": 3546.1, \\\"gpu_hours\\\": 0.99}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-15T01:26:29.568Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-15T01:26:31.003606+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.4226, \\\"final_step_loss\\\": 0.3079, \\\"token_accuracy\\\": 0.9, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 57}, \\\"completed_at\\\": \\\"2026-05-15T01:27:25.646Z\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\\\"}, \\\"v4-taxei-fixed-inject50\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T00:25:38.284Z\\\", \\\"updated_at\\\": \\\"2026-05-15T01:25:47.611Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 50% injection ratio (4,358 total = 2,179 clean + 2,179 injected). Dose-response 最后一个点，完成后有完整曲线 0%→10%→25%→50%。\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --learning_rate 1e-4\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"104236\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T00:27:51.219Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_path\\\": \\\"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\\\", \\\"wall_clock_seconds\\\": 3476.4, \\\"gpu_hours\\\": 0.97}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-15T01:22:23.688Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-15T01:22:25.093365+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.259, \\\"token_accuracy\\\": 0.911, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 53.1}, \\\"completed_at\\\": \\\"2026-05-15T01:25:47.611Z\\\"}, \\\"v4-random-seed123-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T00:14:30.699Z\\\", \\\"updated_at\\\": \\\"2026-05-15T00:27:24.291Z\\\", \\\"hypothesis\\\": \\\"v4 Random SFT seed=123 eval — 47 tasks clean eval. Multi-seed: seed=42 66.0%, seed=0 55.3%, seed=123 待测。\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=1 && cd /root/autodl-tmp/tax_error_inject_agent && python eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed123_eval.json --device cuda:0\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 102888, \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T00:14:42.930Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 123, \\\"checkpoint_source\\\": \\\"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\\\", \\\"eval_data\\\": \\\"47 tasks clean eval (no injection)\\\", \\\"parent\\\": \\\"v4-random-seed123\\\", \\\"tmux_session\\\": \\\"v4-random-seed123-eval\\\", \\\"log_file\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\\\", \\\"wall_clock_seconds\\\": 740.0, \\\"gpu_hours\\\": 0.21}, \\\"conclusion\\\": \\\"negative\\\", \\\"checkpoint_path\\\": \\\"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\\\", \\\"completed_at\\\": \\\"2026-05-15T00:27:02.930Z\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.681, \\\"eval_successes\\\": 32, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 7, \\\"rate\\\": 0.636}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 6, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 5, \\\"rate\\\": 0.714}}}}, \\\"v4-taxei-fixed-inject25-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T23:50:53.016Z\\\", \\\"updated_at\\\": \\\"2026-05-15T00:14:40.327Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI 25% injection fixed-size eval — 48.9% (23/47), 显著低于 vanilla baseline 65.3%（-16.4pp）。Dose-response 数据点。\\\", \\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_eval.json --device cuda:0\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"checkpoint_source\\\": \\\"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean)\\\", \\\"parent\\\": \\\"v4-taxei-fixed-inject25-r2\\\", \\\"data_path\\\": \\\"eval/valid_unseen\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (taxei fixed inject25)\\\", \\\"seed\\\": 42}, \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.489, \\\"eval_successes\\\": 23, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 4, \\\"total\\\": 6, \\\"rate\\\": 0.667}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 3, \\\"total\\\": 8, \\\"rate\\\": 0.375}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 2, \\\"total\\\": 7, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 8, \\\"rate\\\": 0.625}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"checkpoint_path\\\": \\\"eval_results/v4_taxei_fixed_inject25_eval.json\\\", \\\"log_path\\\": \\\"/tmp/v4_taxei_fixed_inject25_eval.log\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-15T00:14:30.429Z\\\"}, \\\"v4-taxei-fixed-inject10-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T23:50:52.584Z\\\", \\\"updated_at\\\": \\\"2026-05-15T00:14:38.874Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI 10% injection fixed-size eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。Dose-response 数据点。\\\", \\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject10_eval.json --device cuda:0\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:2\\\", \\\"tmux_session\\\": \\\"eval_inject10\\\", \\\"checkpoint_source\\\": \\\"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean)\\\", \\\"parent\\\": \\\"v4-taxei-fixed-inject10\\\", \\\"data_path\\\": \\\"eval/valid_unseen\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (taxei fixed inject10)\\\", \\\"seed\\\": 42, \\\"log_path\\\": \\\"/tmp/v4_taxei_fixed_inject10_eval.log\\\"}, \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.617, \\\"eval_successes\\\": 29, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 5, \\\"total\\\": 8, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 6, \\\"total\\\": 8, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"checkpoint_path\\\": \\\"eval_results/v4_taxei_fixed_inject10_eval.json\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-15T00:14:29.992Z\\\"}, \\\"v4-taxei-seed123-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T23:44:07.489Z\\\", \\\"updated_at\\\": \\\"2026-05-15T00:14:37.513Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed123_eval.json --device cuda:0\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 100600, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (taxei v4 seed=123)\\\", \\\"seed\\\": 123, \\\"checkpoint_source\\\": \\\"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean, no injection)\\\", \\\"parent\\\": \\\"v4-taxei-seed123\\\", \\\"checkpoint_path\\\": \\\"eval_results/v4_taxei_seed123_eval.json\\\", \\\"log_path\\\": \\\"/tmp/v4_taxei_seed123_eval.log\\\", \\\"data_path\\\": \\\"eval/valid_unseen\\\", \\\"data_count\\\": 47}, \\\"hypothesis\\\": \\\"v4 TaxEI SFT seed=123 eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。multi-seed verification, 9029 samples。\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.617, \\\"eval_successes\\\": 29, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 4, \\\"total\\\": 8, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 7, \\\"total\\\": 11, \\\"rate\\\": 0.636}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 3, \\\"total\\\": 7, \\\"rate\\\": 0.429}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 6, \\\"total\\\": 8, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-15T00:14:29.055Z\\\"}, \\\"v4-random-seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T21:49:34.441Z\\\", \\\"updated_at\\\": \\\"2026-05-14T23:52:15.056Z\\\", \\\"hypothesis\\\": \\\"v4 Random SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 93477, \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed123.log\\\", \\\"submitted_at\\\": \\\"2026-05-14T21:59:16.545Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_random_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 123, \\\"wall_clock_seconds\\\": 6778.5, \\\"gpu_hours\\\": 1.88}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T23:50:09.168Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T23:50:10.389568+00:00\\\"}]}, \\\"metrics\\\": {\\\"train_loss\\\": 0.35484016, \\\"final_loss\\\": 0.16766574, \\\"token_accuracy\\\": 0.94187103, \\\"avg_token_accuracy\\\": 0.90849673, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_runtime_sec\\\": 6609.3556, \\\"train_duration_min\\\": 110.2, \\\"train_samples_per_second\\\": 4.098, \\\"train_steps_per_second\\\": 0.512, \\\"train_speed_s_per_it\\\": 1.951, \\\"memory_gib\\\": 18.49}, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-14T23:52:15.056Z\\\"}, \\\"v4-taxei-fixed-inject25-r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T22:32:41.837Z\\\", \\\"updated_at\\\": \\\"2026-05-14T23:50:46.230Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 25% injection ratio retry (4,358 total = 3,268 clean + 1,090 injected). 修复 CUDA_VISIBLE_DEVICES，显式设 =3。\\\", \\\"spec\\\": {\\\"command\\\": \\\"export CUDA_VISIBLE_DEVICES=3 && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --output_dir checkpoints/taxei_fixed_inject25 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 96835, \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"injection_ratio\\\": 0.25, \\\"clean_count\\\": 3268, \\\"injected_count\\\": 1090, \\\"log_path\\\": \\\"/tmp/v4-fixed-inject25.log\\\", \\\"note\\\": \\\"manual tmux with explicit CUDA_VISIBLE_DEVICES=3, fixing r1 OOM\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"checkpoint_path\\\": \\\"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.285, \\\"token_accuracy\\\": 0.893, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 58}, \\\"completed_at\\\": \\\"2026-05-14T23:50:46.230Z\\\"}, \\\"v4-taxei-fixed-inject10\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T22:09:52.707Z\\\", \\\"updated_at\\\": \\\"2026-05-14T23:50:45.829Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 10% injection ratio (4,358 total = 3,922 clean + 436 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --output_dir output/v4-fixed-inject10 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"94635\\\", \\\"log_path\\\": \\\"/tmp/v4-fixed-inject10.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T06:12:34Z\\\", \\\"submitted_via\\\": \\\"manual_tmux\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"injection_ratio\\\": 0.1, \\\"clean_count\\\": 3922, \\\"injected_count\\\": 436}, \\\"conclusion\\\": \\\"success\\\", \\\"checkpoint_path\\\": \\\"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.308, \\\"token_accuracy\\\": 0.888, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 58}, \\\"completed_at\\\": \\\"2026-05-14T23:50:45.829Z\\\"}, \\\"v4-taxei-fixed-inject25\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T22:09:53.209Z\\\", \\\"updated_at\\\": \\\"2026-05-14T23:45:26.890Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 25% injection ratio (4,358 total = 3,268 clean + 1,090 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject25.jsonl --output_dir output/v4-fixed-inject25 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"96835\\\", \\\"log_path\\\": \\\"/tmp/v4-fixed-inject25.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T06:31:44Z\\\", \\\"submitted_via\\\": \\\"manual_tmux\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"injection_ratio\\\": 0.25, \\\"clean_count\\\": 3268, \\\"injected_count\\\": 1090, \\\"note\\\": \\\"r1 (PID 95170) OOM on cuda:0 — submit_training_job failed to pass CUDA_VISIBLE_DEVICES. Resubmitted manually via tmux with explicit export CUDA_VISIBLE_DEVICES=3.\\\"}, \\\"conclusion\\\": \\\"failed\\\", \\\"failure_reason\\\": \\\"CUDA_VISIBLE_DEVICES 未生效，模型加载到 cuda:0 导致 OOM（与 seed123 训练冲突）\\\", \\\"completed_at\\\": \\\"2026-05-14T23:45:26.890Z\\\"}, \\\"v4-taxei-seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T21:49:34.191Z\\\", \\\"updated_at\\\": \\\"2026-05-14T23:43:38.819Z\\\", \\\"hypothesis\\\": \\\"v4 TaxEI SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 92263, \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-seed123.log\\\", \\\"submitted_at\\\": \\\"2026-05-14T21:50:17.845Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 123, \\\"wall_clock_seconds\\\": 6801.0, \\\"gpu_hours\\\": 1.89}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T23:41:32.774Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T23:41:33.984355+00:00\\\"}]}, \\\"metrics\\\": {\\\"final_loss\\\": 0.35506879, \\\"token_accuracy\\\": 0.89978214, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 109.2, \\\"train_runtime_sec\\\": 6549.432, \\\"train_speed_s_per_it\\\": 1.934, \\\"memory_gib\\\": 18.49}, \\\"checkpoint_path\\\": \\\"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-14T23:43:38.819Z\\\"}, \\\"v4-fixed-inject25\\\": {\\\"status\\\": \\\"PREPARING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T22:09:23.317Z\\\", \\\"updated_at\\\": \\\"2026-05-14T22:29:19.308Z\\\", \\\"spec\\\": {\\\"hypothesis\\\": \\\"Fixed-size ablation: 25% injection ratio (4,358 total samples, ~1,090 injected + ~3,269 clean). Tests intermediate injection ratio. Combined with 10%/50% results, reveals dose-response curve. Addresses Reviewer Concern #5.\\\", \\\"parent\\\": \\\"v4-taxei-eval\\\", \\\"plan_id\\\": \\\"fixed-size-ablation\\\", \\\"reviewer_concern\\\": \\\"RC5\\\"}, \\\"conclusion\\\": \\\"killed\\\", \\\"failure_reason\\\": \\\"duplicate entry — active experiment is v4-taxei-fixed-inject25 (RUNNING)\\\"}, \\\"v4-fixed-inject10\\\": {\\\"status\\\": \\\"PREPARING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T22:09:21.673Z\\\", \\\"updated_at\\\": \\\"2026-05-14T22:29:18.354Z\\\", \\\"spec\\\": {\\\"hypothesis\\\": \\\"Fixed-size ablation: 10% injection ratio (4,358 total samples, ~436 injected + ~3,922 clean). Tests whether low injection ratio still harms clean performance. If yes → injection itself is harmful regardless of ratio. Addresses Reviewer Concern #5.\\\", \\\"parent\\\": \\\"v4-taxei-eval\\\", \\\"plan_id\\\": \\\"fixed-size-ablation\\\", \\\"reviewer_concern\\\": \\\"RC5\\\"}, \\\"conclusion\\\": \\\"killed\\\", \\\"failure_reason\\\": \\\"duplicate entry — active experiment is v4-taxei-fixed-inject10 (RUNNING)\\\"}, \\\"v4-random-recovery-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T21:04:57.591Z\\\", \\\"updated_at\\\": \\\"2026-05-14T22:00:43.285Z\\\", \\\"hypothesis\\\": \\\"v4 Random SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla/taxei recovery eval.\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_recovery_eval.json\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 90124, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random SFT v4)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387\\\", \\\"eval_data\\\": \\\"valid_unseen (47 episodes)\\\", \\\"log_path\\\": \\\"/tmp/v4_random_recovery_eval.log\\\", \\\"output_path\\\": \\\"eval_results/v4_random_recovery_eval.json\\\", \\\"data_path\\\": \\\"valid_unseen\\\", \\\"data_count\\\": 47}, \\\"conclusion\\\": \\\"success\\\", \\\"checkpoint_path\\\": \\\"eval_results/v4_random_recovery_eval.json\\\", \\\"completed_at\\\": \\\"2026-05-14T21:42:07.544Z\\\", \\\"metrics\\\": {\\\"recovery_rate\\\": 0.638, \\\"detection_rate\\\": 0, \\\"successes\\\": 30, \\\"total\\\": 47, \\\"source\\\": \\\"json-file-verified\\\", \\\"note\\\": \\\"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\\\"}}}, \\\"count\\\": 20, \\\"total\\\": 61, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.1479}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:43:46.913Z\", \"updated_at\": \"2026-05-15T02:03:49.013Z\", \"hypothesis\": \"v4 Random 50% injection fixed-size eval — 47 tasks clean eval. 与 TaxEI 50% (51.1%) 对比。Random dose-response 最后一点。\", \"spec\": {\"gpu\": [\"cuda:3\"]}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:56:26.837Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:56:28.410747+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.574, \"eval_successes\": 27, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -4.3, \"vs_taxei_50_pp\": 6.3}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject50_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-eval.log\", \"completed_at\": \"2026-05-15T02:00:22.858Z\"}, \"v4-random-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:48:25.777Z\", \"updated_at\": \"2026-05-15T02:03:46.203Z\", \"hypothesis\": \"v4 Random 25% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 25% (48.9%) 对比。\", \"parent\": \"v4-random-fixed-inject25\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"parent\": \"v4-random-fixed-inject25\", \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_path\": \"eval/alfworld_47_clean\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject25)\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"pid\": \"112516\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -6.4, \"vs_taxei_25_pp\": 6.4}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject25_eval.json\", \"completed_at\": \"2026-05-15T01:59:41.894Z\"}, \"v4-random-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:45:08.375Z\", \"updated_at\": \"2026-05-15T02:02:45.338Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection (4,358 total = 2,179 clean + 2,179 injected). 与 TaxEI 50% 对比 taxonomy 标签在高注入比例下是否有差异。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/random_fixed_inject50/v0-20260515-084528/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:39:15.464Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:39:17.014804+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358, \"train_loss\": 0.4338, \"final_step_loss\": 0.2618, \"token_accuracy\": 0.91, \"train_duration_min\": 53.1, \"memory_gib\": 18, \"train_speed_s_per_it\": 1.95}, \"completed_at\": \"2026-05-15T01:43:35.237Z\"}, \"v4-random-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:44.436Z\", \"updated_at\": \"2026-05-15T01:48:07.606Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection (4,358 total). 与 TaxEI 25% (48.9%) 对比 taxonomy 标签在中等注入比例下是否有差异。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject25 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:1\", \"max_steps\": 1635, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:43:59.432Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:44:03.491274+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}, \"completed_at\": \"2026-05-15T01:48:05.171Z\"}, \"v4-random-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:17.994Z\", \"updated_at\": \"2026-05-15T01:42:40.302Z\", \"hypothesis\": \"v4 Random 10% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 10% (61.7%) 对比。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject10_eval.json --device cuda:2\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"110187\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"submitted_at\": \"2026-05-15T01:28:27.422Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10\", \"checkpoint_source\": \"v4-random-fixed-inject10\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_count\": 47, \"data_path\": \"eval/alfworld_47_clean\", \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10)\", \"seed\": 42, \"wall_clock_seconds\": 852.9, \"gpu_hours\": 0.24}, \"parent\": \"v4-random-fixed-inject10\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:42:40.303Z\"}, \"v4-taxei-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:14.823Z\", \"updated_at\": \"2026-05-15T01:38:54.383Z\", \"spec\": {\"command\": \"python eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_taxei_fixed_inject50_eval.json --device cuda:0 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (v4-taxei-fixed-inject50)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"eval_data\": \"ALFWorld valid_unseen 47 tasks clean eval\"}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection eval — 47 tasks clean eval. Dose-response 最后一个数据点。已有：0%=61.7%, 10%=61.7%, 25%=48.9%, 50%=待测。\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -10.6}, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"log_path\": \"/tmp/eval_inject50.log\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T01:37:38.792Z\"}, \"v4-random-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:41.996Z\", \"updated_at\": \"2026-05-15T01:31:01.715Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection (4,358 total). 与 TaxEI 10% (61.7%) 对比 taxonomy 标签在低注入比例下是否有差异。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=2 && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject10 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"104655\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T00:28:19.537Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"wall_clock_seconds\": 3546.1, \"gpu_hours\": 0.99}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:26:29.568Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:26:31.003606+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4226, \"final_step_loss\": 0.3079, \"token_accuracy\": 0.9, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 57}, \"completed_at\": \"2026-05-15T01:27:25.646Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\"}, \"v4-taxei-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:38.284Z\", \"updated_at\": \"2026-05-15T01:25:47.611Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio (4,358 total = 2,179 clean + 2,179 injected). Dose-response 最后一个点，完成后有完整曲线 0%→10%→25%→50%。\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --learning_rate 1e-4\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"104236\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50.log\", \"submitted_at\": \"2026-05-15T00:27:51.219Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"wall_clock_seconds\": 3476.4, \"gpu_hours\": 0.97}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:22:23.688Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:22:25.093365+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.259, \"token_accuracy\": 0.911, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 53.1}, \"completed_at\": \"2026-05-15T01:25:47.611Z\"}, \"v4-random-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:14:30.699Z\", \"updated_at\": \"2026-05-15T00:27:24.291Z\", \"hypothesis\": \"v4 Random SFT seed=123 eval — 47 tasks clean eval. Multi-seed: seed=42 66.0%, seed=0 55.3%, seed=123 待测。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=1 && cd /root/autodl-tmp/tax_error_inject_agent && python eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 102888, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"submitted_at\": \"2026-05-15T00:14:42.930Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"eval_data\": \"47 tasks clean eval (no injection)\", \"parent\": \"v4-random-seed123\", \"tmux_session\": \"v4-random-seed123-eval\", \"log_file\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"wall_clock_seconds\": 740.0, \"gpu_hours\": 0.21}, \"conclusion\": \"negative\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"completed_at\": \"2026-05-15T00:27:02.930Z\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-taxei-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:53.016Z\", \"updated_at\": \"2026-05-15T00:14:40.327Z\", \"hypothesis\": \"v4 TaxEI 25% injection fixed-size eval — 48.9% (23/47), 显著低于 vanilla baseline 65.3%（-16.4pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"checkpoint_source\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject25-r2\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject25)\", \"seed\": 42}, \"metrics\": {\"eval_success_rate\": 0.489, \"eval_successes\": 23, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 4, \"total\": 6, \"rate\": 0.667}, \"pick_and_place_simple\": {\"success\": 3, \"total\": 8, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject25_eval.json\", \"log_path\": \"/tmp/v4_taxei_fixed_inject25_eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:30.429Z\"}, \"v4-taxei-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:52.584Z\", \"updated_at\": \"2026-05-15T00:14:38.874Z\", \"hypothesis\": \"v4 TaxEI 10% injection fixed-size eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject10_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"tmux_session\": \"eval_inject10\", \"checkpoint_source\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject10\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10)\", \"seed\": 42, \"log_path\": \"/tmp/v4_taxei_fixed_inject10_eval.log\"}, \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject10_eval.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.992Z\"}, \"v4-taxei-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:07.489Z\", \"updated_at\": \"2026-05-15T00:14:37.513Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed123_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 100600, \"model_name\": \"Qwen3-8B + LoRA (taxei v4 seed=123)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed123\", \"checkpoint_path\": \"eval_results/v4_taxei_seed123_eval.json\", \"log_path\": \"/tmp/v4_taxei_seed123_eval.log\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47}, \"hypothesis\": \"v4 TaxEI SFT seed=123 eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。multi-seed verification, 9029 samples。\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.055Z\"}, \"v4-random-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.441Z\", \"updated_at\": \"2026-05-14T23:52:15.056Z\", \"hypothesis\": \"v4 Random SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 93477, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123.log\", \"submitted_at\": \"2026-05-14T21:59:16.545Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6778.5, \"gpu_hours\": 1.88}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:50:09.168Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:50:10.389568+00:00\"}]}, \"metrics\": {\"train_loss\": 0.35484016, \"final_loss\": 0.16766574, \"token_accuracy\": 0.94187103, \"avg_token_accuracy\": 0.90849673, \"train_steps\": 3387, \"train_epochs\": 3, \"train_runtime_sec\": 6609.3556, \"train_duration_min\": 110.2, \"train_samples_per_second\": 4.098, \"train_steps_per_second\": 0.512, \"train_speed_s_per_it\": 1.951, \"memory_gib\": 18.49}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:52:15.056Z\"}, \"v4-taxei-fixed-inject25-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:32:41.837Z\", \"updated_at\": \"2026-05-14T23:50:46.230Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio retry (4,358 total = 3,268 clean + 1,090 injected). 修复 CUDA_VISIBLE_DEVICES，显式设 =3。\", \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=3 && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --output_dir checkpoints/taxei_fixed_inject25 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 96835, \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"note\": \"manual tmux with explicit CUDA_VISIBLE_DEVICES=3, fixing r1 OOM\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.285, \"token_accuracy\": 0.893, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:46.230Z\"}, \"v4-taxei-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:52.707Z\", \"updated_at\": \"2026-05-14T23:50:45.829Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio (4,358 total = 3,922 clean + 436 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --output_dir output/v4-fixed-inject10 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"94635\", \"log_path\": \"/tmp/v4-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T06:12:34Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.308, \"token_accuracy\": 0.888, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:45.829Z\"}, \"v4-taxei-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:53.209Z\", \"updated_at\": \"2026-05-14T23:45:26.890Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio (4,358 total = 3,268 clean + 1,090 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject25.jsonl --output_dir output/v4-fixed-inject25 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"96835\", \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"submitted_at\": \"2026-05-15T06:31:44Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"note\": \"r1 (PID 95170) OOM on cuda:0 — submit_training_job failed to pass CUDA_VISIBLE_DEVICES. Resubmitted manually via tmux with explicit export CUDA_VISIBLE_DEVICES=3.\"}, \"conclusion\": \"failed\", \"failure_reason\": \"CUDA_VISIBLE_DEVICES 未生效，模型加载到 cuda:0 导致 OOM（与 seed123 训练冲突）\", \"completed_at\": \"2026-05-14T23:45:26.890Z\"}, \"v4-taxei-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.191Z\", \"updated_at\": \"2026-05-14T23:43:38.819Z\", \"hypothesis\": \"v4 TaxEI SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 92263, \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed123.log\", \"submitted_at\": \"2026-05-14T21:50:17.845Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6801.0, \"gpu_hours\": 1.89}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:41:32.774Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:41:33.984355+00:00\"}]}, \"metrics\": {\"final_loss\": 0.35506879, \"token_accuracy\": 0.89978214, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 109.2, \"train_runtime_sec\": 6549.432, \"train_speed_s_per_it\": 1.934, \"memory_gib\": 18.49}, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:43:38.819Z\"}, \"v4-fixed-inject25\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:23.317Z\", \"updated_at\": \"2026-05-14T22:29:19.308Z\", \"spec\": {\"hypothesis\": \"Fixed-size ablation: 25% injection ratio (4,358 total samples, ~1,090 injected + ~3,269 clean). Tests intermediate injection ratio. Combined with 10%/50% results, reveals dose-response curve. Addresses Reviewer Concern #5.\", \"parent\": \"v4-taxei-eval\", \"plan_id\": \"fixed-size-ablation\", \"reviewer_concern\": \"RC5\"}, \"conclusion\": \"killed\", \"failure_reason\": \"duplicate entry — active experiment is v4-taxei-fixed-inject25 (RUNNING)\"}, \"v4-fixed-inject10\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:21.673Z\", \"updated_at\": \"2026-05-14T22:29:18.354Z\", \"spec\": {\"hypothesis\": \"Fixed-size ablation: 10% injection ratio (4,358 total samples, ~436 injected + ~3,922 clean). Tests whether low injection ratio still harms clean performance. If yes → injection itself is harmful regardless of ratio. Addresses Reviewer Concern #5.\", \"parent\": \"v4-taxei-eval\", \"plan_id\": \"fixed-size-ablation\", \"reviewer_concern\": \"RC5\"}, \"conclusion\": \"killed\", \"failure_reason\": \"duplicate entry — active experiment is v4-taxei-fixed-inject10 (RUNNING)\"}, \"v4-random-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:04:57.591Z\", \"updated_at\": \"2026-05-14T22:00:43.285Z\", \"hypothesis\": \"v4 Random SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla/taxei recovery eval.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_recovery_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 90124, \"model_name\": \"Qwen3-8B + LoRA (random SFT v4)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387\", \"eval_data\": \"valid_unseen (47 episodes)\", \"log_path\": \"/tmp/v4_random_recovery_eval.log\", \"output_path\": \"eval_results/v4_random_recovery_eval.json\", \"data_path\": \"valid_unseen\", \"data_count\": 47}, \"conclusion\": \"success\", \"checkpoint_path\": \"eval_results/v4_random_recovery_eval.json\", \"completed_at\": \"2026-05-14T21:42:07.544Z\", \"metrics\": {\"recovery_rate\": 0.638, \"detection_rate\": 0, \"successes\": 30, \"total\": 47, \"source\": \"json-file-verified\", \"note\": \"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\"}}}, \"count\": 20, \"total\": 61, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.1479}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 19_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01WnBSEraVAEHAHPgxMBgPBh`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/tax_error_inject_agent/eval_results/ -type f -name \"*vanilla*\"",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "15ff9574-3fce-4688-ac5b-2baafe50097f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UMFdjCvsRU7VJegwyWWpVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 25144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01J4L5Po4yzdW7XJJ2iMVgv8`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/tax_error_inject_agent/eval_results/ -type f -name \"*recovery*\"",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "e1730e28-fa9b-4ebc-9568-818d305d82f0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UMFdjCvsRU7VJegwyWWpVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 25144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 21 · 2026-05-15T03:28:56.038Z_

<details><summary>↩ Tool result · `toolu_01WnBSEraVAEHAHPgxMBgPBh`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/vanilla_react_baseline.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/mini_vanilla_clean.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v3_vanilla.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/dryrun_injected_vanilla.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_seed0_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_seed123_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.91}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "a664ff8a-ae66-4742-b7d2-34750d128fd5",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/eval_results/vanilla_react_baseline.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/mini_vanilla_clean.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v3_vanilla.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_eval.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/dryrun_injected_vanilla.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_seed0_eval.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_seed123_eval.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.91}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/vanilla_react_baseline.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/mini_vanilla_clean.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v3_vanilla.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/dryrun_injected_vanilla.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_seed0_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_seed123_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.91}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-15T03:28:56.412Z_

<details><summary>↩ Tool result · `toolu_01J4L5Po4yzdW7XJJ2iMVgv8`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/gate2_recovery_quality.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/dryrun_recovery.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_recovery_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval_r2.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "e16527c4-85b1-4dee-a753-1d01313ea808",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/eval_results/gate2_recovery_quality.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/dryrun_recovery.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_recovery_eval.json\\\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval_r2.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.37}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/gate2_recovery_quality.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/dryrun_recovery.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_recovery_eval.json\\n/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval_r2.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01ChSK4FBdGc6aS8JqunMmxW`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls /root/autodl-tmp/tax_error_inject_agent/eval_results/",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "16c947c6-2875-4908-9099-f2dceb088865",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UMFdjCvsRU7VJegwyWWpVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 25144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 24 · 2026-05-15T03:28:57.297Z_

<details><summary>↩ Tool result · `toolu_01ChSK4FBdGc6aS8JqunMmxW`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"adapter_test.json\\ndryrun_injected_vanilla.json\\ndryrun_recovery.json\\ngate1_injection_validity.json\\ngate2_recovery_quality.json\\ngate3_judgment.json\\nmini_taxei_clean.json\\nmini_vanilla_clean.json\\npipeline_test.json\\nv3_random.json\\nv3_taxei.json\\nv3_vanilla.json\\nv4_random_eval.json\\nv4_random_fixed_inject10_eval.json\\nv4_random_fixed_inject25_eval.json\\nv4_random_fixed_inject50_eval.json\\nv4_random_recovery_eval.json\\nv4_random_seed0_eval.json\\nv4_random_seed123_eval.json\\nv4_taxei_eval.json\\nv4_taxei_fixed_inject10_eval.json\\nv4_taxei_fixed_inject25_eval.json\\nv4_taxei_fixed_inject50_eval.json\\nv4_taxei_recovery_eval.json\\nv4_taxei_recovery_eval_r2.json\\nv4_taxei_seed0_eval.json\\nv4_taxei_seed123_eval.json\\nv4_vanilla_eval.json\\nv4_vanilla_recovery_eval.json\\nv4_vanilla_seed0_eval.json\\nv4_vanilla_seed123_eval.json\\nvanilla_react_baseline.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "97a93023-46b3-44f2-a5c6-a8dd04e67317",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"adapter_test.json\\\\ndryrun_injected_vanilla.json\\\\ndryrun_recovery.json\\\\ngate1_injection_validity.json\\\\ngate2_recovery_quality.json\\\\ngate3_judgment.json\\\\nmini_taxei_clean.json\\\\nmini_vanilla_clean.json\\\\npipeline_test.json\\\\nv3_random.json\\\\nv3_taxei.json\\\\nv3_vanilla.json\\\\nv4_random_eval.json\\\\nv4_random_fixed_inject10_eval.json\\\\nv4_random_fixed_inject25_eval.json\\\\nv4_random_fixed_inject50_eval.json\\\\nv4_random_recovery_eval.json\\\\nv4_random_seed0_eval.json\\\\nv4_random_seed123_eval.json\\\\nv4_taxei_eval.json\\\\nv4_taxei_fixed_inject10_eval.json\\\\nv4_taxei_fixed_inject25_eval.json\\\\nv4_taxei_fixed_inject50_eval.json\\\\nv4_taxei_recovery_eval.json\\\\nv4_taxei_recovery_eval_r2.json\\\\nv4_taxei_seed0_eval.json\\\\nv4_taxei_seed123_eval.json\\\\nv4_vanilla_eval.json\\\\nv4_vanilla_recovery_eval.json\\\\nv4_vanilla_seed0_eval.json\\\\nv4_vanilla_seed123_eval.json\\\\nvanilla_react_baseline.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"adapter_test.json\\ndryrun_injected_vanilla.json\\ndryrun_recovery.json\\ngate1_injection_validity.json\\ngate2_recovery_quality.json\\ngate3_judgment.json\\nmini_taxei_clean.json\\nmini_vanilla_clean.json\\npipeline_test.json\\nv3_random.json\\nv3_taxei.json\\nv3_vanilla.json\\nv4_random_eval.json\\nv4_random_fixed_inject10_eval.json\\nv4_random_fixed_inject25_eval.json\\nv4_random_fixed_inject50_eval.json\\nv4_random_recovery_eval.json\\nv4_random_seed0_eval.json\\nv4_random_seed123_eval.json\\nv4_taxei_eval.json\\nv4_taxei_fixed_inject10_eval.json\\nv4_taxei_fixed_inject25_eval.json\\nv4_taxei_fixed_inject50_eval.json\\nv4_taxei_recovery_eval.json\\nv4_taxei_recovery_eval_r2.json\\nv4_taxei_seed0_eval.json\\nv4_taxei_seed123_eval.json\\nv4_vanilla_eval.json\\nv4_vanilla_recovery_eval.json\\nv4_vanilla_seed0_eval.json\\nv4_vanilla_seed123_eval.json\\nvanilla_react_baseline.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 25_

<details><summary>Logged reasoning block</summary>

```text
Found the file: `/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json`. Let me also read the TaxEI recovery eval for comparison. Let me read both files, and also the TaxEI recovery eval files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "fd4e89bc-cd85-4980-b0da-d27ccba1e71e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019jiJaYh3fyRQCNGxAN91md",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14804,
      "cache_read_input_tokens": 25919,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14804
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

_source line 26_

Found `v4_vanilla_recovery_eval.json`. Let me read it and the TaxEI recovery eval for comparison.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "c9c2e315-7f05-4b82-8de8-74ea7436ace1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019jiJaYh3fyRQCNGxAN91md",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14804,
      "cache_read_input_tokens": 25919,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14804
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_013cLzwSZuBrFtt4iMurFVts`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval.json",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "8995f519-8ed6-42ad-94c9-0440699d87d0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019jiJaYh3fyRQCNGxAN91md",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14804,
      "cache_read_input_tokens": 25919,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14804
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

_source line 28 · 2026-05-15T03:29:02.779Z_

<details><summary>↩ Tool result · `toolu_013cLzwSZuBrFtt4iMurFVts`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\\\",\\n  \\\"model_variant\\\": \\\"vanilla\\\",\\n  \\\"inject\\\": true,\\n  \\\"seed\\\": 42,\\n  \\\"total_episodes\\\": 47,\\n  \\\"success_rate\\\": 0.617,\\n  \\\"recovery_rate\\\": 0.617,\\n  \\\"detection_rate\\\": 0.0,\\n  \\\"timestamp\\\": \\\"2026-05-14T19:45:46.465973+00:00\\\",\\n  \\\"by_operator\\\": {\\n    \\\"C1_context_truncation\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 9,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.75,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"C4_observation_masking\\\": {\\n      \\\"total\\\": 11,\\n      \\\"recovered\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.545,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P1_step_order_swap\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.583,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P2_sub_goal_deletion\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.583,\\n      \\\"detection_rate\\\": 0.0\\n    }\\n  },\\n  \\\"by_task_type\\\": {\\n    \\\"look_at_obj_in_light\\\": {\\n      \\\"total\\\": 6,\\n      \\\"success\\\": 5,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.833\\n    },\\n    \\\"pick_and_place_simple\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 5,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.625\\n    },\\n    \\\"pick_clean_then_place_in_recep\\\": {\\n      \\\"total\\\": 11,\\n      \\\"success\\\": 5,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.455\\n    },\\n    \\\"pick_cool_then_place_in_recep\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 4,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.571\\n    },\\n    \\\"pick_heat_then_place_in_recep\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.75\\n    },\\n    \\\"pick_two_obj_and_place\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 4,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.571\\n    }\\n  },\\n  \\\"episodes\\\": [\\n    {\\n      \\\"task_name\\\": \\\"look_at_obj_in_light-AlarmClock-None-DeskLamp-308\\\",\\n      \\\"task_type\\\": \\\"look_at_obj_in_light\\\",\\n      \\\"task_desc\\\": \\\"Hold the clock and turn on the lamp.\\\",\\n      \\\"success\\\": true,\\n      \\\"steps\\\": 12,\\n      \\\"operator\\\": \\\"P1_step_order_swap\\\",\\n      \\\"injection_step\\\": 2,\\n      \\\"injected\\\": true,\\n      \\\"recovery_analysis\\\": {\\n        \\\"detected\\\": false,\\n        \\\"detection_step\\\": null,\\n        \\\"recovery_actions_count\\\": 1,\\n        \\\"steps_after_injection\\\": 10\\n      },\\n      \\\"trajectory\\\": [\\n        {\\n          \\\"step\\\": 0,\\n          \\\"observation\\\": \\\"-= Welcome to TextWorld, ALFRED! =-\\\\n\\\\nYou are in the middle of a room. Looking quickly around you, you see a bed 1, a desk 2, a desk 1, a drawer 6, a drawer 5, a drawer 4, a drawer 3, a drawer 2, a dra\\\",\\n          \\\"action\\\": \\\"go to desk 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 1,\\n          \\\"observation\\\": \\\"You arrive at desk 1. On the desk 1, you see a bowl 1, a desklamp 1, a mug 1, and a pencil 1.\\\",\\n          \\\"action\\\": \\\"use desklamp 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 2,\\n          \\\"observation\\\": \\\"You turn on the desklamp 1.\\\",\\n          \\\"action\\\": \\\"go to shelf 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": true,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 3,\\n          \\\"observation\\\": \\\"You arrive at shelf 1. On the shelf 1, you see a keychain 3, and a pen 3.\\\",\\n          \\\"action\\\": \\\"go to shelf 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 4,\\n          \\\"observation\\\": \\\"You arrive at shelf 2. On the shelf 2, you see nothing.\\\",\\n          \\\"action\\\": \\\"go to shelf 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": fa\\n\\n... [截断: 输出过长，省略 468263 字符] ...\\n\\n       \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 39,\\n          \\\"observation\\\": \\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"take toiletpaper 1 from cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 40,\\n          \\\"observation\\\": \\\"You pick up the toiletpaper 1 from the cabinet 2.\\\",\\n          \\\"action\\\": \\\"move toiletpaper 1 to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 41,\\n          \\\"observation\\\": \\\"You move the toiletpaper 1 to the cabinet 2.\\\",\\n          \\\"action\\\": \\\"close cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 42,\\n          \\\"observation\\\": \\\"You close the cabinet 2.\\\",\\n          \\\"action\\\": \\\"look\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": true\\n        },\\n        {\\n          \\\"step\\\": 43,\\n          \\\"observation\\\": \\\"You are facing the cabinet 2. Next to it, you see nothing.\\\",\\n          \\\"action\\\": \\\"open cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 44,\\n          \\\"observation\\\": \\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"close cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 45,\\n          \\\"observation\\\": \\\"You close the cabinet 2.\\\",\\n          \\\"action\\\": \\\"examine cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": true\\n        },\\n        {\\n          \\\"step\\\": 46,\\n          \\\"observation\\\": \\\"The cabinet 2 is closed.\\\",\\n          \\\"action\\\": \\\"open cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 47,\\n          \\\"observation\\\": \\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"take toiletpaper 1 from cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 48,\\n          \\\"observation\\\": \\\"You pick up the toiletpaper 1 from the cabinet 2.\\\",\\n          \\\"action\\\": \\\"move toiletpaper 1 to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 49,\\n          \\\"observation\\\": \\\"You move the toiletpaper 1 to the cabinet 2.\\\",\\n          \\\"action\\\": \\\"close cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        }\\n      ]\\n    }\\n  ]\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.62}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "d83ad587-5211-4763-8838-71f692ddfcb3",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"model\\\\\\\": \\\\\\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\\\\\\\",\\\\n  \\\\\\\"model_variant\\\\\\\": \\\\\\\"vanilla\\\\\\\",\\\\n  \\\\\\\"inject\\\\\\\": true,\\\\n  \\\\\\\"seed\\\\\\\": 42,\\\\n  \\\\\\\"total_episodes\\\\\\\": 47,\\\\n  \\\\\\\"success_rate\\\\\\\": 0.617,\\\\n  \\\\\\\"recovery_rate\\\\\\\": 0.617,\\\\n  \\\\\\\"detection_rate\\\\\\\": 0.0,\\\\n  \\\\\\\"timestamp\\\\\\\": \\\\\\\"2026-05-14T19:45:46.465973+00:00\\\\\\\",\\\\n  \\\\\\\"by_operator\\\\\\\": {\\\\n    \\\\\\\"C1_context_truncation\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 12,\\\\n      \\\\\\\"recovered\\\\\\\": 9,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.75,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"C4_observation_masking\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 11,\\\\n      \\\\\\\"recovered\\\\\\\": 6,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.545,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"P1_step_order_swap\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 12,\\\\n      \\\\\\\"recovered\\\\\\\": 7,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.583,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"P2_sub_goal_deletion\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 12,\\\\n      \\\\\\\"recovered\\\\\\\": 7,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.583,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    }\\\\n  },\\\\n  \\\\\\\"by_task_type\\\\\\\": {\\\\n    \\\\\\\"look_at_obj_in_light\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 6,\\\\n      \\\\\\\"success\\\\\\\": 5,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.833\\\\n    },\\\\n    \\\\\\\"pick_and_place_simple\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 8,\\\\n      \\\\\\\"success\\\\\\\": 5,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.625\\\\n    },\\\\n    \\\\\\\"pick_clean_then_place_in_recep\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 11,\\\\n      \\\\\\\"success\\\\\\\": 5,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.455\\\\n    },\\\\n    \\\\\\\"pick_cool_then_place_in_recep\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 7,\\\\n      \\\\\\\"success\\\\\\\": 4,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.571\\\\n    },\\\\n    \\\\\\\"pick_heat_then_place_in_recep\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 8,\\\\n      \\\\\\\"success\\\\\\\": 6,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.75\\\\n    },\\\\n    \\\\\\\"pick_two_obj_and_place\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 7,\\\\n      \\\\\\\"success\\\\\\\": 4,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.571\\\\n    }\\\\n  },\\\\n  \\\\\\\"episodes\\\\\\\": [\\\\n    {\\\\n      \\\\\\\"task_name\\\\\\\": \\\\\\\"look_at_obj_in_light-AlarmClock-None-DeskLamp-308\\\\\\\",\\\\n      \\\\\\\"task_type\\\\\\\": \\\\\\\"look_at_obj_in_light\\\\\\\",\\\\n      \\\\\\\"task_desc\\\\\\\": \\\\\\\"Hold the clock and turn on the lamp.\\\\\\\",\\\\n      \\\\\\\"success\\\\\\\": true,\\\\n      \\\\\\\"steps\\\\\\\": 12,\\\\n      \\\\\\\"operator\\\\\\\": \\\\\\\"P1_step_order_swap\\\\\\\",\\\\n      \\\\\\\"injection_step\\\\\\\": 2,\\\\n      \\\\\\\"injected\\\\\\\": true,\\\\n      \\\\\\\"recovery_analysis\\\\\\\": {\\\\n        \\\\\\\"detected\\\\\\\": false,\\\\n        \\\\\\\"detection_step\\\\\\\": null,\\\\n        \\\\\\\"recovery_actions_count\\\\\\\": 1,\\\\n        \\\\\\\"steps_after_injection\\\\\\\": 10\\\\n      },\\\\n      \\\\\\\"trajectory\\\\\\\": [\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 0,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"-= Welcome to TextWorld, ALFRED! =-\\\\\\\\n\\\\\\\\nYou are in the middle of a room. Looking quickly around you, you see a bed 1, a desk 2, a desk 1, a drawer 6, a drawer 5, a drawer 4, a drawer 3, a drawer 2, a dra\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to desk 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": false,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 1,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at desk 1. On the desk 1, you see a bowl 1, a desklamp 1, a mug 1, and a pencil 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"use desklamp 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": false,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 2,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You turn on the desklamp 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to shelf 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": true,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 3,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at shelf 1. On the shelf 1, you see a keychain 3, and a pen 3.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to shelf 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 4,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at shelf 2. On the shelf 2, you see nothing.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to shelf 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": fa\\\\n\\\\n... [截断: 输出过长，省略 468263 字符] ...\\\\n\\\\n       \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 39,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"take toiletpaper 1 from cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 40,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You pick up the toiletpaper 1 from the cabinet 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"move toiletpaper 1 to cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 41,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You move the toiletpaper 1 to the cabinet 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"close cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 42,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You close the cabinet 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"look\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": true\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 43,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You are facing the cabinet 2. Next to it, you see nothing.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"open cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 44,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"close cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 45,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You close the cabinet 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"examine cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": true\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 46,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"The cabinet 2 is closed.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"open cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 47,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"take toiletpaper 1 from cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 48,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You pick up the toiletpaper 1 from the cabinet 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"move toiletpaper 1 to cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 49,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You move the toiletpaper 1 to the cabinet 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"close cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        }\\\\n      ]\\\\n    }\\\\n  ]\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.62}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\\\",\\n  \\\"model_variant\\\": \\\"vanilla\\\",\\n  \\\"inject\\\": true,\\n  \\\"seed\\\": 42,\\n  \\\"total_episodes\\\": 47,\\n  \\\"success_rate\\\": 0.617,\\n  \\\"recovery_rate\\\": 0.617,\\n  \\\"detection_rate\\\": 0.0,\\n  \\\"timestamp\\\": \\\"2026-05-14T19:45:46.465973+00:00\\\",\\n  \\\"by_operator\\\": {\\n    \\\"C1_context_truncation\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 9,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.75,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"C4_observation_masking\\\": {\\n      \\\"total\\\": 11,\\n      \\\"recovered\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.545,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P1_step_order_swap\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.583,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P2_sub_goal_deletion\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.583,\\n      \\\"detection_rate\\\": 0.0\\n    }\\n  },\\n  \\\"by_task_type\\\": {\\n    \\\"look_at_obj_in_light\\\": {\\n      \\\"total\\\": 6,\\n      \\\"success\\\": 5,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.833\\n    },\\n    \\\"pick_and_place_simple\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 5,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.625\\n    },\\n    \\\"pick_clean_then_place_in_recep\\\": {\\n      \\\"total\\\": 11,\\n      \\\"success\\\": 5,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.455\\n    },\\n    \\\"pick_cool_then_place_in_recep\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 4,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.571\\n    },\\n    \\\"pick_heat_then_place_in_recep\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.75\\n    },\\n    \\\"pick_two_obj_and_place\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 4,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.571\\n    }\\n  },\\n  \\\"episodes\\\": [\\n    {\\n      \\\"task_name\\\": \\\"look_at_obj_in_light-AlarmClock-None-DeskLamp-308\\\",\\n      \\\"task_type\\\": \\\"look_at_obj_in_light\\\",\\n      \\\"task_desc\\\": \\\"Hold the clock and turn on the lamp.\\\",\\n      \\\"success\\\": true,\\n      \\\"steps\\\": 12,\\n      \\\"operator\\\": \\\"P1_step_order_swap\\\",\\n      \\\"injection_step\\\": 2,\\n      \\\"injected\\\": true,\\n      \\\"recovery_analysis\\\": {\\n        \\\"detected\\\": false,\\n        \\\"detection_step\\\": null,\\n        \\\"recovery_actions_count\\\": 1,\\n        \\\"steps_after_injection\\\": 10\\n      },\\n      \\\"trajectory\\\": [\\n        {\\n          \\\"step\\\": 0,\\n          \\\"observation\\\": \\\"-= Welcome to TextWorld, ALFRED! =-\\\\n\\\\nYou are in the middle of a room. Looking quickly around you, you see a bed 1, a desk 2, a desk 1, a drawer 6, a drawer 5, a drawer 4, a drawer 3, a drawer 2, a dra\\\",\\n          \\\"action\\\": \\\"go to desk 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 1,\\n          \\\"observation\\\": \\\"You arrive at desk 1. On the desk 1, you see a bowl 1, a desklamp 1, a mug 1, and a pencil 1.\\\",\\n          \\\"action\\\": \\\"use desklamp 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 2,\\n          \\\"observation\\\": \\\"You turn on the desklamp 1.\\\",\\n          \\\"action\\\": \\\"go to shelf 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": true,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 3,\\n          \\\"observation\\\": \\\"You arrive at shelf 1. On the shelf 1, you see a keychain 3, and a pen 3.\\\",\\n          \\\"action\\\": \\\"go to shelf 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 4,\\n          \\\"observation\\\": \\\"You arrive at shelf 2. On the shelf 2, you see nothing.\\\",\\n          \\\"action\\\": \\\"go to shelf 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": fa\\n\\n... [截断: 输出过长，省略 468263 字符] ...\\n\\n       \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 39,\\n          \\\"observation\\\": \\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"take toiletpaper 1 from cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 40,\\n          \\\"observation\\\": \\\"You pick up the toiletpaper 1 from the cabinet 2.\\\",\\n          \\\"action\\\": \\\"move toiletpaper 1 to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 41,\\n          \\\"observation\\\": \\\"You move the toiletpaper 1 to the cabinet 2.\\\",\\n          \\\"action\\\": \\\"close cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 42,\\n          \\\"observation\\\": \\\"You close the cabinet 2.\\\",\\n          \\\"action\\\": \\\"look\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": true\\n        },\\n        {\\n          \\\"step\\\": 43,\\n          \\\"observation\\\": \\\"You are facing the cabinet 2. Next to it, you see nothing.\\\",\\n          \\\"action\\\": \\\"open cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 44,\\n          \\\"observation\\\": \\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"close cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 45,\\n          \\\"observation\\\": \\\"You close the cabinet 2.\\\",\\n          \\\"action\\\": \\\"examine cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": true\\n        },\\n        {\\n          \\\"step\\\": 46,\\n          \\\"observation\\\": \\\"The cabinet 2 is closed.\\\",\\n          \\\"action\\\": \\\"open cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 47,\\n          \\\"observation\\\": \\\"You open the cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"take toiletpaper 1 from cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 48,\\n          \\\"observation\\\": \\\"You pick up the toiletpaper 1 from the cabinet 2.\\\",\\n          \\\"action\\\": \\\"move toiletpaper 1 to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 49,\\n          \\\"observation\\\": \\\"You move the toiletpaper 1 to the cabinet 2.\\\",\\n          \\\"action\\\": \\\"close cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        }\\n      ]\\n    }\\n  ]\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.62}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01W2i2MuTKfh7JPKTwJ2t2qn`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval.json",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "4b1bdbb3-2b35-4460-8ce1-16fe09d2939b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019jiJaYh3fyRQCNGxAN91md",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14804,
      "cache_read_input_tokens": 25919,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14804
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

_source line 30 · 2026-05-15T03:29:03.294Z_

<details><summary>↩ Tool result · `toolu_01W2i2MuTKfh7JPKTwJ2t2qn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\\\",\\n  \\\"model_variant\\\": \\\"taxei\\\",\\n  \\\"inject\\\": true,\\n  \\\"seed\\\": 42,\\n  \\\"total_episodes\\\": 47,\\n  \\\"success_rate\\\": 0.596,\\n  \\\"recovery_rate\\\": 0.596,\\n  \\\"detection_rate\\\": 0.0,\\n  \\\"timestamp\\\": \\\"2026-05-14T20:49:14.687239+00:00\\\",\\n  \\\"by_operator\\\": {\\n    \\\"C1_context_truncation\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 8,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.667,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"C4_observation_masking\\\": {\\n      \\\"total\\\": 11,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.636,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P1_step_order_swap\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.583,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P2_sub_goal_deletion\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.5,\\n      \\\"detection_rate\\\": 0.0\\n    }\\n  },\\n  \\\"by_task_type\\\": {\\n    \\\"look_at_obj_in_light\\\": {\\n      \\\"total\\\": 6,\\n      \\\"success\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 1.0\\n    },\\n    \\\"pick_and_place_simple\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 4,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.5\\n    },\\n    \\\"pick_clean_then_place_in_recep\\\": {\\n      \\\"total\\\": 11,\\n      \\\"success\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.545\\n    },\\n    \\\"pick_cool_then_place_in_recep\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 3,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.429\\n    },\\n    \\\"pick_heat_then_place_in_recep\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.875\\n    },\\n    \\\"pick_two_obj_and_place\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 2,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.286\\n    }\\n  },\\n  \\\"episodes\\\": [\\n    {\\n      \\\"task_name\\\": \\\"look_at_obj_in_light-AlarmClock-None-DeskLamp-308\\\",\\n      \\\"task_type\\\": \\\"look_at_obj_in_light\\\",\\n      \\\"task_desc\\\": \\\"Hold the clock and turn on the lamp.\\\",\\n      \\\"success\\\": true,\\n      \\\"steps\\\": 5,\\n      \\\"operator\\\": \\\"P1_step_order_swap\\\",\\n      \\\"injection_step\\\": 2,\\n      \\\"injected\\\": true,\\n      \\\"recovery_analysis\\\": {\\n        \\\"detected\\\": false,\\n        \\\"detection_step\\\": null,\\n        \\\"recovery_actions_count\\\": 0,\\n        \\\"steps_after_injection\\\": 3\\n      },\\n      \\\"trajectory\\\": [\\n        {\\n          \\\"step\\\": 0,\\n          \\\"observation\\\": \\\"-= Welcome to TextWorld, ALFRED! =-\\\\n\\\\nYou are in the middle of a room. Looking quickly around you, you see a bed 1, a desk 2, a desk 1, a drawer 6, a drawer 5, a drawer 4, a drawer 3, a drawer 2, a dra\\\",\\n          \\\"action\\\": \\\"go to desk 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 1,\\n          \\\"observation\\\": \\\"You arrive at desk 1. On the desk 1, you see a bowl 1, a desklamp 1, a mug 1, and a pencil 1.\\\",\\n          \\\"action\\\": \\\"use desklamp 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 2,\\n          \\\"observation\\\": \\\"You turn on the desklamp 1.\\\",\\n          \\\"action\\\": \\\"go to desk 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": true,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 3,\\n          \\\"observation\\\": \\\"You arrive at desk 2. On the desk 2, you see a alarmclock 1.\\\",\\n          \\\"action\\\": \\\"take alarmclock 1 from desk 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 4,\\n          \\\"observation\\\": \\\"You pick up the alarmclock 1 from the desk 2.\\\",\\n          \\\"action\\\": \\\"go to desk 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"pos\\n\\n... [截断: 输出过长，省略 474103 字符] ...\\n\\n      \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 39,\\n          \\\"observation\\\": \\\"You arrive at cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"close cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 40,\\n          \\\"observation\\\": \\\"You close the cabinet 3.\\\",\\n          \\\"action\\\": \\\"go to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 41,\\n          \\\"observation\\\": \\\"You arrive at cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2.\\\",\\n          \\\"action\\\": \\\"go to cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 42,\\n          \\\"observation\\\": \\\"You arrive at cabinet 3. The cabinet 3 is closed.\\\",\\n          \\\"action\\\": \\\"open cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 43,\\n          \\\"observation\\\": \\\"You open the cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"close cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 44,\\n          \\\"observation\\\": \\\"You close the cabinet 3.\\\",\\n          \\\"action\\\": \\\"go to cabinet 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 45,\\n          \\\"observation\\\": \\\"You arrive at cabinet 1. The cabinet 1 is open. In it, you see a candle 2, and a cloth 1.\\\",\\n          \\\"action\\\": \\\"go to cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 46,\\n          \\\"observation\\\": \\\"You arrive at cabinet 3. The cabinet 3 is closed.\\\",\\n          \\\"action\\\": \\\"open cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 47,\\n          \\\"observation\\\": \\\"You open the cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"take toiletpaper 1 from cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 48,\\n          \\\"observation\\\": \\\"You pick up the toiletpaper 1 from the cabinet 3.\\\",\\n          \\\"action\\\": \\\"go to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 49,\\n          \\\"observation\\\": \\\"You arrive at cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2.\\\",\\n          \\\"action\\\": \\\"move toiletpaper 1 to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        }\\n      ]\\n    }\\n  ]\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "a1a381aa-c617-4c5f-8bf3-27025cf2ed2f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"model\\\\\\\": \\\\\\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\\\\\\\",\\\\n  \\\\\\\"model_variant\\\\\\\": \\\\\\\"taxei\\\\\\\",\\\\n  \\\\\\\"inject\\\\\\\": true,\\\\n  \\\\\\\"seed\\\\\\\": 42,\\\\n  \\\\\\\"total_episodes\\\\\\\": 47,\\\\n  \\\\\\\"success_rate\\\\\\\": 0.596,\\\\n  \\\\\\\"recovery_rate\\\\\\\": 0.596,\\\\n  \\\\\\\"detection_rate\\\\\\\": 0.0,\\\\n  \\\\\\\"timestamp\\\\\\\": \\\\\\\"2026-05-14T20:49:14.687239+00:00\\\\\\\",\\\\n  \\\\\\\"by_operator\\\\\\\": {\\\\n    \\\\\\\"C1_context_truncation\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 12,\\\\n      \\\\\\\"recovered\\\\\\\": 8,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.667,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"C4_observation_masking\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 11,\\\\n      \\\\\\\"recovered\\\\\\\": 7,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.636,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"P1_step_order_swap\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 12,\\\\n      \\\\\\\"recovered\\\\\\\": 7,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.583,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"P2_sub_goal_deletion\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 12,\\\\n      \\\\\\\"recovered\\\\\\\": 6,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"recovery_rate\\\\\\\": 0.5,\\\\n      \\\\\\\"detection_rate\\\\\\\": 0.0\\\\n    }\\\\n  },\\\\n  \\\\\\\"by_task_type\\\\\\\": {\\\\n    \\\\\\\"look_at_obj_in_light\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 6,\\\\n      \\\\\\\"success\\\\\\\": 6,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 1.0\\\\n    },\\\\n    \\\\\\\"pick_and_place_simple\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 8,\\\\n      \\\\\\\"success\\\\\\\": 4,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.5\\\\n    },\\\\n    \\\\\\\"pick_clean_then_place_in_recep\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 11,\\\\n      \\\\\\\"success\\\\\\\": 6,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.545\\\\n    },\\\\n    \\\\\\\"pick_cool_then_place_in_recep\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 7,\\\\n      \\\\\\\"success\\\\\\\": 3,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.429\\\\n    },\\\\n    \\\\\\\"pick_heat_then_place_in_recep\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 8,\\\\n      \\\\\\\"success\\\\\\\": 7,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.875\\\\n    },\\\\n    \\\\\\\"pick_two_obj_and_place\\\\\\\": {\\\\n      \\\\\\\"total\\\\\\\": 7,\\\\n      \\\\\\\"success\\\\\\\": 2,\\\\n      \\\\\\\"detected\\\\\\\": 0,\\\\n      \\\\\\\"rate\\\\\\\": 0.286\\\\n    }\\\\n  },\\\\n  \\\\\\\"episodes\\\\\\\": [\\\\n    {\\\\n      \\\\\\\"task_name\\\\\\\": \\\\\\\"look_at_obj_in_light-AlarmClock-None-DeskLamp-308\\\\\\\",\\\\n      \\\\\\\"task_type\\\\\\\": \\\\\\\"look_at_obj_in_light\\\\\\\",\\\\n      \\\\\\\"task_desc\\\\\\\": \\\\\\\"Hold the clock and turn on the lamp.\\\\\\\",\\\\n      \\\\\\\"success\\\\\\\": true,\\\\n      \\\\\\\"steps\\\\\\\": 5,\\\\n      \\\\\\\"operator\\\\\\\": \\\\\\\"P1_step_order_swap\\\\\\\",\\\\n      \\\\\\\"injection_step\\\\\\\": 2,\\\\n      \\\\\\\"injected\\\\\\\": true,\\\\n      \\\\\\\"recovery_analysis\\\\\\\": {\\\\n        \\\\\\\"detected\\\\\\\": false,\\\\n        \\\\\\\"detection_step\\\\\\\": null,\\\\n        \\\\\\\"recovery_actions_count\\\\\\\": 0,\\\\n        \\\\\\\"steps_after_injection\\\\\\\": 3\\\\n      },\\\\n      \\\\\\\"trajectory\\\\\\\": [\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 0,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"-= Welcome to TextWorld, ALFRED! =-\\\\\\\\n\\\\\\\\nYou are in the middle of a room. Looking quickly around you, you see a bed 1, a desk 2, a desk 1, a drawer 6, a drawer 5, a drawer 4, a drawer 3, a drawer 2, a dra\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to desk 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": false,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 1,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at desk 1. On the desk 1, you see a bowl 1, a desklamp 1, a mug 1, and a pencil 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"use desklamp 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": false,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 2,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You turn on the desklamp 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to desk 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": true,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 3,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at desk 2. On the desk 2, you see a alarmclock 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"take alarmclock 1 from desk 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 4,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You pick up the alarmclock 1 from the desk 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to desk 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"pos\\\\n\\\\n... [截断: 输出过长，省略 474103 字符] ...\\\\n\\\\n      \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 39,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"close cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 40,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You close the cabinet 3.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 41,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 42,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at cabinet 3. The cabinet 3 is closed.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"open cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 43,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You open the cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"close cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 44,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You close the cabinet 3.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to cabinet 1\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 45,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at cabinet 1. The cabinet 1 is open. In it, you see a candle 2, and a cloth 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 46,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at cabinet 3. The cabinet 3 is closed.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"open cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 47,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You open the cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"take toiletpaper 1 from cabinet 3\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 48,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You pick up the toiletpaper 1 from the cabinet 3.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"go to cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        },\\\\n        {\\\\n          \\\\\\\"step\\\\\\\": 49,\\\\n          \\\\\\\"observation\\\\\\\": \\\\\\\"You arrive at cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2.\\\\\\\",\\\\n          \\\\\\\"action\\\\\\\": \\\\\\\"move toiletpaper 1 to cabinet 2\\\\\\\",\\\\n          \\\\\\\"think_snippet\\\\\\\": \\\\\\\"\\\\\\\",\\\\n          \\\\\\\"injected_this_step\\\\\\\": false,\\\\n          \\\\\\\"post_injection\\\\\\\": true,\\\\n          \\\\\\\"detected_error\\\\\\\": false,\\\\n          \\\\\\\"recovery_action\\\\\\\": false\\\\n        }\\\\n      ]\\\\n    }\\\\n  ]\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.4}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\\\",\\n  \\\"model_variant\\\": \\\"taxei\\\",\\n  \\\"inject\\\": true,\\n  \\\"seed\\\": 42,\\n  \\\"total_episodes\\\": 47,\\n  \\\"success_rate\\\": 0.596,\\n  \\\"recovery_rate\\\": 0.596,\\n  \\\"detection_rate\\\": 0.0,\\n  \\\"timestamp\\\": \\\"2026-05-14T20:49:14.687239+00:00\\\",\\n  \\\"by_operator\\\": {\\n    \\\"C1_context_truncation\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 8,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.667,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"C4_observation_masking\\\": {\\n      \\\"total\\\": 11,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.636,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P1_step_order_swap\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.583,\\n      \\\"detection_rate\\\": 0.0\\n    },\\n    \\\"P2_sub_goal_deletion\\\": {\\n      \\\"total\\\": 12,\\n      \\\"recovered\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"recovery_rate\\\": 0.5,\\n      \\\"detection_rate\\\": 0.0\\n    }\\n  },\\n  \\\"by_task_type\\\": {\\n    \\\"look_at_obj_in_light\\\": {\\n      \\\"total\\\": 6,\\n      \\\"success\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 1.0\\n    },\\n    \\\"pick_and_place_simple\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 4,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.5\\n    },\\n    \\\"pick_clean_then_place_in_recep\\\": {\\n      \\\"total\\\": 11,\\n      \\\"success\\\": 6,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.545\\n    },\\n    \\\"pick_cool_then_place_in_recep\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 3,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.429\\n    },\\n    \\\"pick_heat_then_place_in_recep\\\": {\\n      \\\"total\\\": 8,\\n      \\\"success\\\": 7,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.875\\n    },\\n    \\\"pick_two_obj_and_place\\\": {\\n      \\\"total\\\": 7,\\n      \\\"success\\\": 2,\\n      \\\"detected\\\": 0,\\n      \\\"rate\\\": 0.286\\n    }\\n  },\\n  \\\"episodes\\\": [\\n    {\\n      \\\"task_name\\\": \\\"look_at_obj_in_light-AlarmClock-None-DeskLamp-308\\\",\\n      \\\"task_type\\\": \\\"look_at_obj_in_light\\\",\\n      \\\"task_desc\\\": \\\"Hold the clock and turn on the lamp.\\\",\\n      \\\"success\\\": true,\\n      \\\"steps\\\": 5,\\n      \\\"operator\\\": \\\"P1_step_order_swap\\\",\\n      \\\"injection_step\\\": 2,\\n      \\\"injected\\\": true,\\n      \\\"recovery_analysis\\\": {\\n        \\\"detected\\\": false,\\n        \\\"detection_step\\\": null,\\n        \\\"recovery_actions_count\\\": 0,\\n        \\\"steps_after_injection\\\": 3\\n      },\\n      \\\"trajectory\\\": [\\n        {\\n          \\\"step\\\": 0,\\n          \\\"observation\\\": \\\"-= Welcome to TextWorld, ALFRED! =-\\\\n\\\\nYou are in the middle of a room. Looking quickly around you, you see a bed 1, a desk 2, a desk 1, a drawer 6, a drawer 5, a drawer 4, a drawer 3, a drawer 2, a dra\\\",\\n          \\\"action\\\": \\\"go to desk 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 1,\\n          \\\"observation\\\": \\\"You arrive at desk 1. On the desk 1, you see a bowl 1, a desklamp 1, a mug 1, and a pencil 1.\\\",\\n          \\\"action\\\": \\\"use desklamp 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": false,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 2,\\n          \\\"observation\\\": \\\"You turn on the desklamp 1.\\\",\\n          \\\"action\\\": \\\"go to desk 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": true,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 3,\\n          \\\"observation\\\": \\\"You arrive at desk 2. On the desk 2, you see a alarmclock 1.\\\",\\n          \\\"action\\\": \\\"take alarmclock 1 from desk 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 4,\\n          \\\"observation\\\": \\\"You pick up the alarmclock 1 from the desk 2.\\\",\\n          \\\"action\\\": \\\"go to desk 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"pos\\n\\n... [截断: 输出过长，省略 474103 字符] ...\\n\\n      \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 39,\\n          \\\"observation\\\": \\\"You arrive at cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"close cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 40,\\n          \\\"observation\\\": \\\"You close the cabinet 3.\\\",\\n          \\\"action\\\": \\\"go to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 41,\\n          \\\"observation\\\": \\\"You arrive at cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2.\\\",\\n          \\\"action\\\": \\\"go to cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 42,\\n          \\\"observation\\\": \\\"You arrive at cabinet 3. The cabinet 3 is closed.\\\",\\n          \\\"action\\\": \\\"open cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 43,\\n          \\\"observation\\\": \\\"You open the cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"close cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 44,\\n          \\\"observation\\\": \\\"You close the cabinet 3.\\\",\\n          \\\"action\\\": \\\"go to cabinet 1\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 45,\\n          \\\"observation\\\": \\\"You arrive at cabinet 1. The cabinet 1 is open. In it, you see a candle 2, and a cloth 1.\\\",\\n          \\\"action\\\": \\\"go to cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 46,\\n          \\\"observation\\\": \\\"You arrive at cabinet 3. The cabinet 3 is closed.\\\",\\n          \\\"action\\\": \\\"open cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 47,\\n          \\\"observation\\\": \\\"You open the cabinet 3. The cabinet 3 is open. In it, you see a spraybottle 1, and a toiletpaper 1.\\\",\\n          \\\"action\\\": \\\"take toiletpaper 1 from cabinet 3\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 48,\\n          \\\"observation\\\": \\\"You pick up the toiletpaper 1 from the cabinet 3.\\\",\\n          \\\"action\\\": \\\"go to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        },\\n        {\\n          \\\"step\\\": 49,\\n          \\\"observation\\\": \\\"You arrive at cabinet 2. The cabinet 2 is open. In it, you see a soapbottle 2.\\\",\\n          \\\"action\\\": \\\"move toiletpaper 1 to cabinet 2\\\",\\n          \\\"think_snippet\\\": \\\"\\\",\\n          \\\"injected_this_step\\\": false,\\n          \\\"post_injection\\\": true,\\n          \\\"detected_error\\\": false,\\n          \\\"recovery_action\\\": false\\n        }\\n      ]\\n    }\\n  ]\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 31_

<details><summary>Logged reasoning block</summary>

```text
I have the data. Let me extract the per-operator breakdown:

**Vanilla recovery eval (v4_vanilla_recovery_eval.json):**
- Overall: 61.7% (29/47)
- C1_context_truncation: 75.0% (9/12)
- C4_observation_masking: 54.5% (6/11)
- P1_step_order_swap: 58.3% (7/12)
- P2_sub_goal_deletion: 58.3% (7/12)


**TaxEI recovery eval (v4_taxei_recovery_eval.json):**
- Overall: 59.6% (28/47)
- C1_context_truncation: 66.7% (8/12)
- C4_observation_masking: 63.6% (7/11)
- P1_step_order_swap: 58.3% (7/12)
- P2_sub_goal_deletion: 50.0% (6/12)

Now I'm calculating the performance differences between the two approaches across each operator category.

Looking at the reported Figure 2 deltas against what I'm actually seeing in the data, there are some notable discrepancies—C4 shows a +9.1pp improvement rather than the claimed +6.1pp, P1 is flat at 0.0pp instead of -2.7pp, and C1 is down 8.3pp rather than 5.6pp. Let me double-check the TaxEI baseline numbers to see if there's a different interpretation of the data. I'm computing the actual deltas between the TaxEI and vanilla data, and they're not matching what was claimed in Figure 2 — C1 is off by 2.7 percentage points, C4 by 3 points, P1 by 2.7 points, and P2 is nearly correct. Something's inconsistent here, so let me verify my calculations. the Fig 2 uses different baseline data. Let me re-read the task:

"验证 Fig 2 中的 delta 是否正确 (C4=+6.1, P1=-2.7, C1=-5.6, P2=-8.4)"

So these are the claimed deltas in Fig 2. My actual calculations show:
- C1: -8.3pp (claimed -5.6) → INCORRECT
- C4: +9.1pp (claimed +6.1) → INCORRECT
- P1: 0.0pp (claimed -2.7) → INCORRECT
- P2: -8.3pp (claimed -8.4) → Close, ~CORRECT

Actually wait, maybe the recovery_rate numbers aren't what I think. Let me re-examine the actual recovery rates for both conditions. Computing the deltas by subtracting Vanilla from TaxEI, I'm getting C1 at -8.33pp, C4 at +9.09pp, P1 at 0pp, and P2 at -5pp.

These don't match the claimed deltas at all. Let me check if there's a different TaxEI recovery eval (r2) that was used, and also search the registry more carefully since the initial query only returned 20 of 61 total entries.

Looking at the r2 file might reveal different per-operator numbers, or maybe the Fig 2 deltas were computed against a seed-averaged vanilla baseline instead. I'll read through the r2 file and proceed with what I have so far.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "f23683a0-2e42-4d45-ab3f-400371bbda8d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YXUEEW1RwBH9w7or8YaFdq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8456,
      "cache_read_input_tokens": 40723,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8456
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

_source line 32_

Got both files. Let me also check the TaxEI r2 file and find the vanilla recovery eval registry entry.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "aa7832d3-d084-416c-a2e5-b0bdc84e06a2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YXUEEW1RwBH9w7or8YaFdq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8456,
      "cache_read_input_tokens": 40723,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8456
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

_source line 33_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01VPk2HvsTsSEhrx5qzMZAKC`</summary>

```json
{
  "server": "autodl-5090",
  "command": "python3 -c \"import json; d=json.load(open('/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval_r2.json')); print(json.dumps(d.get('by_operator',{}), indent=2))\"",
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "c8717c2a-ba2d-4b4d-b711-bd0f348c59dc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YXUEEW1RwBH9w7or8YaFdq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8456,
      "cache_read_input_tokens": 40723,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8456
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

_source line 34 · 2026-05-15T03:29:35.041Z_

<details><summary>↩ Tool result · `toolu_01VPk2HvsTsSEhrx5qzMZAKC`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "d18a28a8-0283-48e8-b46e-ec6664b25066",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01TpqVAMfSMVsjbXYMirqfkK`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "status",
    "metrics",
    "conclusion"
  ],
  "limit": 61
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "b4d5174c-77f6-4b30-a9d1-f38ca9f35581",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YXUEEW1RwBH9w7or8YaFdq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8456,
      "cache_read_input_tokens": 40723,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8456
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

_source line 36 · 2026-05-15T03:29:36.325Z_

<details><summary>↩ Tool result · `toolu_01TpqVAMfSMVsjbXYMirqfkK`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject50-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.574, \"eval_successes\": 27, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -4.3, \"vs_taxei_50_pp\": 6.3}}, \"v4-random-fixed-inject25-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -6.4, \"vs_taxei_25_pp\": 6.4}}, \"v4-random-fixed-inject50\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358, \"train_loss\": 0.4338, \"final_step_loss\": 0.2618, \"token_accuracy\": 0.91, \"train_duration_min\": 53.1, \"memory_gib\": 18, \"train_speed_s_per_it\": 1.95}}, \"v4-random-fixed-inject25\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}}, \"v4-random-fixed-inject10-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject50-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -10.6}, \"conclusion\": \"negative\"}, \"v4-random-fixed-inject10\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4226, \"final_step_loss\": 0.3079, \"token_accuracy\": 0.9, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 57}}, \"v4-taxei-fixed-inject50\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.259, \"token_accuracy\": 0.911, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 53.1}}, \"v4-random-seed123-eval\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-taxei-fixed-inject25-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.489, \"eval_successes\": 23, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 4, \"total\": 6, \"rate\": 0.667}, \"pick_and_place_simple\": {\"success\": 3, \"total\": 8, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-seed123-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-random-seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.35484016, \"final_loss\": 0.16766574, \"token_accuracy\": 0.94187103, \"avg_token_accuracy\": 0.90849673, \"train_steps\": 3387, \"train_epochs\": 3, \"train_runtime_sec\": 6609.3556, \"train_duration_min\": 110.2, \"train_samples_per_second\": 4.098, \"train_steps_per_second\": 0.512, \"train_speed_s_per_it\": 1.951, \"memory_gib\": 18.49}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject25-r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.285, \"token_accuracy\": 0.893, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}}, \"v4-taxei-fixed-inject10\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.308, \"token_accuracy\": 0.888, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}}, \"v4-taxei-fixed-inject25\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"v4-taxei-seed123\": {\"status\": \"DONE\", \"metrics\": {\"final_loss\": 0.35506879, \"token_accuracy\": 0.89978214, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 109.2, \"train_runtime_sec\": 6549.432, \"train_speed_s_per_it\": 1.934, \"memory_gib\": 18.49}, \"conclusion\": \"success\"}, \"v4-random-recovery-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.638, \"detection_rate\": 0, \"successes\": 30, \"total\": 47, \"source\": \"json-file-verified\", \"note\": \"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\"}}, \"v4-taxei-recovery-eval-r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.596, \"detection_rate\": 0, \"total_episodes\": 47, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 8, \"total\": 12, \"rate\": 0.667}, \"C4_observation_masking\": {\"recovered\": 7, \"total\": 11, \"rate\": 0.636}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 6, \"total\": 12, \"rate\": 0.5}}}}, \"v4-taxei-seed0-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47, \"vs_seed42_pp\": -14.9}}, \"v4-random-seed0-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_seed42_pp\": -10.7}}, \"v4-vanilla-recovery-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"recovery_rate\": 0.617, \"detection_rate\": 0}}, \"v4-taxei-recovery-eval\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"recovery_rate\": 0.596, \"detection_rate\": 0}}, \"v4-vanilla-seed123-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3, \"vs_seed0_pp\": -2.1, \"per_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}}, \"v4-random-seed0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.912, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}}, \"v4-taxei-seed0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.917, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}}, \"v4-vanilla-seed0-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"vs_seed42_pp\": 6.4, \"mcnemar_vs_seed42_p\": 0.375, \"discordant_pairs\": 5, \"per_task\": {\"look_at_obj_in_light\": \"5/6 (83.3%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"4/7 (57.1%)\", \"pick_heat_then_place\": \"7/8 (87.5%)\", \"pick_two_obj_and_place\": \"5/7 (71.4%)\"}}}, \"v4-vanilla-seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.288, \"token_accuracy\": 0.903, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58.9}}, \"v4-vanilla-seed0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.297, \"avg_loss\": 0.416, \"token_accuracy\": 0.902, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}}, \"v4-vanilla-seed7\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"traj_collect_500\": {\"status\": \"DONE\", \"metrics\": {\"successful_trajectories\": 501, \"failed_trajectories\": 213, \"total_attempts\": 714, \"success_rate\": 0.702, \"api_cost_usd\": 8.86, \"collection_time_sec\": 5245}, \"conclusion\": \"negative\"}, \"mini-vanilla-sft\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_success_rate\": 0.149, \"eval_successes\": 7, \"eval_total\": 47, \"vs_baseline_pp\": -27.7, \"per_task\": {\"look_at_obj_in_light\": \"0/6 (0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"2/11 (18.2%)\", \"pick_cool_then_place\": \"0/7 (0%)\", \"pick_heat_then_place\": \"3/8 (37.5%)\", \"pick_two_obj_and_place\": \"0/7 (0%)\"}, \"train_steps\": 54, \"train_duration_min\": 5}}, \"mini-taxei-sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.447, \"eval_successes\": 21, \"eval_total\": 47, \"vs_baseline_pp\": 2.1, \"per_task\": {\"look_at_obj_in_light\": \"3/6 (50.0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"1/7 (14.3%)\", \"pick_heat_then_place\": \"6/8 (75.0%)\", \"pick_two_obj_and_place\": \"3/7 (42.9%)\"}, \"train_steps\": 195, \"train_duration_min\": 16.3}}, \"vanilla-react-baseline\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.426, \"total_tasks\": 47, \"successes\": 20, \"per_task_type\": {\"pick_heat_then_place\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"look_at_obj_in_light\": {\"success\": 3, \"total\": 6, \"rate\": 0.5}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_cool_then_place\": {\"success\": 0, \"total\": 7, \"rate\": 0}}}}, \"sft-dryrun-73\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss_init\": 2.436, \"train_loss_final\": 1.543, \"train_loss_avg\": 1.894, \"peak_memory_gib\": 19.22, \"steps\": 8, \"duration_sec\": 42, \"data_vanilla\": 124, \"data_injected_dryrun\": 96, \"injected_failed\": 4}}}, \"count\": 35, \"total\": 35, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.1376}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "c69b67a9-2fb4-4ffe-99f5-85f00767917c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"v4-random-fixed-inject50-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.574, \\\"eval_successes\\\": 27, \\\"eval_total\\\": 47, \\\"vs_vanilla_seed42_pp\\\": -4.3, \\\"vs_taxei_50_pp\\\": 6.3}}, \\\"v4-random-fixed-inject25-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.553, \\\"eval_successes\\\": 26, \\\"eval_total\\\": 47, \\\"vs_vanilla_seed42_pp\\\": -6.4, \\\"vs_taxei_25_pp\\\": 6.4}}, \\\"v4-random-fixed-inject50\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"data_count\\\": 4358, \\\"train_loss\\\": 0.4338, \\\"final_step_loss\\\": 0.2618, \\\"token_accuracy\\\": 0.91, \\\"train_duration_min\\\": 53.1, \\\"memory_gib\\\": 18, \\\"train_speed_s_per_it\\\": 1.95}}, \\\"v4-random-fixed-inject25\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"data_count\\\": 4358}}, \\\"v4-random-fixed-inject10-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.681, \\\"eval_successes\\\": 32, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 6, \\\"rate\\\": 0.545}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 7, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 5, \\\"rate\\\": 0.714}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject50-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.511, \\\"eval_successes\\\": 24, \\\"eval_total\\\": 47, \\\"vs_vanilla_seed42_pp\\\": -10.6}, \\\"conclusion\\\": \\\"negative\\\"}, \\\"v4-random-fixed-inject10\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.4226, \\\"final_step_loss\\\": 0.3079, \\\"token_accuracy\\\": 0.9, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 57}}, \\\"v4-taxei-fixed-inject50\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.259, \\\"token_accuracy\\\": 0.911, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 53.1}}, \\\"v4-random-seed123-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.681, \\\"eval_successes\\\": 32, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 7, \\\"rate\\\": 0.636}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 6, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 5, \\\"rate\\\": 0.714}}}}, \\\"v4-taxei-fixed-inject25-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.489, \\\"eval_successes\\\": 23, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 4, \\\"total\\\": 6, \\\"rate\\\": 0.667}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 3, \\\"total\\\": 8, \\\"rate\\\": 0.375}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 2, \\\"total\\\": 7, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 8, \\\"rate\\\": 0.625}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject10-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.617, \\\"eval_successes\\\": 29, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 5, \\\"total\\\": 8, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 6, \\\"total\\\": 8, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-seed123-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.617, \\\"eval_successes\\\": 29, \\\"eval_total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 4, \\\"total\\\": 8, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 7, \\\"total\\\": 11, \\\"rate\\\": 0.636}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 3, \\\"total\\\": 7, \\\"rate\\\": 0.429}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 6, \\\"total\\\": 8, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.35484016, \\\"final_loss\\\": 0.16766574, \\\"token_accuracy\\\": 0.94187103, \\\"avg_token_accuracy\\\": 0.90849673, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_runtime_sec\\\": 6609.3556, \\\"train_duration_min\\\": 110.2, \\\"train_samples_per_second\\\": 4.098, \\\"train_steps_per_second\\\": 0.512, \\\"train_speed_s_per_it\\\": 1.951, \\\"memory_gib\\\": 18.49}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject25-r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.285, \\\"token_accuracy\\\": 0.893, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 58}}, \\\"v4-taxei-fixed-inject10\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.308, \\\"token_accuracy\\\": 0.888, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 58}}, \\\"v4-taxei-fixed-inject25\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"v4-taxei-seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.35506879, \\\"token_accuracy\\\": 0.89978214, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 109.2, \\\"train_runtime_sec\\\": 6549.432, \\\"train_speed_s_per_it\\\": 1.934, \\\"memory_gib\\\": 18.49}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-recovery-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"recovery_rate\\\": 0.638, \\\"detection_rate\\\": 0, \\\"successes\\\": 30, \\\"total\\\": 47, \\\"source\\\": \\\"json-file-verified\\\", \\\"note\\\": \\\"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\\\"}}, \\\"v4-taxei-recovery-eval-r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"recovery_rate\\\": 0.596, \\\"detection_rate\\\": 0, \\\"total_episodes\\\": 47, \\\"per_operator\\\": {\\\"C1_context_truncation\\\": {\\\"recovered\\\": 8, \\\"total\\\": 12, \\\"rate\\\": 0.667}, \\\"C4_observation_masking\\\": {\\\"recovered\\\": 7, \\\"total\\\": 11, \\\"rate\\\": 0.636}, \\\"P1_step_order_swap\\\": {\\\"recovered\\\": 7, \\\"total\\\": 12, \\\"rate\\\": 0.583}, \\\"P2_sub_goal_deletion\\\": {\\\"recovered\\\": 6, \\\"total\\\": 12, \\\"rate\\\": 0.5}}}}, \\\"v4-taxei-seed0-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.468, \\\"eval_successes\\\": 22, \\\"eval_total\\\": 47, \\\"vs_seed42_pp\\\": -14.9}}, \\\"v4-random-seed0-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.553, \\\"eval_successes\\\": 26, \\\"eval_total\\\": 47, \\\"vs_seed42_pp\\\": -10.7}}, \\\"v4-vanilla-recovery-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.617, \\\"successes\\\": 29, \\\"total\\\": 47, \\\"recovery_rate\\\": 0.617, \\\"detection_rate\\\": 0}}, \\\"v4-taxei-recovery-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.596, \\\"successes\\\": 28, \\\"total\\\": 47, \\\"recovery_rate\\\": 0.596, \\\"detection_rate\\\": 0}}, \\\"v4-vanilla-seed123-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.66, \\\"eval_successes\\\": 31, \\\"eval_total\\\": 47, \\\"vs_seed42_pp\\\": 4.3, \\\"vs_seed0_pp\\\": -2.1, \\\"per_task\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 6, \\\"total\\\": 8, \\\"rate\\\": 0.75}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 7, \\\"total\\\": 8, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}}, \\\"v4-random-seed0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.355, \\\"token_accuracy\\\": 0.912, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 110}}, \\\"v4-taxei-seed0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.355, \\\"token_accuracy\\\": 0.917, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 110}}, \\\"v4-vanilla-seed0-eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.681, \\\"eval_successes\\\": 32, \\\"eval_total\\\": 47, \\\"vs_seed42_pp\\\": 6.4, \\\"mcnemar_vs_seed42_p\\\": 0.375, \\\"discordant_pairs\\\": 5, \\\"per_task\\\": {\\\"look_at_obj_in_light\\\": \\\"5/6 (83.3%)\\\", \\\"pick_and_place_simple\\\": \\\"5/8 (62.5%)\\\", \\\"pick_clean_then_place\\\": \\\"6/11 (54.5%)\\\", \\\"pick_cool_then_place\\\": \\\"4/7 (57.1%)\\\", \\\"pick_heat_then_place\\\": \\\"7/8 (87.5%)\\\", \\\"pick_two_obj_and_place\\\": \\\"5/7 (71.4%)\\\"}}}, \\\"v4-vanilla-seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.288, \\\"token_accuracy\\\": 0.903, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 58.9}}, \\\"v4-vanilla-seed0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.297, \\\"avg_loss\\\": 0.416, \\\"token_accuracy\\\": 0.902, \\\"train_steps\\\": 1635, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 58}}, \\\"v4-vanilla-seed7\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"traj_collect_500\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"successful_trajectories\\\": 501, \\\"failed_trajectories\\\": 213, \\\"total_attempts\\\": 714, \\\"success_rate\\\": 0.702, \\\"api_cost_usd\\\": 8.86, \\\"collection_time_sec\\\": 5245}, \\\"conclusion\\\": \\\"negative\\\"}, \\\"mini-vanilla-sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.149, \\\"eval_successes\\\": 7, \\\"eval_total\\\": 47, \\\"vs_baseline_pp\\\": -27.7, \\\"per_task\\\": {\\\"look_at_obj_in_light\\\": \\\"0/6 (0%)\\\", \\\"pick_and_place_simple\\\": \\\"2/8 (25.0%)\\\", \\\"pick_clean_then_place\\\": \\\"2/11 (18.2%)\\\", \\\"pick_cool_then_place\\\": \\\"0/7 (0%)\\\", \\\"pick_heat_then_place\\\": \\\"3/8 (37.5%)\\\", \\\"pick_two_obj_and_place\\\": \\\"0/7 (0%)\\\"}, \\\"train_steps\\\": 54, \\\"train_duration_min\\\": 5}}, \\\"mini-taxei-sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.447, \\\"eval_successes\\\": 21, \\\"eval_total\\\": 47, \\\"vs_baseline_pp\\\": 2.1, \\\"per_task\\\": {\\\"look_at_obj_in_light\\\": \\\"3/6 (50.0%)\\\", \\\"pick_and_place_simple\\\": \\\"2/8 (25.0%)\\\", \\\"pick_clean_then_place\\\": \\\"6/11 (54.5%)\\\", \\\"pick_cool_then_place\\\": \\\"1/7 (14.3%)\\\", \\\"pick_heat_then_place\\\": \\\"6/8 (75.0%)\\\", \\\"pick_two_obj_and_place\\\": \\\"3/7 (42.9%)\\\"}, \\\"train_steps\\\": 195, \\\"train_duration_min\\\": 16.3}}, \\\"vanilla-react-baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"overall_success_rate\\\": 0.426, \\\"total_tasks\\\": 47, \\\"successes\\\": 20, \\\"per_task_type\\\": {\\\"pick_heat_then_place\\\": {\\\"success\\\": 5, \\\"total\\\": 8, \\\"rate\\\": 0.625}, \\\"look_at_obj_in_light\\\": {\\\"success\\\": 3, \\\"total\\\": 6, \\\"rate\\\": 0.5}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 4, \\\"total\\\": 8, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 3, \\\"total\\\": 7, \\\"rate\\\": 0.429}, \\\"pick_cool_then_place\\\": {\\\"success\\\": 0, \\\"total\\\": 7, \\\"rate\\\": 0}}}}, \\\"sft-dryrun-73\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss_init\\\": 2.436, \\\"train_loss_final\\\": 1.543, \\\"train_loss_avg\\\": 1.894, \\\"peak_memory_gib\\\": 19.22, \\\"steps\\\": 8, \\\"duration_sec\\\": 42, \\\"data_vanilla\\\": 124, \\\"data_injected_dryrun\\\": 96, \\\"injected_failed\\\": 4}}}, \\\"count\\\": 35, \\\"total\\\": 35, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.1376}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject50-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.574, \"eval_successes\": 27, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -4.3, \"vs_taxei_50_pp\": 6.3}}, \"v4-random-fixed-inject25-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -6.4, \"vs_taxei_25_pp\": 6.4}}, \"v4-random-fixed-inject50\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358, \"train_loss\": 0.4338, \"final_step_loss\": 0.2618, \"token_accuracy\": 0.91, \"train_duration_min\": 53.1, \"memory_gib\": 18, \"train_speed_s_per_it\": 1.95}}, \"v4-random-fixed-inject25\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}}, \"v4-random-fixed-inject10-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject50-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -10.6}, \"conclusion\": \"negative\"}, \"v4-random-fixed-inject10\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4226, \"final_step_loss\": 0.3079, \"token_accuracy\": 0.9, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 57}}, \"v4-taxei-fixed-inject50\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.259, \"token_accuracy\": 0.911, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 53.1}}, \"v4-random-seed123-eval\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-taxei-fixed-inject25-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.489, \"eval_successes\": 23, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 4, \"total\": 6, \"rate\": 0.667}, \"pick_and_place_simple\": {\"success\": 3, \"total\": 8, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-seed123-eval\": {\"status\": \"DONE\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-random-seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.35484016, \"final_loss\": 0.16766574, \"token_accuracy\": 0.94187103, \"avg_token_accuracy\": 0.90849673, \"train_steps\": 3387, \"train_epochs\": 3, \"train_runtime_sec\": 6609.3556, \"train_duration_min\": 110.2, \"train_samples_per_second\": 4.098, \"train_steps_per_second\": 0.512, \"train_speed_s_per_it\": 1.951, \"memory_gib\": 18.49}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject25-r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.285, \"token_accuracy\": 0.893, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}}, \"v4-taxei-fixed-inject10\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.308, \"token_accuracy\": 0.888, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}}, \"v4-taxei-fixed-inject25\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"v4-taxei-seed123\": {\"status\": \"DONE\", \"metrics\": {\"final_loss\": 0.35506879, \"token_accuracy\": 0.89978214, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 109.2, \"train_runtime_sec\": 6549.432, \"train_speed_s_per_it\": 1.934, \"memory_gib\": 18.49}, \"conclusion\": \"success\"}, \"v4-random-recovery-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.638, \"detection_rate\": 0, \"successes\": 30, \"total\": 47, \"source\": \"json-file-verified\", \"note\": \"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\"}}, \"v4-taxei-recovery-eval-r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.596, \"detection_rate\": 0, \"total_episodes\": 47, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 8, \"total\": 12, \"rate\": 0.667}, \"C4_observation_masking\": {\"recovered\": 7, \"total\": 11, \"rate\": 0.636}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 6, \"total\": 12, \"rate\": 0.5}}}}, \"v4-taxei-seed0-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47, \"vs_seed42_pp\": -14.9}}, \"v4-random-seed0-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_seed42_pp\": -10.7}}, \"v4-vanilla-recovery-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"recovery_rate\": 0.617, \"detection_rate\": 0}}, \"v4-taxei-recovery-eval\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"recovery_rate\": 0.596, \"detection_rate\": 0}}, \"v4-vanilla-seed123-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3, \"vs_seed0_pp\": -2.1, \"per_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}}, \"v4-random-seed0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.912, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}}, \"v4-taxei-seed0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.917, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}}, \"v4-vanilla-seed0-eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"vs_seed42_pp\": 6.4, \"mcnemar_vs_seed42_p\": 0.375, \"discordant_pairs\": 5, \"per_task\": {\"look_at_obj_in_light\": \"5/6 (83.3%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"4/7 (57.1%)\", \"pick_heat_then_place\": \"7/8 (87.5%)\", \"pick_two_obj_and_place\": \"5/7 (71.4%)\"}}}, \"v4-vanilla-seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.288, \"token_accuracy\": 0.903, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58.9}}, \"v4-vanilla-seed0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.297, \"avg_loss\": 0.416, \"token_accuracy\": 0.902, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}}, \"v4-vanilla-seed7\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"traj_collect_500\": {\"status\": \"DONE\", \"metrics\": {\"successful_trajectories\": 501, \"failed_trajectories\": 213, \"total_attempts\": 714, \"success_rate\": 0.702, \"api_cost_usd\": 8.86, \"collection_time_sec\": 5245}, \"conclusion\": \"negative\"}, \"mini-vanilla-sft\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_success_rate\": 0.149, \"eval_successes\": 7, \"eval_total\": 47, \"vs_baseline_pp\": -27.7, \"per_task\": {\"look_at_obj_in_light\": \"0/6 (0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"2/11 (18.2%)\", \"pick_cool_then_place\": \"0/7 (0%)\", \"pick_heat_then_place\": \"3/8 (37.5%)\", \"pick_two_obj_and_place\": \"0/7 (0%)\"}, \"train_steps\": 54, \"train_duration_min\": 5}}, \"mini-taxei-sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.447, \"eval_successes\": 21, \"eval_total\": 47, \"vs_baseline_pp\": 2.1, \"per_task\": {\"look_at_obj_in_light\": \"3/6 (50.0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"1/7 (14.3%)\", \"pick_heat_then_place\": \"6/8 (75.0%)\", \"pick_two_obj_and_place\": \"3/7 (42.9%)\"}, \"train_steps\": 195, \"train_duration_min\": 16.3}}, \"vanilla-react-baseline\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.426, \"total_tasks\": 47, \"successes\": 20, \"per_task_type\": {\"pick_heat_then_place\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"look_at_obj_in_light\": {\"success\": 3, \"total\": 6, \"rate\": 0.5}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_cool_then_place\": {\"success\": 0, \"total\": 7, \"rate\": 0}}}}, \"sft-dryrun-73\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss_init\": 2.436, \"train_loss_final\": 1.543, \"train_loss_avg\": 1.894, \"peak_memory_gib\": 19.22, \"steps\": 8, \"duration_sec\": 42, \"data_vanilla\": 124, \"data_injected_dryrun\": 96, \"injected_failed\": 4}}}, \"count\": 35, \"total\": 35, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.1376}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 37_

<details><summary>Logged reasoning block</summary>

````text
Now I have all the data. Let me also check the r2 TaxEI file to see if the per-operator data differs.

From the registry, `v4-taxei-recovery-eval-r2` has:
```
per_operator: {
  C1: 8/12 = 66.7%
  C4: 7/11 = 63.6%
  P1: 7/12 = 58.3%
  P2: 6/12 = 50.0%
}
```

This matches the r1 JSON file exactly. So TaxEI data is consistent.


Now looking at the vanilla recovery eval entry in the registry — it has the overall metrics but is missing the per-operator breakdown. I can extract that from the vanilla JSON file, which shows the individual operator success rates for C1, C4, P1, and P2.

Comparing against the TaxEI results, I'm calculating the deltas to see where TaxEI improved or regressed relative to vanilla. Most operators show small differences, though C4 shows a notable improvement of about 9 percentage points. But when I check this against what Figure 2 claims, there's a discrepancy in the C4 delta that I need to investigate.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "5e33e85c-c1bc-434f-a72d-b7a2f33e0191",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J74c3Z3EqUXXkSRSAZ9qqf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7593,
      "cache_read_input_tokens": 49179,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7593
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

All data extracted. Now let me update the registry and register the report.

**Vanilla per-operator (from JSON):**
| Operator | Recovered | Total | Rate |
|----------|-----------|-------|------|
| C1_context_truncation | 9 | 12 | 75.0% |
| C4_observation_masking | 6 | 11 | 54.5% |
| P1_step_order_swap | 7 | 12 | 58.3% |
| P2_sub_goal_deletion | 7 | 12 | 58.3% |

**Delta (TaxEI - Vanilla):**
| Operator | TaxEI | Vanilla | Delta |
|----------|-------|---------|-------|
| C1 | 66.7% | 75.0% | **-8.3pp** |
| C4 | 63.6% | 54.5% | **+9.1pp** |
| P1 | 58.3% | 58.3% | **0.0pp** |
| P2 | 50.0% | 58.3% | **-8.3pp** |

Fig 2 claimed deltas are **all incorrect**: C4 claimed +6.1 (actual +9.1), P1 claimed -2.7 (actual 0.0), C1 claimed -5.6 (actual -8.3), P2 claimed -8.4 (actual -8.3).

Updating registry and registering artifact now.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "eefc1260-0fc6-468e-b10e-9facce2758d3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J74c3Z3EqUXXkSRSAZ9qqf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7593,
      "cache_read_input_tokens": 49179,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7593
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_016kz3UzqgkdHVZHAk3tqW1p`</summary>

```json
{
  "exp_id": "v4-vanilla-recovery-eval",
  "field": "metrics",
  "value": {
    "success_rate": 0.617,
    "successes": 29,
    "total": 47,
    "recovery_rate": 0.617,
    "detection_rate": 0,
    "per_operator": {
      "C1_context_truncation": {
        "recovered": 9,
        "total": 12,
        "rate": 0.75
      },
      "C4_observation_masking": {
        "recovered": 6,
        "total": 11,
        "rate": 0.545
      },
      "P1_step_order_swap": {
        "recovered": 7,
        "total": 12,
        "rate": 0.583
      },
      "P2_sub_goal_deletion": {
        "recovered": 7,
        "total": 12,
        "rate": 0.583
      }
    }
  },
  "project": "tax_error_inject_agent"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "7ef145f0-7e81-43f9-941e-e2547b0b8fcd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J74c3Z3EqUXXkSRSAZ9qqf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7593,
      "cache_read_input_tokens": 49179,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7593
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

_source line 40 · 2026-05-15T03:29:56.193Z_

<details><summary>↩ Tool result · `toolu_016kz3UzqgkdHVZHAk3tqW1p`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"v4-vanilla-recovery-eval\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:30:18.314Z\", \"updated_at\": \"2026-05-15T03:29:56.077Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_recovery_eval.json\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=42)\", \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks with error injection\", \"seed\": 42, \"parent\": \"mini-vanilla-sft-v4\", \"checkpoint_path\": \"eval_results/v4_vanilla_recovery_eval.json\", \"log_path\": \"eval_results/v4_vanilla_recovery_eval.json\"}, \"hypothesis\": \"v4 Vanilla SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"recovery_rate\": 0.617, \"detection_rate\": 0, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 9, \"total\": 12, \"rate\": 0.75}, \"C4_observation_masking\": {\"recovered\": 6, \"total\": 11, \"rate\": 0.545}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}}}, \"completed_at\": \"2026-05-14T21:20:15.791Z\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2827}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "ababae06-ca0e-4511-b544-3c4e2efa6e6a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"v4-vanilla-recovery-eval\\\", \\\"experiment\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-14T19:30:18.314Z\\\", \\\"updated_at\\\": \\\"2026-05-15T03:29:56.077Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_recovery_eval.json\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"model_name\\\": \\\"Qwen3-8B + LoRA (vanilla v4 seed=42)\\\", \\\"checkpoint_source\\\": \\\"checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks with error injection\\\", \\\"seed\\\": 42, \\\"parent\\\": \\\"mini-vanilla-sft-v4\\\", \\\"checkpoint_path\\\": \\\"eval_results/v4_vanilla_recovery_eval.json\\\", \\\"log_path\\\": \\\"eval_results/v4_vanilla_recovery_eval.json\\\"}, \\\"hypothesis\\\": \\\"v4 Vanilla SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.617, \\\"successes\\\": 29, \\\"total\\\": 47, \\\"recovery_rate\\\": 0.617, \\\"detection_rate\\\": 0, \\\"per_operator\\\": {\\\"C1_context_truncation\\\": {\\\"recovered\\\": 9, \\\"total\\\": 12, \\\"rate\\\": 0.75}, \\\"C4_observation_masking\\\": {\\\"recovered\\\": 6, \\\"total\\\": 11, \\\"rate\\\": 0.545}, \\\"P1_step_order_swap\\\": {\\\"recovered\\\": 7, \\\"total\\\": 12, \\\"rate\\\": 0.583}, \\\"P2_sub_goal_deletion\\\": {\\\"recovered\\\": 7, \\\"total\\\": 12, \\\"rate\\\": 0.583}}}, \\\"completed_at\\\": \\\"2026-05-14T21:20:15.791Z\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.2827}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"v4-vanilla-recovery-eval\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:30:18.314Z\", \"updated_at\": \"2026-05-15T03:29:56.077Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_recovery_eval.json\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=42)\", \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks with error injection\", \"seed\": 42, \"parent\": \"mini-vanilla-sft-v4\", \"checkpoint_path\": \"eval_results/v4_vanilla_recovery_eval.json\", \"log_path\": \"eval_results/v4_vanilla_recovery_eval.json\"}, \"hypothesis\": \"v4 Vanilla SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"recovery_rate\": 0.617, \"detection_rate\": 0, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 9, \"total\": 12, \"rate\": 0.75}, \"C4_observation_masking\": {\"recovered\": 6, \"total\": 11, \"rate\": 0.545}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}}}, \"completed_at\": \"2026-05-14T21:20:15.791Z\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2827}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01UvCF3RGiAKkLzKXFqf6anw`</summary>

```json
{
  "name": "vanilla-recovery-per-operator-breakdown",
  "type": "report",
  "description": "Per-operator recovery breakdown for vanilla vs TaxEI, with Fig 2 delta verification",
  "project": "tax_error_inject_agent",
  "exp_id": "v4-vanilla-recovery-eval",
  "content_filename": "vanilla_recovery_per_operator_breakdown.md",
  "content": "# Vanilla Recovery Eval: Per-Operator Breakdown\n\nSource: `eval_results/v4_vanilla_recovery_eval.json` (seed=42, 47 episodes)\n\n## Vanilla Per-Operator Recovery\n\n| Operator | Recovered | Total | Rate |\n|----------|-----------|-------|------|\n| C1_context_truncation | 9 | 12 | 75.0% |\n| C4_observation_masking | 6 | 11 | 54.5% |\n| P1_step_order_swap | 7 | 12 | 58.3% |\n| P2_sub_goal_deletion | 7 | 12 | 58.3% |\n| **Overall** | **29** | **47** | **61.7%** |\n\n## TaxEI Per-Operator Recovery (known, from v4-taxei-recovery-eval)\n\n| Operator | Recovered | Total | Rate |\n|----------|-----------|-------|------|\n| C1_context_truncation | 8 | 12 | 66.7% |\n| C4_observation_masking | 7 | 11 | 63.6% |\n| P1_step_order_swap | 7 | 12 | 58.3% |\n| P2_sub_goal_deletion | 6 | 12 | 50.0% |\n| **Overall** | **28** | **47** | **59.6%** |\n\n## Delta Table (TaxEI - Vanilla)\n\n| Operator | Vanilla | TaxEI | Delta (pp) | Fig 2 Claimed | Match? |\n|----------|---------|-------|------------|---------------|--------|\n| C1_context_truncation | 75.0% | 66.7% | **-8.3** | -5.6 | NO |\n| C4_observation_masking | 54.5% | 63.6% | **+9.1** | +6.1 | NO |\n| P1_step_order_swap | 58.3% | 58.3% | **0.0** | -2.7 | NO |\n| P2_sub_goal_deletion | 58.3% | 50.0% | **-8.3** | -8.4 | ~YES (rounding) |\n\n## Fig 2 Delta Verification\n\n**3 of 4 deltas are INCORRECT in Fig 2:**\n\n1. **C1**: Fig 2 claims -5.6pp, actual is -8.3pp (off by 2.7pp)\n2. **C4**: Fig 2 claims +6.1pp, actual is +9.1pp (off by 3.0pp)\n3. **P1**: Fig 2 claims -2.7pp, actual is 0.0pp (off by 2.7pp)\n4. **P2**: Fig 2 claims -8.4pp, actual is -8.3pp (off by 0.1pp — acceptable rounding)\n\nDirectional patterns are preserved (C4 is the only positive delta, C1/P2 are negative), but magnitudes are wrong. P1 direction is also wrong (claimed negative, actually zero).\n\n**Possible explanation**: Fig 2 may have used a different run (different seed or r2) for either vanilla or TaxEI baseline. The r2 TaxEI eval has identical per-operator numbers to r1, so the discrepancy is not from TaxEI side.\n",
  "tags": [
    "recovery-eval",
    "per-operator",
    "fig2-verification",
    "vanilla",
    "taxei"
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
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "2c1cec2d-82cc-4d43-96e4-01e06b44ac91",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J74c3Z3EqUXXkSRSAZ9qqf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7593,
      "cache_read_input_tokens": 49179,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7593
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

_source line 42 · 2026-05-15T03:30:09.321Z_

<details><summary>↩ Tool result · `toolu_01UvCF3RGiAKkLzKXFqf6anw`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_8856f0\", \"name\": \"vanilla-recovery-per-operator-breakdown\", \"type\": \"report\", \"description\": \"Per-operator recovery breakdown for vanilla vs TaxEI, with Fig 2 delta verification\", \"path\": \"projects/tax_error_inject_agent/artifacts/v4-vanilla-recovery-eval/report/vanilla_recovery_per_operator_breakdown.md\", \"url\": null, \"project\": \"tax_error_inject_agent\", \"exp_id\": \"v4-vanilla-recovery-eval\", \"skill\": \"\", \"created_at\": \"2026-05-15T03:30:09.260782+00:00\", \"tags\": [\"recovery-eval\", \"per-operator\", \"fig2-verification\", \"vanilla\", \"taxei\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "a35a3648-3504-4314-80af-f479fc4b1bec",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260515_8856f0\\\", \\\"name\\\": \\\"vanilla-recovery-per-operator-breakdown\\\", \\\"type\\\": \\\"report\\\", \\\"description\\\": \\\"Per-operator recovery breakdown for vanilla vs TaxEI, with Fig 2 delta verification\\\", \\\"path\\\": \\\"projects/tax_error_inject_agent/artifacts/v4-vanilla-recovery-eval/report/vanilla_recovery_per_operator_breakdown.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"tax_error_inject_agent\\\", \\\"exp_id\\\": \\\"v4-vanilla-recovery-eval\\\", \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-15T03:30:09.260782+00:00\\\", \\\"tags\\\": [\\\"recovery-eval\\\", \\\"per-operator\\\", \\\"fig2-verification\\\", \\\"vanilla\\\", \\\"taxei\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_8856f0\", \"name\": \"vanilla-recovery-per-operator-breakdown\", \"type\": \"report\", \"description\": \"Per-operator recovery breakdown for vanilla vs TaxEI, with Fig 2 delta verification\", \"path\": \"projects/tax_error_inject_agent/artifacts/v4-vanilla-recovery-eval/report/vanilla_recovery_per_operator_breakdown.md\", \"url\": null, \"project\": \"tax_error_inject_agent\", \"exp_id\": \"v4-vanilla-recovery-eval\", \"skill\": \"\", \"created_at\": \"2026-05-15T03:30:09.260782+00:00\", \"tags\": [\"recovery-eval\", \"per-operator\", \"fig2-verification\", \"vanilla\", \"taxei\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 43_

Registry updated, artifact registered.

**结果总结：**

Vanilla per-operator recovery (seed=42):
- C1: 75.0% (9/12) — 最高，context truncation 容忍度好
- C4: 54.5% (6/11)
- P1: 58.3% (7/12)
- P2: 58.3% (7/12)

**Fig 2 delta 验证：4 个中 3 个有误。** 只有 P2 (-8.3 vs claimed -8.4) 基本正确。C4 实际 +9.1 (claimed +6.1)，C1 实际 -8.3 (claimed -5.6)，P1 实际 0.0 (claimed -2.7)。方向大致对（C4 唯一正 delta），但数值和 P1 方向需要修正。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "uuid": "34919c2c-d7d7-4474-b0c2-dd7441085618",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019u1Hp1iwVt1FGBAtWGpDPz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3464,
      "cache_read_input_tokens": 56772,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3464
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

_source line 44_

Registry updated, artifact registered.

**结果总结：**

Vanilla per-operator recovery (seed=42):
- C1: 75.0% (9/12) — 最高，context truncation 容忍度好
- C4: 54.5% (6/11)
- P1: 58.3% (7/12)
- P2: 58.3% (7/12)

**Fig 2 delta 验证：4 个中 3 个有误。** 只有 P2 (-8.3 vs claimed -8.4) 基本正确。C4 实际 +9.1 (claimed +6.1)，C1 实际 -8.3 (claimed -5.6)，P1 实际 0.0 (claimed -2.7)。方向大致对（C4 唯一正 delta），但数值和 P1 方向需要修正。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 96502,
  "duration_api_ms": 96827,
  "num_turns": 15,
  "stop_reason": "end_turn",
  "session_id": "daa5c89a-1483-4816-870c-a351e5a5b684",
  "total_cost_usd": 0.57342125,
  "usage": {
    "input_tokens": 11,
    "cache_creation_input_tokens": 48395,
    "cache_read_input_tokens": 232897,
    "output_tokens": 6125,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 48395,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 238,
        "cache_read_input_tokens": 56772,
        "cache_creation_input_tokens": 3464,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 3464
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1244,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001324,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 11,
      "outputTokens": 6125,
      "cacheReadInputTokens": 232897,
      "cacheCreationInputTokens": 48395,
      "webSearchRequests": 0,
      "costUSD": 0.57209725,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "b7948146-d6c2-4460-aa25-490ea6e6c5b5"
}
```

</details>

---

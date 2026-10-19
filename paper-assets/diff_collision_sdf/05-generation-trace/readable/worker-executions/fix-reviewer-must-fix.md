# fix reviewer must fix

**How Action Collapse Creates Illusory Safety in Diffusion-Based VLA Collision Avoidance Evaluation** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 125
- **Recorded user turns:** 0
- **Tool calls:** 46
- **Original source:** `logs/workers/worker_fix_reviewer_must_fix_20260527T203458.log`
- **Structured JSON:** [`3c5e61878cd0e87c9955.json`](../../sessions/3c/3c5e61878cd0e87c9955.json)

## Before a recorded user message

125 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf",
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
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
  "uuid": "8b00efcd-0c18-4e4b-a112-762880c18d8d",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-be-idea-gen-0515-projects-diff-collision-sdf/memory/"
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
    "resetsAt": 1779930600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "1afb7f86-188c-49a2-a736-60d5c03553bb",
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369"
}
```

---

### Assistant

_source line 4_

I'll start by examining the paper files on the server to understand the current state.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "51a97260-a1a1-48fb-9082-3dfb02bb366b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TsHpHUytq8FeMQpMDrm5eJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12690,
      "cache_read_input_tokens": 11451,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12690
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01SRUHV44FydnhiWGxRrvapV`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "edd5565b-80d5-4ef1-9035-7135ed929fe2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TsHpHUytq8FeMQpMDrm5eJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12690,
      "cache_read_input_tokens": 11451,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12690
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

_source line 6 · 2026-05-27T20:35:11.369Z_

<details><summary>↩ Tool result · `toolu_01SRUHV44FydnhiWGxRrvapV`</summary>

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
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f05f30d3-a65a-40ca-83ee-127f25af552a",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__ssh_execute"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute",
    "total_deferred_tools": 23
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me start by examining the paper files on the server to understand the current state of each item that needs fixing.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "eeb9a61d-ca86-42a6-b7c6-c144e6c7c320",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MyHbMpPWwta6joYhFFvRFi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 689,
      "cache_read_input_tokens": 24141,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 689
      },
      "output_tokens": 30,
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

Let me first check the file structure and current state of all relevant files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "2297edca-0d34-4dea-852b-21a37444f1cb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MyHbMpPWwta6joYhFFvRFi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 689,
      "cache_read_input_tokens": 24141,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 689
      },
      "output_tokens": 30,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01SBM5an37R2KJ4sGcTrzAPk`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root/colliforce-vla/paper/ -name \"*.tex\" | head -20",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "5a3a7b4a-d11b-4943-955d-e50c67cbaab4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MyHbMpPWwta6joYhFFvRFi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 689,
      "cache_read_input_tokens": 24141,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 689
      },
      "output_tokens": 30,
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

_source line 10 · 2026-05-27T20:35:15.659Z_

<details><summary>↩ Tool result · `toolu_01SBM5an37R2KJ4sGcTrzAPk`</summary>

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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "7649d7f2-545d-45db-8bf4-bd15452cc486",
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

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01HkAyberR81TM3AmxNJBu86`</summary>

```json
{
  "server": "westd-45947",
  "command": "grep -rn \"within.*pp\" /root/colliforce-vla/paper/ --include=\"*.tex\"",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f5876165-7a66-4edb-8510-55ba70e9c5d9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MyHbMpPWwta6joYhFFvRFi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 689,
      "cache_read_input_tokens": 24141,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 689
      },
      "output_tokens": 30,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01RU1B7KR2kmoWUjnEvd7AVP`</summary>

```json
{
  "server": "westd-45947",
  "command": "grep -rn \"0.005.*0.01\" /root/colliforce-vla/paper/ --include=\"*.tex\"",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a631e192-7a67-416f-aa36-86334e4a1e01",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MyHbMpPWwta6joYhFFvRFi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 689,
      "cache_read_input_tokens": 24141,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 689
      },
      "output_tokens": 30,
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

_source line 13 · 2026-05-27T20:35:17.676Z_

<details><summary>↩ Tool result · `toolu_01HkAyberR81TM3AmxNJBu86`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/colliforce-vla/paper/: No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 1.07}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "cb95d364-90a9-4063-8812-1f625cae04a5",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"grep: /root/colliforce-vla/paper/: No such file or directory\\\\n\\\", \\\"return_code\\\": 2}, \\\"error\\\": \\\"exit code 2\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.07}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/colliforce-vla/paper/: No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 1.07}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-27T20:35:18.199Z_

<details><summary>↩ Tool result · `toolu_01RU1B7KR2kmoWUjnEvd7AVP`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/colliforce-vla/paper/: No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.51}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f3a2176a-c8ed-408c-b2db-9d0a406bbf59",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"grep: /root/colliforce-vla/paper/: No such file or directory\\\\n\\\", \\\"return_code\\\": 2}, \\\"error\\\": \\\"exit code 2\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.51}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"grep: /root/colliforce-vla/paper/: No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.51}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01JSQEWvCU92jeQgJdBnQcKD`</summary>

```json
{
  "server": "westd-45947",
  "command": "grep -rn \"z.test\\|z-test\\|z =\\|z=\" /root/colliforce-vla/paper/ --include=\"*.tex\"",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "8a944f53-4f9c-46b9-b8f0-4f897a077441",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MyHbMpPWwta6joYhFFvRFi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 689,
      "cache_read_input_tokens": 24141,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 689
      },
      "output_tokens": 30,
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

_source line 16 · 2026-05-27T20:35:18.330Z_

<details><summary>↩ Tool result · `toolu_01JSQEWvCU92jeQgJdBnQcKD`</summary>

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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a816160d-6b0e-4ad1-9167-ec998688c6fe",
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

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
The paper directory doesn't exist at `/root/colliforce-vla/paper/`. Let me check what's actually on the server.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "72685e5c-d7cf-47e5-b197-573592119c4f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WAv89pmbry6K5nwDK2otda",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 24830,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1024
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

_source line 18_

Paper directory not found at expected path. Let me locate it.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a796f9d3-0430-451a-bf1a-a72b67fa4557",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WAv89pmbry6K5nwDK2otda",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 24830,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1024
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

_source line 19_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01VJtGeRcoMAB4WS6PCRdTyJ`</summary>

```json
{
  "server": "westd-45947",
  "command": "ls /root/colliforce-vla/",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "e6516e45-9b22-48af-90f6-15a6f8605150",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WAv89pmbry6K5nwDK2otda",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 24830,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1024
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

_source line 20 · 2026-05-27T20:35:22.846Z_

<details><summary>↩ Tool result · `toolu_01VJtGeRcoMAB4WS6PCRdTyJ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"LIBERO\\nartifacts\\nassets\\ncheckpoints\\ncolliforce\\ncompute_threshold_sensitivity_v2.py\\ndata\\ndebug_action_consistency.py\\ngenerate_training_data.py\\nlogs\\nopenpi\\nreeval_batch2.sh\\nrun_all_eval_v8.sh\\nscripts\\nsdf_pipeline.py\\nvlsa-aegis\\nwandb\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "e9e0dd54-c183-4b17-bf9c-262cbe7f83ab",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"LIBERO\\\\nartifacts\\\\nassets\\\\ncheckpoints\\\\ncolliforce\\\\ncompute_threshold_sensitivity_v2.py\\\\ndata\\\\ndebug_action_consistency.py\\\\ngenerate_training_data.py\\\\nlogs\\\\nopenpi\\\\nreeval_batch2.sh\\\\nrun_all_eval_v8.sh\\\\nscripts\\\\nsdf_pipeline.py\\\\nvlsa-aegis\\\\nwandb\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.44}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"LIBERO\\nartifacts\\nassets\\ncheckpoints\\ncolliforce\\ncompute_threshold_sensitivity_v2.py\\ndata\\ndebug_action_consistency.py\\ngenerate_training_data.py\\nlogs\\nopenpi\\nreeval_batch2.sh\\nrun_all_eval_v8.sh\\nscripts\\nsdf_pipeline.py\\nvlsa-aegis\\nwandb\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 21_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_016eP9DWLFquEceL86awFv18`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root -name \"paper\" -type d -maxdepth 4",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a3b26dd1-a94f-4ea3-912a-28c0d90f915f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WAv89pmbry6K5nwDK2otda",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 24830,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1024
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

_source line 22 · 2026-05-27T20:35:23.492Z_

<details><summary>↩ Tool result · `toolu_016eP9DWLFquEceL86awFv18`</summary>

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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "3efe9b7c-f0e2-4b5c-8ef8-a516d2646a3c",
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

### Assistant

_source line 23_

<details><summary>Logged reasoning block</summary>

```text
No `paper` directory on westd-45947. The project context says the server is `westd-35807`, but the task says to use `westd-45947`. Let me check on westd-35807 instead, which is the primary server listed in the project context.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f018ca97-c9ec-4863-8374-fe2bfd5d1dc3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Jf5gn4qRiu6yQbWyML165o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 25854,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
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

_source line 24_

No `paper` directory on westd-45947. Let me check the primary server westd-35807.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "462c4788-4f19-46e9-ab89-4aebba001e6c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Jf5gn4qRiu6yQbWyML165o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 25854,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
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

_source line 25_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01H1EdsmTnWWeu13MaUKLvJR`</summary>

```json
{
  "server": "westd-35807",
  "command": "ls /root/colliforce-vla/paper/",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "990dc68d-920c-4ff3-a456-2e5cafa43f83",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Jf5gn4qRiu6yQbWyML165o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 25854,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
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

_source line 26 · 2026-05-27T20:35:41.400Z_

<details><summary>↩ Tool result · `toolu_01H1EdsmTnWWeu13MaUKLvJR`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"ls: cannot access '/root/colliforce-vla/paper/': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.99}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a3e8a7cf-659c-498c-b5f1-8bb5667c7261",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"ls: cannot access '/root/colliforce-vla/paper/': No such file or directory\\\\n\\\", \\\"return_code\\\": 2}, \\\"error\\\": \\\"exit code 2\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.99}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"ls: cannot access '/root/colliforce-vla/paper/': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.99}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Yaaea7ujGSpxyMnhJQ8ZJL`</summary>

```json
{
  "server": "westd-35807",
  "command": "find /root -name \"*.tex\" -maxdepth 5",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b10d5f1a-a086-48ab-8d43-e3f1df734382",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018xA5AmMPXraLfN1fKB5G3A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 318,
      "cache_read_input_tokens": 26547,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 318
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

### Tool call

_source line 28_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FxMP4YLC3U7CLN3P9eKPMD`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root -name \"*.tex\" -maxdepth 5",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "8bce64bb-cfbf-4fad-b52d-0e96def2507e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018xA5AmMPXraLfN1fKB5G3A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 318,
      "cache_read_input_tokens": 26547,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 318
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

_source line 29 · 2026-05-27T20:35:44.698Z_

<details><summary>↩ Tool result · `toolu_01Yaaea7ujGSpxyMnhJQ8ZJL`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "738dece4-0681-4142-9f62-6ebaa070390d",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.45}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-27T20:35:45.176Z_

<details><summary>↩ Tool result · `toolu_01FxMP4YLC3U7CLN3P9eKPMD`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.47}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "d772aa64-398f-417b-a64a-a734e6a2c8cd",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.47}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.47}}"
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
No .tex files on either server. Let me check if the paper is in the local project directory instead.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b6500d9b-95e7-4374-95ae-3aaa1cf5fb7b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lnkbsn9FmQe8j6it9m4cvS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 26865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 424
      },
      "output_tokens": 23,
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

No `.tex` files on either server. Let me check locally.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "08937433-eb17-4bd7-913b-8812cdde5130",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lnkbsn9FmQe8j6it9m4cvS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 26865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 424
      },
      "output_tokens": 23,
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

<details open><summary>🔧 Tool call — Glob · `toolu_01DDrdYEmVNBnjpW9bk3W7VK`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "c08a9ff5-2df9-46a0-9983-7183b7b472aa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lnkbsn9FmQe8j6it9m4cvS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 26865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 424
      },
      "output_tokens": 23,
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

_source line 34 · 2026-05-27T20:35:50.252Z_

<details><summary>↩ Tool result · `toolu_01DDrdYEmVNBnjpW9bk3W7VK`</summary>

```text
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/method.tex
artifacts/drafts/method.tex
artifacts/_project/paper/related_work.tex
artifacts/drafts/experiments.tex
artifacts/drafts/abstract.tex
artifacts/drafts/conclusion.tex
artifacts/drafts/introduction.tex
artifacts/drafts/related_work.tex
artifacts/_project/paper/analysis_claim1.tex
artifacts/drafts/analysis_claim1.tex
artifacts/_project/paper/analysis_claim2.tex
artifacts/drafts/analysis_claim2.tex
artifacts/_project/paper/analysis_claim3.tex
artifacts/drafts/analysis_claim3.tex
artifacts/_project/paper/experimental_framework.tex
artifacts/drafts/experimental_framework.tex
artifacts/_project/paper/introduction_v2.tex
artifacts/_project/paper/abstract_v2.tex
artifacts/drafts/abstract_v2.tex
artifacts/drafts/introduction_v2.tex
artifacts/drafts/related_work_v2.tex
artifacts/_project/paper/related_work_v2.tex
artifacts/dream_reports/dream_20260525T223036/best/paper.tex
artifacts/dream_reports/dream_20260525T223036/median/paper.tex
artifacts/dream_reports/dream_20260525T223036/worst/paper.tex
artifacts/dream_reports/dream_20260526T023936/best/paper.tex
artifacts/dream_reports/dream_20260526T023936/median/paper.tex
artifacts/dream_reports/dream_20260526T023936/worst/paper.tex
artifacts/reeval_comparison.tex
artifacts/_project/paper/discussion.tex
docs/paper/_archive/method.tex
docs/paper/_archive/experiments.tex
docs/paper/_archive/conclusion_DEPRECATED.tex
docs/paper/appendix.tex
docs/paper/archive/analysis_claim4.tex
docs/paper/archive/analysis_claim2.tex
docs/paper/archive/analysis_claim1.tex
docs/paper/archive/analysis_claim3.tex
docs/paper/contingency_claim3.tex
docs/paper/experimental_framework.tex
docs/paper/main.tex
docs/paper/abstract.tex
docs/paper/claim1.tex
docs/paper/claim2.tex
docs/paper/discussion.tex
docs/paper/related_work.tex
docs/paper/method.tex
docs/paper/introduction.tex
docs/paper/claim3.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "9b1f59ab-ab1b-402a-984f-b9dbacac0dce",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/paper/introduction.tex",
      "artifacts/_project/paper/method.tex",
      "artifacts/drafts/method.tex",
      "artifacts/_project/paper/related_work.tex",
      "artifacts/drafts/experiments.tex",
      "artifacts/drafts/abstract.tex",
      "artifacts/drafts/conclusion.tex",
      "artifacts/drafts/introduction.tex",
      "artifacts/drafts/related_work.tex",
      "artifacts/_project/paper/analysis_claim1.tex",
      "artifacts/drafts/analysis_claim1.tex",
      "artifacts/_project/paper/analysis_claim2.tex",
      "artifacts/drafts/analysis_claim2.tex",
      "artifacts/_project/paper/analysis_claim3.tex",
      "artifacts/drafts/analysis_claim3.tex",
      "artifacts/_project/paper/experimental_framework.tex",
      "artifacts/drafts/experimental_framework.tex",
      "artifacts/_project/paper/introduction_v2.tex",
      "artifacts/_project/paper/abstract_v2.tex",
      "artifacts/drafts/abstract_v2.tex",
      "artifacts/drafts/introduction_v2.tex",
      "artifacts/drafts/related_work_v2.tex",
      "artifacts/_project/paper/related_work_v2.tex",
      "artifacts/dream_reports/dream_20260525T223036/best/paper.tex",
      "artifacts/dream_reports/dream_20260525T223036/median/paper.tex",
      "artifacts/dream_reports/dream_20260525T223036/worst/paper.tex",
      "artifacts/dream_reports/dream_20260526T023936/best/paper.tex",
      "artifacts/dream_reports/dream_20260526T023936/median/paper.tex",
      "artifacts/dream_reports/dream_20260526T023936/worst/paper.tex",
      "artifacts/reeval_comparison.tex",
      "artifacts/_project/paper/discussion.tex",
      "docs/paper/_archive/method.tex",
      "docs/paper/_archive/experiments.tex",
      "docs/paper/_archive/conclusion_DEPRECATED.tex",
      "docs/paper/appendix.tex",
      "docs/paper/archive/analysis_claim4.tex",
      "docs/paper/archive/analysis_claim2.tex",
      "docs/paper/archive/analysis_claim1.tex",
      "docs/paper/archive/analysis_claim3.tex",
      "docs/paper/contingency_claim3.tex",
      "docs/paper/experimental_framework.tex",
      "docs/paper/main.tex",
      "docs/paper/abstract.tex",
      "docs/paper/claim1.tex",
      "docs/paper/claim2.tex",
      "docs/paper/discussion.tex",
      "docs/paper/related_work.tex",
      "docs/paper/method.tex",
      "docs/paper/introduction.tex",
      "docs/paper/claim3.tex"
    ],
    "durationMs": 19,
    "numFiles": 50,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01D8NrqyB6eRtC7uTbtf1UP2`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root -name \"claim3.tex\" -maxdepth 6",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b42df9d2-264f-4074-a598-c9ab9c814160",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lnkbsn9FmQe8j6it9m4cvS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 26865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 424
      },
      "output_tokens": 23,
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

_source line 36_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01AABYmPdw6Z6zV5DDxfs19M`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root -name \"method.tex\" -maxdepth 6",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "4a3f6dbf-dbea-4bd0-9389-eb2db14670a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lnkbsn9FmQe8j6it9m4cvS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 26865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 424
      },
      "output_tokens": 23,
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

_source line 37 · 2026-05-27T20:35:51.413Z_

<details><summary>↩ Tool result · `toolu_01D8NrqyB6eRtC7uTbtf1UP2`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "2473d574-603f-43b5-b9dd-21748fb873e8",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.5}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 38 · 2026-05-27T20:35:51.999Z_

<details><summary>↩ Tool result · `toolu_01AABYmPdw6Z6zV5DDxfs19M`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.57}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "18759a17-9086-4824-80ec-e4d7d985bb01",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.57}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.57}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 39_

<details><summary>Logged reasoning block</summary>

```text
The paper files are local, under `/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/`. The task references `sections/claim3.tex` but the actual path is `docs/paper/claim3.tex`. Let me read the relevant files now.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "1e21f9ed-b5a4-4bff-8d0e-996240c8c9e1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mEuXqtaDwTrtipbos8eVv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1186,
      "cache_read_input_tokens": 27289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1186
      },
      "output_tokens": 19,
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

_source line 40_

Paper files are local under `docs/paper/`. Let me read all relevant files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b084e010-d5ac-4a23-8166-eccd6945a058",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mEuXqtaDwTrtipbos8eVv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1186,
      "cache_read_input_tokens": 27289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1186
      },
      "output_tokens": 19,
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

_source line 41_

<details open><summary>🔧 Tool call — Read · `toolu_01LENQ4wc65bDGGXjtLu5YAy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "2cb05f7a-a6c3-451f-8f6d-b5d6ba9d567d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mEuXqtaDwTrtipbos8eVv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1186,
      "cache_read_input_tokens": 27289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1186
      },
      "output_tokens": 19,
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

_source line 42 · 2026-05-27T20:35:57.800Z_

<details><summary>↩ Tool result · `toolu_01LENQ4wc65bDGGXjtLu5YAy`</summary>

```text
1	\section{Avoidance Source Diagnosis}\label{sec:avoidance_source}
2	
3	Fine-tuning on collision-free demonstrations produces genuine collision avoidance: LoRA-adapted Pi0.5 raises CAR by ${\sim}$28 percentage points with zero frozen episodes. Does SDF geometric supervision contribute additional avoidance beyond what demonstrations provide? We compare LoRA-only, LoRA+SDF ($\lambda = 0.005$), and LoRA+SDF ($\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint.
4	
5	\begin{table}[t]
6	\centering
7	\caption{Avoidance source attribution on SafeLIBERO. SDF at $\lambda \leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \approx 0.039$, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\% frozen rate and displacement $>$\,0.37\,m.}
8	\label{tab:avoidance_source}
9	\vspace{2pt}
10	\small
11	\begin{tabular}{lcccc}
12	\toprule
13	Method & Seeds & TSR (\%) & CAR (\%) & EE Disp (m) \\
14	\midrule
15	Pi0.5 baseline & 3 & 74.7\,$\pm$\,1.5 & 26.8\,$\pm$\,1.6 & 0.367 \\
16	\midrule
17	LoRA-only (no SDF) & 3 & 49.7\,$\pm$\,3.2 & 54.83\,$\pm$\,2.25 & 0.391 \\
18	LoRA+SDF $\lambda{=}0.005$ & 3 & 54.0\,$\pm$\,3.0 & 54.5\,$\pm$\,2.29 & 0.387 \\
19	LoRA+SDF $\lambda{=}0.01$ & 3 & 53.8\,$\pm$\,1.5 & 56.33\,$\pm$\,1.61 & 0.389 \\
20	LoRA+SDF $\lambda{=}0.1$\textsuperscript{$\dagger$} & 2 & 48.0\,$\pm$\,1.4 & 58.25\,$\pm$\,0.35 & 0.394 \\
21	\bottomrule
22	\end{tabular}
23	\vspace{1pt}
24	{\footnotesize \textsuperscript{$\dagger$}30K checkpoint, two of three seeds; third seed in progress.}
25	\end{table}
26	
27	Table~\ref{tab:avoidance_source} shows that collision-free demonstrations alone raise CAR by ${\sim}$28 percentage points (26.8\% $\to$ 54.83\%) with zero frozen episodes and displacement above 0.37\,m, which confirms genuine avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only CAR (54.83\%) is within 0.33\,pp of $\lambda = 0.005$ and statistically indistinguishable from $\lambda = 0.01$ (56.33\%, $p > 0.1$; Appendix~\ref{sec:appendix_null}). A Phase~2 ablation ($\lambda = 0$ after step 5K) yields CAR\,=\,57.5\%\footnote{Single seed (s2); computational constraints precluded additional seeds for this ablation.}; SDF gradients produce no lasting behavioral effect. The per-task CAR ordering is preserved across all conditions (chocolate\_pudding highest, bbq\_sauce lowest) and invariant to $\lambda$ across a 20$\times$ range; avoidance patterns reflect the demonstration distribution rather than geometric supervision.
28	
29	\paragraph{CAR--TSR trade-off.}\label{sec:tsr_collapse}
30	Fine-tuning degrades TSR by ${\sim}$21--25\,pp (74.7\% $\to$ 49.7--54.0\%), a consequence of distributional shift from the pre-trained prior rather than learned paralysis (all models retain $>$\,0.37\,m displacement and 0\% frozen episodes). The SSR/TSR ratio increases from 0.33 (baseline) to 0.51--0.57 (Appendix~\ref{sec:appendix_ssr}): among task-completing episodes, a larger fraction avoids collisions after fine-tuning.
31	
32	\paragraph{Dose-response at higher loss weights.}\label{sec:lambda_high}
33	Increasing $\lambda$ by 20$\times$ to 0.1 yields CAR\,=\,58.25\%\,$\pm$\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\%, $\sigma = 2.04$, $z = 1.76$, $p \approx 0.039$). This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\%, within 0.3$\sigma$ of the null; Appendix~\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\lambda \leq 0.01$ ($p > 0.1$), with a marginal signal at $\lambda = 0.1$ whose modest effect size (${\sim}$3.6\,pp) and limited sample preclude strong conclusions. Even at elevated $\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.
34	
35	\begin{figure}[t]
36	\centering
37	\includegraphics[width=0.85\linewidth]{fig5_lambda_curve}
38	\caption{Effect of SDF loss weight $\lambda$ on CAR and TSR. $\lambda = 0$: LoRA-only. Low $\lambda$ ($\leq 0.01$) remains within the null band; $\lambda = 0.1$ (58.25\%, 2 seeds) shows a marginal departure ($p \approx 0.039$) whose per-task pattern still matches the demonstration distribution.}
39	\label{fig:lambda_car}
40	\end{figure}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "7643d845-93db-455a-af30-438b08f8245b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
      "content": "\\section{Avoidance Source Diagnosis}\\label{sec:avoidance_source}\n\nFine-tuning on collision-free demonstrations produces genuine collision avoidance: LoRA-adapted Pi0.5 raises CAR by ${\\sim}$28 percentage points with zero frozen episodes. Does SDF geometric supervision contribute additional avoidance beyond what demonstrations provide? We compare LoRA-only, LoRA+SDF ($\\lambda = 0.005$), and LoRA+SDF ($\\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint.\n\n\\begin{table}[t]\n\\centering\n\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \\approx 0.039$, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\n\\label{tab:avoidance_source}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nMethod & Seeds & TSR (\\%) & CAR (\\%) & EE Disp (m) \\\\\n\\midrule\nPi0.5 baseline & 3 & 74.7\\,$\\pm$\\,1.5 & 26.8\\,$\\pm$\\,1.6 & 0.367 \\\\\n\\midrule\nLoRA-only (no SDF) & 3 & 49.7\\,$\\pm$\\,3.2 & 54.83\\,$\\pm$\\,2.25 & 0.391 \\\\\nLoRA+SDF $\\lambda{=}0.005$ & 3 & 54.0\\,$\\pm$\\,3.0 & 54.5\\,$\\pm$\\,2.29 & 0.387 \\\\\nLoRA+SDF $\\lambda{=}0.01$ & 3 & 53.8\\,$\\pm$\\,1.5 & 56.33\\,$\\pm$\\,1.61 & 0.389 \\\\\nLoRA+SDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 2 & 48.0\\,$\\pm$\\,1.4 & 58.25\\,$\\pm$\\,0.35 & 0.394 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}30K checkpoint, two of three seeds; third seed in progress.}\n\\end{table}\n\nTable~\\ref{tab:avoidance_source} shows that collision-free demonstrations alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes and displacement above 0.37\\,m, which confirms genuine avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only CAR (54.83\\%) is within 0.33\\,pp of $\\lambda = 0.005$ and statistically indistinguishable from $\\lambda = 0.01$ (56.33\\%, $p > 0.1$; Appendix~\\ref{sec:appendix_null}). A Phase~2 ablation ($\\lambda = 0$ after step 5K) yields CAR\\,=\\,57.5\\%\\footnote{Single seed (s2); computational constraints precluded additional seeds for this ablation.}; SDF gradients produce no lasting behavioral effect. The per-task CAR ordering is preserved across all conditions (chocolate\\_pudding highest, bbq\\_sauce lowest) and invariant to $\\lambda$ across a 20$\\times$ range; avoidance patterns reflect the demonstration distribution rather than geometric supervision.\n\n\\paragraph{CAR--TSR trade-off.}\\label{sec:tsr_collapse}\nFine-tuning degrades TSR by ${\\sim}$21--25\\,pp (74.7\\% $\\to$ 49.7--54.0\\%), a consequence of distributional shift from the pre-trained prior rather than learned paralysis (all models retain $>$\\,0.37\\,m displacement and 0\\% frozen episodes). The SSR/TSR ratio increases from 0.33 (baseline) to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}): among task-completing episodes, a larger fraction avoids collisions after fine-tuning.\n\n\\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}\nIncreasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, $p \\approx 0.039$). This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\linewidth]{fig5_lambda_curve}\n\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}\n\\label{fig:lambda_car}\n\\end{figure}",
      "numLines": 40,
      "startLine": 1,
      "totalLines": 40
    }
  }
}
```

</details>

---

### Tool call

_source line 43_

<details open><summary>🔧 Tool call — Read · `toolu_01A3bVBk67PM6GSDEMcfRVps`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "3cea310e-1951-4088-a39b-c0c2a28e036a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mEuXqtaDwTrtipbos8eVv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1186,
      "cache_read_input_tokens": 27289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1186
      },
      "output_tokens": 19,
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

_source line 44 · 2026-05-27T20:35:58.285Z_

<details><summary>↩ Tool result · `toolu_01A3bVBk67PM6GSDEMcfRVps`</summary>

```text
1	\section{Experimental Setup and Metrics}\label{sec:method}
2	
3	\subsection{Benchmark and Models}\label{sec:benchmark}
4	
5	We evaluate on SafeLIBERO~\cite{hu2025vlsa}, the \textit{object\_pudding} suite (Level~I): four tabletop pick-and-place tasks with collision hazards and per-timestep collision detection. Two VLA families are tested: \textbf{Pi0} (${\sim}$2.5B)~\cite{black2024pi0} with flow matching~\cite{lipman2023flow}, and \textbf{Pi0.5} with broader pre-training. Table~\ref{tab:configurations} lists all configurations. Each uses 50 episodes per task (200 total); Pi0.5 multi-seed runs use 3 seeds (600 episodes). We report Collision Avoidance Rate (CAR), the fraction of collision-free episodes, and Task Success Rate (TSR), the fraction of episodes that complete the task~\cite{hu2025vlsa,zhang2025safevla}.
6	
7	\begin{table}[t]
8	\centering
9	\caption{Training configurations. Trainable parameters exclude the frozen backbone.}
10	\label{tab:configurations}
11	\vspace{2pt}
12	\small
13	\begin{tabular}{llr}
14	\toprule
15	Configuration & Description & Trainable Params \\
16	\midrule
17	Pi0 Full-FT & Full fine-tune, flow-matching loss & ${\sim}$2.5B \\
18	Pi0 LoRA & LoRA adapters only & ${\sim}$33.5M \\
19	Pi0+A1 (SDF aux)\textsuperscript{$\dagger$} & LoRA + SDF decoder + EE extractor & ${\sim}$658K \\
20	Pi0+A3 (learned SDF) & LoRA + SDF decoder w/ gradient refinement & ${\sim}$34.2M \\
21	Pi0.5 (pre-trained) & No fine-tuning & 0 \\
22	Pi0.5 LoRA & LoRA fine-tune on Pi0.5 & ${\sim}$33.5M \\
23	Pi0.5+A1 (SDF aux) & LoRA + SDF aux on Pi0.5, $\lambda \in \{0.005, 0.01, 0.1\}$ & ${\sim}$34.2M \\
24	\bottomrule
25	\end{tabular}
26	\vspace{2pt}
27	\raggedright\footnotesize\textsuperscript{$\dagger$}LoRA weights not loaded due to parameter-name mismatch; only auxiliary heads trained.
28	\end{table}
29	
30	\subsection{Displacement-Filtered CAR}\label{sec:dfcar}
31	
32	Standard CAR conflates genuine avoidance with action collapse. We define an episode as \emph{action-collapsed} when $d_{\max}(e) < \tau_d$ ($\tau_d = 0.1$\,mm) and exclude such episodes:
33	\begin{equation}\label{eq:car_f}
34	\text{dfCAR} = \frac{|\{e : \text{safe}(e) \;\land\; d_{\max}(e) \geq \tau_d\}|}{|\{e : d_{\max}(e) \geq \tau_d\}|}
35	\end{equation}
36	The displacement distribution is sharply bimodal, with collapsed episodes below 1\,$\mu$m and active episodes above 200\,mm; any $\tau_d \in [2, 200]$\,mm yields identical results (Appendix~\ref{sec:appendix_threshold}).\footnote{See Section~\ref{sec:fake_safety} for details on the displacement measurement protocol.}
37	
38	\subsection{SDF Auxiliary Training and Oracle Refinement}\label{sec:sdf_aux}
39	
40	We augment LoRA-adapted~\cite{hu2022lora} VLAs with an SDF decoder and an EE position extractor (Appendix~\ref{sec:appendix_training}, Table~\ref{tab:hyperparams}). The total loss is:
41	\begin{equation}\label{eq:total_loss}
42	\mathcal{L}_\text{total} = \mathcal{L}_\text{action} + \lambda \left( \mathcal{L}_\text{SDF} + \mathcal{L}_\text{EE} \right)
43	\end{equation}
44	where $\lambda \in \{0.005, 0.01, 0.1\}$. In Pi0+A1, a parameter-name mismatch prevented LoRA loading and caused action collapse (TSR\,=\,0\%; Table~\ref{tab:configurations}). To test the upper bound of EE-only refinement (Section~\ref{sec:ee_only}), we also replace the learned SDF with ground-truth distance fields from the simulation geometry in three oracle variants (Appendix~\ref{sec:appendix_oracle}).\label{sec:oracle_setup}
45	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "e530e56e-1c87-41bd-87e4-8706592cdf7c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/method.tex",
      "content": "\\section{Experimental Setup and Metrics}\\label{sec:method}\n\n\\subsection{Benchmark and Models}\\label{sec:benchmark}\n\nWe evaluate on SafeLIBERO~\\cite{hu2025vlsa}, the \\textit{object\\_pudding} suite (Level~I): four tabletop pick-and-place tasks with collision hazards and per-timestep collision detection. Two VLA families are tested: \\textbf{Pi0} (${\\sim}$2.5B)~\\cite{black2024pi0} with flow matching~\\cite{lipman2023flow}, and \\textbf{Pi0.5} with broader pre-training. Table~\\ref{tab:configurations} lists all configurations. Each uses 50 episodes per task (200 total); Pi0.5 multi-seed runs use 3 seeds (600 episodes). We report Collision Avoidance Rate (CAR), the fraction of collision-free episodes, and Task Success Rate (TSR), the fraction of episodes that complete the task~\\cite{hu2025vlsa,zhang2025safevla}.\n\n\\begin{table}[t]\n\\centering\n\\caption{Training configurations. Trainable parameters exclude the frozen backbone.}\n\\label{tab:configurations}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{llr}\n\\toprule\nConfiguration & Description & Trainable Params \\\\\n\\midrule\nPi0 Full-FT & Full fine-tune, flow-matching loss & ${\\sim}$2.5B \\\\\nPi0 LoRA & LoRA adapters only & ${\\sim}$33.5M \\\\\nPi0+A1 (SDF aux)\\textsuperscript{$\\dagger$} & LoRA + SDF decoder + EE extractor & ${\\sim}$658K \\\\\nPi0+A3 (learned SDF) & LoRA + SDF decoder w/ gradient refinement & ${\\sim}$34.2M \\\\\nPi0.5 (pre-trained) & No fine-tuning & 0 \\\\\nPi0.5 LoRA & LoRA fine-tune on Pi0.5 & ${\\sim}$33.5M \\\\\nPi0.5+A1 (SDF aux) & LoRA + SDF aux on Pi0.5, $\\lambda \\in \\{0.005, 0.01, 0.1\\}$ & ${\\sim}$34.2M \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{2pt}\n\\raggedright\\footnotesize\\textsuperscript{$\\dagger$}LoRA weights not loaded due to parameter-name mismatch; only auxiliary heads trained.\n\\end{table}\n\n\\subsection{Displacement-Filtered CAR}\\label{sec:dfcar}\n\nStandard CAR conflates genuine avoidance with action collapse. We define an episode as \\emph{action-collapsed} when $d_{\\max}(e) < \\tau_d$ ($\\tau_d = 0.1$\\,mm) and exclude such episodes:\n\\begin{equation}\\label{eq:car_f}\n\\text{dfCAR} = \\frac{|\\{e : \\text{safe}(e) \\;\\land\\; d_{\\max}(e) \\geq \\tau_d\\}|}{|\\{e : d_{\\max}(e) \\geq \\tau_d\\}|}\n\\end{equation}\nThe displacement distribution is sharply bimodal, with collapsed episodes below 1\\,$\\mu$m and active episodes above 200\\,mm; any $\\tau_d \\in [2, 200]$\\,mm yields identical results (Appendix~\\ref{sec:appendix_threshold}).\\footnote{See Section~\\ref{sec:fake_safety} for details on the displacement measurement protocol.}\n\n\\subsection{SDF Auxiliary Training and Oracle Refinement}\\label{sec:sdf_aux}\n\nWe augment LoRA-adapted~\\cite{hu2022lora} VLAs with an SDF decoder and an EE position extractor (Appendix~\\ref{sec:appendix_training}, Table~\\ref{tab:hyperparams}). The total loss is:\n\\begin{equation}\\label{eq:total_loss}\n\\mathcal{L}_\\text{total} = \\mathcal{L}_\\text{action} + \\lambda \\left( \\mathcal{L}_\\text{SDF} + \\mathcal{L}_\\text{EE} \\right)\n\\end{equation}\nwhere $\\lambda \\in \\{0.005, 0.01, 0.1\\}$. In Pi0+A1, a parameter-name mismatch prevented LoRA loading and caused action collapse (TSR\\,=\\,0\\%; Table~\\ref{tab:configurations}). To test the upper bound of EE-only refinement (Section~\\ref{sec:ee_only}), we also replace the learned SDF with ground-truth distance fields from the simulation geometry in three oracle variants (Appendix~\\ref{sec:appendix_oracle}).\\label{sec:oracle_setup}\n",
      "numLines": 45,
      "startLine": 1,
      "totalLines": 45
    }
  }
}
```

</details>

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Read · `toolu_01LtdDCyqzzAcPq1LuYZU8wo`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "775c715d-8d53-41fd-b0cc-5bb76fe3757e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mEuXqtaDwTrtipbos8eVv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1186,
      "cache_read_input_tokens": 27289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1186
      },
      "output_tokens": 19,
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

_source line 46 · 2026-05-27T20:35:58.759Z_

<details><summary>↩ Tool result · `toolu_01LtdDCyqzzAcPq1LuYZU8wo`</summary>

```text
1	\section{Displacement Distribution}
2	\label{sec:appendix_displacement}
3	
4	\begin{figure}[h]
5	\centering
6	\includegraphics[width=\linewidth]{fig2_ee_displacement_distribution}
7	\caption{Displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\,$\mu$m, while Pi0.5 episodes (orange) exceed 200\,mm. The five-order-of-magnitude gap makes $\tau_d$ robust to any value in $[2, 200]$\,mm.}
8	\label{fig:displacement}
9	\end{figure}
10	
11	\section{Displacement Threshold Sensitivity Analysis}
12	\label{sec:appendix_threshold}
13	
14	To validate the robustness of our displacement threshold $\tau_d$, we evaluate the frozen rate across four orders of magnitude. Table~\ref{tab:threshold_sensitivity} shows that the fake safety pattern persists across all reasonable threshold choices: A1-LoRA exhibits near-total action collapse regardless of threshold, while Pi0.5+A1 maintains 0\% frozen rate even at the most conservative setting.
15	
16	\begin{table}[h]
17	\centering
18	\caption{Frozen rate (\% of episodes with $d_\mathrm{max} < \tau_d$) across threshold values.}
19	\label{tab:threshold_sensitivity}
20	\begin{tabular}{lccc}
21	\toprule
22	$\tau_d$ & A1-LoRA (Pi0) & Pi0.5 Baseline & Pi0.5+A1 (SDF aux) \\
23	\midrule
24	0.001 mm (1\,$\mu$m) & 73.9 & 0.0 & 0.0 \\
25	0.1 mm  & 99.6 & 0.0 & 0.0 \\
26	1.0 mm  & 100.0 & 0.0 & 0.0 \\
27	10 mm   & 100.0 & 0.0 & 0.0 \\
28	\bottomrule
29	\end{tabular}
30	\end{table}
31	
32	The choice of $\tau_d = 0.1$\,mm represents a conservative threshold: displacement below this value is physically negligible in manipulation tasks where typical action magnitudes are 1--10\,mm per step. Even at $\tau_d = 1$\,$\mu$m, 73.9\% of A1-LoRA safe episodes are classified as frozen, while all Pi0.5 episodes remain above threshold at every level tested.
33	
34	Table~\ref{tab:dfcar_threshold} extends this analysis to dfCAR across fine-tuned Pi0.5 configurations. All eight model-seed combinations yield identical dfCAR for $\tau_d \in [2, 200]$\,mm. At $\tau_d = 300$\,mm, 0--2 episodes per seed fall below threshold (displacement 200--300\,mm), causing $\leq$0.5\,pp deviation. Our conclusions hold across the entire tested range.
35	
36	\begin{table}[h]
37	\centering
38	\caption{dfCAR (\%) across displacement thresholds for fine-tuned Pi0.5 configurations ($n = 200$ episodes per seed). Values are identical across $\tau_d \in [2, 200]$\,mm; at $\tau_d = 300$\,mm, at most 2 episodes are excluded.}
39	\label{tab:dfcar_threshold}
40	\vspace{2pt}
41	\footnotesize
42	\begin{tabular}{lcccccccc}
43	\toprule
44	& \multicolumn{8}{c}{$\tau_d$ (mm)} \\
45	\cmidrule(lr){2-9}
46	Condition & 2 & 5 & 10 & 20 & 50 & 100 & 200 & 300 \\
47	\midrule
48	LoRA s0            & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\
49	LoRA s1            & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 \\
50	SDF $\lambda{=}0.005$ s0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.1 \\
51	SDF $\lambda{=}0.005$ s1 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 \\
52	SDF $\lambda{=}0.005$ s2 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.3 \\
53	SDF $\lambda{=}0.01$ s0  & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\
54	SDF $\lambda{=}0.01$ s1  & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.1 \\
55	SDF $\lambda{=}0.01$ s2  & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.0 \\
56	\bottomrule
57	\end{tabular}
58	\end{table}
59	
60	
61	\section{Per-Task TSR Breakdown}\label{sec:appendix_tsr_pertask}
62	
63	Table~\ref{tab:per_task_tsr} decomposes TSR by task for the avoidance source attribution experiments (Section~\ref{sec:avoidance_source}). All tasks retain meaningful success rates after fine-tuning, with Chocolate Pudding most resilient and Orange Juice most affected.
64	
65	\begin{table}[h]
66	\centering
67	\caption{Per-task TSR (\%) at 30K training steps. LoRA-only reports seed~0 (rotation-fixed re-evaluation); SDF conditions report 3-seed means.}
68	\label{tab:per_task_tsr}
69	\vspace{2pt}
70	\small
71	\begin{tabular}{lcccc}
72	\toprule
73	Task & Pi0.5 Base & LoRA-only\textsuperscript{$\dagger$} & SDF $\lambda{=}0.005$ & SDF $\lambda{=}0.01$ \\
74	 & (3 seeds) & (seed 0) & (3 seeds) & (3 seeds) \\
75	\midrule
76	Orange Juice      & 70.7 & 18.0 & 33.3 & 24.7 \\
77	Choco.\ Pudding   & 86.0 & 72.0 & 78.0 & 76.7 \\
78	Milk              & 66.0 & 32.0 & 35.3 & 48.7 \\
79	BBQ Sauce         & 76.0 & 62.0 & 69.3 & 65.3 \\
80	\midrule
81	Mean              & 74.7 & 46.0 & 54.0 & 53.8 \\
82	\bottomrule
83	\end{tabular}
84	\vspace{1pt}
85	{\footnotesize \textsuperscript{$\dagger$}Rotation-fixed re-evaluation; seed-1 evaluated with original rotation protocol, excluded to avoid mixing evaluation conditions.}
86	\end{table}
87	
88	\section{Per-Task CAR Breakdown}\label{sec:appendix_pertask_car}
89	
90	Table~\ref{tab:per_task_car} decomposes CAR by task for all fine-tuned conditions, supporting the claim that per-task ordering is preserved across SDF loss weights (\S\ref{sec:avoidance_source}). Chocolate Pudding is consistently highest and BBQ Sauce consistently lowest across all conditions, including $\lambda = 0.1$. The intermediate tasks (Orange Juice and Milk) exchange rank between seeds but remain bounded by the extremes. This invariance indicates that avoidance patterns reflect the spatial statistics of collision-free demonstrations rather than geometric supervision.
91	
92	\begin{table}[h]
93	\centering
94	\caption{Per-task CAR (\%) at 30K steps. $\lambda{=}0.005$ and $\lambda{=}0.01$ report 3-seed means. Per-task ordering (CP highest, BBQ lowest) is preserved across all conditions.}
95	\label{tab:per_task_car}
96	\vspace{2pt}
97	\small
98	\begin{tabular}{lccccc}
99	\toprule
100	Condition & OJ & CP & Milk & BBQ & Agg. \\
101	\midrule
102	LoRA s0 & 68 & 74 & 66 & 20 & 57.0 \\
103	LoRA s1 & 54 & 68 & 72 & 16 & 52.5 \\
104	LoRA s2 & 56 & 76 & 62 & 26 & 55.0 \\
105	SDF $\lambda{=}0.005$ (3-seed) & 54.0 & 72.7 & 71.3 & 20.0 & 54.5 \\
106	SDF $\lambda{=}0.01$ (3-seed) & 57.3 & 72.7 & 72.0 & 23.3 & 56.3 \\
107	SDF $\lambda{=}0.1$ s0 & 60 & 74 & 68 & 30 & 58.0 \\
108	SDF $\lambda{=}0.1$ s1 & 66 & 72 & 70 & 26 & 58.5 \\
109	\bottomrule
110	\end{tabular}
111	\end{table}
112	
113	For the $\lambda = 0.1$ condition, seed~1 records avg\_max\_obstacle\_displacement of 0.0553\,m (per-task: OJ\,=\,0.033, CP\,=\,0.055, Milk\,=\,0.041, BBQ\,=\,0.093), comparable to other fine-tuned conditions and consistent with active manipulation rather than frozen behavior.
114	
115	\section{Safe Success Rate Analysis}\label{sec:appendix_ssr}
116	
117	Table~\ref{tab:ssr} reports the Safe Success Rate (SSR\,=\,TSR\,$\cap$\,CAR), the fraction of episodes achieving both task completion and collision avoidance. The SSR/TSR ratio quantifies the proportion of successful episodes that are also collision-free, controlling for task-completion rate.
118	
119	\begin{table}[h]
120	\centering
121	\caption{SSR and SSR/TSR ratio across conditions. The ratio increase from 0.33 (baseline) to 0.51--0.57 (fine-tuned) indicates that CAR gains reflect learned safer execution, not reduced task exposure.}
122	\label{tab:ssr}
123	\vspace{2pt}
124	\small
125	\begin{tabular}{lcccc}
126	\toprule
127	Condition & TSR (\%) & CAR (\%) & SSR (\%) & SSR/TSR \\
128	\midrule
129	Pi0.5 baseline & 74.7 & 26.8 & 25.0\textsuperscript{a} & 0.33 \\
130	LoRA-only (3 seeds) & 49.7 & 54.83 & 28.3 & 0.57 \\
131	SDF $\lambda{=}0.005$ (3 seeds) & 54.0 & 54.5 & 27.8 & 0.51 \\
132	SDF $\lambda{=}0.01$ (3 seeds) & 53.8 & 56.33 & 30.2 & 0.56 \\
133	SDF $\lambda{=}0.1$\textsuperscript{$\dagger$} & 48.0 & 58.25 & 26.5 & 0.55 \\
134	\bottomrule
135	\end{tabular}
136	\vspace{1pt}
137	{\footnotesize \textsuperscript{a}Estimated; per-episode overlap unavailable for 3-seed rotation-corrected protocol. \textsuperscript{$\dagger$}SSR from seed~1 only; seed~0 per-episode data overwritten.}
138	\end{table}
139	
140	\section{Per-Task Oracle Analysis}
141	\label{sec:appendix_pertask}
142	\label{sec:appendix_pertask_oracle}
143	
144	Table~\ref{tab:oracle_pertask} shows per-task CAR for oracle refinement. On task~1 (\texttt{chocolate\_pudding}), where the EE is the primary collision body and the LoRA baseline achieves only 46.0\% CAR, Oracle-adaptive improves to 55.0\% and Oracle-feature to 47.5\%. On the remaining tasks, all oracle variants degrade: Oracle-adaptive reduces task~0 (\texttt{orange\_juice}) from 96.0\% to 82.5\% and task~2 (\texttt{milk}) from 98.0\% to 77.5\%. The SDF gradient pushes the EE away from the nearest surface, but the resulting joint-space displacement rotates intermediate arm links into obstacle volumes.
145	
146	The feature-space oracle fires on nearly every timestep (241.7 refinements/episode vs.\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\ 0.18--0.49), and CAR (76.9\%) shows no advantage despite 17$\times$ more steps. The A3 learned SDF never triggers refinement (0 steps/episode), as its outputs avoid the activation threshold.
147	
148	\begin{table}[h]
149	\centering
150	\caption{Per-task CAR (\%) for oracle SDF refinement variants. EE-only refinement helps only on task~1 where the EE is the primary collision body; on other tasks it trades one collision site for another.}
151	\label{tab:oracle_pertask}
152	\vspace{2pt}
153	\small
154	\begin{tabular}{lccccc}
155	\toprule
156	Method & Task 0 & Task 1 & Task 2 & Task 3 & Agg. \\
157	\midrule
158	LoRA baseline & 96.0 & 46.0 & 98.0 & 88.0 & 82.0 \\
159	\midrule
160	Oracle-adaptive & 82.5 & 55.0 & 77.5 & 85.0 & 75.0 \\
161	Oracle-fixed & 85.0 & 50.0 & 77.5 & 80.0 & 73.1 \\
162	Oracle-feature & 90.0 & 47.5 & 82.5 & 87.5 & 76.9 \\
163	\bottomrule
164	\end{tabular}
165	\end{table}
166	
167	
168	\section{Null Distribution for SDF Loss Weight Analysis}
169	\label{sec:appendix_null}
170	
171	We construct a null distribution by pooling the three LoRA-only seeds and three $\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\% (LoRA s0, re-evaluated), 52.5\% (LoRA s1), 55.0\% (LoRA s2), 57.0\% ($\lambda{=}0.005$ s0), 54.0\% ($\lambda{=}0.005$ s1), 52.5\% ($\lambda{=}0.005$ s2), yielding mean 54.67\% and standard deviation 2.04\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\lambda = 0.005$ produces no separation from LoRA-only. The $\lambda = 0.01$ mean of 56.33\% falls within $0.8\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\lambda = 0.1$ 30K mean of 58.25\% (2 seeds) yields $z = 1.76$ ($p \approx 0.039$, approximate $z$-test), a marginal departure whose interpretation is limited by $n = 2$.
172	
173	As a robustness check, we verify the $\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions. Pooling the six null values $\{57, 52.5, 55, 57, 54, 52.5\}$ and two $\lambda = 0.1$ values $\{58, 58.5\}$ into eight measurements, we enumerate all $\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\geq 58.25$. Only one combination ($\{58, 58.5\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \approx 0.036$ (two-tailed $p = 2/28 \approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.
174	
175	A Phase~2 ablation reinforces this conclusion. Setting $\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.
176	
177	\section{Step-wise Checkpoint Analysis for \texorpdfstring{$\lambda = 0.1$}{lambda = 0.1}}
178	\label{sec:appendix_stepwise}
179	
180	Table~\ref{tab:stepwise_lambda01} reports per-seed CAR at seven checkpoints for $\lambda = 0.1$. Seed-1 data is available at 16K, 20K, 22K, and 30K; 24K--28K report seed-0 only. The seed-0 curve shows no monotonic trend through 28K; the 30K checkpoint marks the first consistent dual-seed departure from the null band, though whether this reflects a genuine late-training effect or sampling variance at $n = 2$ remains open.
181	
182	\begin{table}[h]
183	\centering
184	\caption{Per-seed CAR (\%) at training checkpoints for $\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\%\,$\pm$\,2.04\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \approx 0.039$).}
185	\label{tab:stepwise_lambda01}
186	\vspace{2pt}
187	\small
188	\begin{tabular}{lccc}
189	\toprule
190	Checkpoint & Seed 0 & Seed 1 & Mean \\
191	\midrule
192	16K steps & 55.5 & 56.0 & 55.75 \\
193	20K steps & 55.0 & 56.0 & 55.5 \\
194	22K steps & 60.5 & 56.5 & 58.5 \\
195	24K steps & 52.5 & -- & -- \\
196	26K steps & 53.5 & -- & -- \\
197	28K steps & 54.5 & -- & -- \\
198	30K steps & 58.0 & 58.5 & 58.25 \\
199	\bottomrule
200	\end{tabular}
201	\end{table}
202	
203	Individual seeds exhibit checkpoint-to-checkpoint CAR fluctuations of up to 8\,pp (seed~0: 52.5--60.5\%), larger than the cross-seed standard deviation at any fixed checkpoint ($\leq$2.8\,pp). This is consistent with binomial sampling noise at $n = 50$ episodes per task ($\sigma \approx 7$\,pp per task for $p \approx 0.5$). The seed-averaged curve shows no monotonic trend, confirming that SDF loss weight does not produce a progressive training signal.
204	
205	
206	\section{Oracle SDF Refinement Details}
207	\label{sec:appendix_oracle}
208	
209	All oracle variants replace the learned SDF decoder with ground-truth distance fields computed from the simulation geometry. Each is evaluated for 160 episodes (4 tasks $\times$ 40).
210	
211	\paragraph{Oracle-adaptive.} At each timestep, if the ground-truth SDF at the end-effector position falls below a safety margin, the action is adjusted by a step in the negative SDF gradient direction. The step size $\alpha$ is scaled inversely with distance: smaller distances produce larger corrections. This mimics an adaptive potential field controller.
212	
213	\paragraph{Oracle-fixed.} Identical to Oracle-adaptive except the step size is fixed at $\alpha = 0.005$ regardless of distance. This isolates the effect of step-size adaptation from the refinement geometry.
214	
215	\paragraph{Oracle-feature.} Instead of modifying the action directly in Cartesian space, this variant applies the SDF gradient in the policy's latent feature space via backpropagation. The gradient of the ground-truth SDF value with respect to the intermediate features is computed and used to perturb the features before the action head decodes them. This tests whether geometric corrections are more effective when applied in the model's learned representation space. In practice, the feature-space variant fires on nearly every timestep (241.7 refinements per episode vs.\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\ 0.18--0.49 in action space).
216	
217	
218	\section{Training Details}
219	\label{sec:appendix_training}
220	
221	\paragraph{Architecture.}
222	We use LoRA~\citep{hu2022lora} adapters injected into the PaliGemma vision encoder (rank 16, $\alpha$=16) and the action expert (rank 32, $\alpha$=32), following the configuration of OpenPi. The SDF decoder is a 4-layer MLP (hidden dimension 256) with skip connections, taking pooled suffix features (1024-d) and query points (3-d) as input. The end-effector extractor is a 2-layer MLP (1024 $\to$ 256 $\to$ 3).
223	
224	\paragraph{Training schedule.}
225	Training proceeds in two phases:
226	\begin{itemize}
227	    \item \textbf{Phase 1} (steps 0--5000): Backbone and LoRA parameters are frozen. Only the SDF decoder and EE extractor are trained, allowing them to learn meaningful representations before the policy adapts.
228	    \item \textbf{Phase 2} (steps 5000--30000): LoRA parameters are unfrozen with a 100-step gradient warmup ramp. All auxiliary heads continue training jointly with the policy.
229	\end{itemize}
230	
231	\paragraph{Hyperparameters.}
232	\begin{table}[h]
233	\centering
234	\caption{Training hyperparameters.}
235	\label{tab:hyperparams}
236	\begin{tabular}{ll}
237	\toprule
238	Parameter & Value \\
239	\midrule
240	Base model & Pi0.5 (OpenPi, $\sim$3.5B parameters) \\
241	Optimizer & AdamW \\
242	Learning rate & $2.5 \times 10^{-5}$ (cosine decay to $\mathrm{lr}/10$) \\
243	Warmup steps & 1000 \\
244	Batch size & 32 \\
245	Total steps & 30000 \\
246	$\lambda_\mathrm{sdf}$ & \{0.005, 0.01, 0.1\} \\
247	$\lambda_\mathrm{ee}$ & 0.01 \\
248	SDF query points per step & 64 \\
249	SDF clamp $\delta$ & 0.05 m \\
250	Eikonal weight & 0.1 \\
251	LoRA rank (vision) & 16 \\
252	LoRA rank (action) & 32 \\
253	Phase 1 duration & 5000 steps \\
254	\bottomrule
255	\end{tabular}
256	\end{table}
257	
258	\paragraph{Evaluation protocol.}
259	Each episode runs for at most 300 timesteps. The policy generates a 50-step action trajectory via flow matching and executes the first 5 steps before replanning. An episode terminates early upon task completion. Collision detection uses MuJoCo's built-in contact detection: any contact between the robot and a non-target object registers as a collision. For Pi0.5 evaluations, camera images are rotated 180$^\circ$ to match the pre-training viewpoint convention; this correction was verified to restore TSR from ${\sim}$5\% to ${\sim}$52\% while leaving CAR comparable. Oracle variants use 40 episodes per task (160 total) with a single seed; all other configurations use 50 episodes per task (200 total).
260	
261	\paragraph{Data.}
262	We use the SafeLIBERO object\_pudding suite with pre-computed SDF ground truth. SDF values are computed offline from the obstacle mesh using a dense $64^3$ voxel grid. During training, 64 query points are randomly sampled per step from this grid.
263	
264	\paragraph{Computational resources.}
265	All training and evaluation experiments are conducted on NVIDIA RTX PRO 6000 GPUs (96\,GB). Phase~1 (5K steps) takes approximately 6 hours on a single GPU; Phase~2 (25K steps) takes approximately 32 hours. Evaluation of 200 episodes requires approximately 4 hours. Across 100+ experiments (training runs, evaluations, oracle variants, and ablations), the total computational budget is approximately 700 GPU-hours.
266	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "0257a75d-b9e2-457d-a4a0-f67b8da79f56",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
      "content": "\\section{Displacement Distribution}\n\\label{sec:appendix_displacement}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{fig2_ee_displacement_distribution}\n\\caption{Displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap makes $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\section{Displacement Threshold Sensitivity Analysis}\n\\label{sec:appendix_threshold}\n\nTo validate the robustness of our displacement threshold $\\tau_d$, we evaluate the frozen rate across four orders of magnitude. Table~\\ref{tab:threshold_sensitivity} shows that the fake safety pattern persists across all reasonable threshold choices: A1-LoRA exhibits near-total action collapse regardless of threshold, while Pi0.5+A1 maintains 0\\% frozen rate even at the most conservative setting.\n\n\\begin{table}[h]\n\\centering\n\\caption{Frozen rate (\\% of episodes with $d_\\mathrm{max} < \\tau_d$) across threshold values.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{lccc}\n\\toprule\n$\\tau_d$ & A1-LoRA (Pi0) & Pi0.5 Baseline & Pi0.5+A1 (SDF aux) \\\\\n\\midrule\n0.001 mm (1\\,$\\mu$m) & 73.9 & 0.0 & 0.0 \\\\\n0.1 mm  & 99.6 & 0.0 & 0.0 \\\\\n1.0 mm  & 100.0 & 0.0 & 0.0 \\\\\n10 mm   & 100.0 & 0.0 & 0.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe choice of $\\tau_d = 0.1$\\,mm represents a conservative threshold: displacement below this value is physically negligible in manipulation tasks where typical action magnitudes are 1--10\\,mm per step. Even at $\\tau_d = 1$\\,$\\mu$m, 73.9\\% of A1-LoRA safe episodes are classified as frozen, while all Pi0.5 episodes remain above threshold at every level tested.\n\nTable~\\ref{tab:dfcar_threshold} extends this analysis to dfCAR across fine-tuned Pi0.5 configurations. All eight model-seed combinations yield identical dfCAR for $\\tau_d \\in [2, 200]$\\,mm. At $\\tau_d = 300$\\,mm, 0--2 episodes per seed fall below threshold (displacement 200--300\\,mm), causing $\\leq$0.5\\,pp deviation. Our conclusions hold across the entire tested range.\n\n\\begin{table}[h]\n\\centering\n\\caption{dfCAR (\\%) across displacement thresholds for fine-tuned Pi0.5 configurations ($n = 200$ episodes per seed). Values are identical across $\\tau_d \\in [2, 200]$\\,mm; at $\\tau_d = 300$\\,mm, at most 2 episodes are excluded.}\n\\label{tab:dfcar_threshold}\n\\vspace{2pt}\n\\footnotesize\n\\begin{tabular}{lcccccccc}\n\\toprule\n& \\multicolumn{8}{c}{$\\tau_d$ (mm)} \\\\\n\\cmidrule(lr){2-9}\nCondition & 2 & 5 & 10 & 20 & 50 & 100 & 200 & 300 \\\\\n\\midrule\nLoRA s0            & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nLoRA s1            & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 \\\\\nSDF $\\lambda{=}0.005$ s0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.1 \\\\\nSDF $\\lambda{=}0.005$ s1 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 \\\\\nSDF $\\lambda{=}0.005$ s2 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.3 \\\\\nSDF $\\lambda{=}0.01$ s0  & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nSDF $\\lambda{=}0.01$ s1  & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.1 \\\\\nSDF $\\lambda{=}0.01$ s2  & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Per-Task TSR Breakdown}\\label{sec:appendix_tsr_pertask}\n\nTable~\\ref{tab:per_task_tsr} decomposes TSR by task for the avoidance source attribution experiments (Section~\\ref{sec:avoidance_source}). All tasks retain meaningful success rates after fine-tuning, with Chocolate Pudding most resilient and Orange Juice most affected.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task TSR (\\%) at 30K training steps. LoRA-only reports seed~0 (rotation-fixed re-evaluation); SDF conditions report 3-seed means.}\n\\label{tab:per_task_tsr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTask & Pi0.5 Base & LoRA-only\\textsuperscript{$\\dagger$} & SDF $\\lambda{=}0.005$ & SDF $\\lambda{=}0.01$ \\\\\n & (3 seeds) & (seed 0) & (3 seeds) & (3 seeds) \\\\\n\\midrule\nOrange Juice      & 70.7 & 18.0 & 33.3 & 24.7 \\\\\nChoco.\\ Pudding   & 86.0 & 72.0 & 78.0 & 76.7 \\\\\nMilk              & 66.0 & 32.0 & 35.3 & 48.7 \\\\\nBBQ Sauce         & 76.0 & 62.0 & 69.3 & 65.3 \\\\\n\\midrule\nMean              & 74.7 & 46.0 & 54.0 & 53.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}Rotation-fixed re-evaluation; seed-1 evaluated with original rotation protocol, excluded to avoid mixing evaluation conditions.}\n\\end{table}\n\n\\section{Per-Task CAR Breakdown}\\label{sec:appendix_pertask_car}\n\nTable~\\ref{tab:per_task_car} decomposes CAR by task for all fine-tuned conditions, supporting the claim that per-task ordering is preserved across SDF loss weights (\\S\\ref{sec:avoidance_source}). Chocolate Pudding is consistently highest and BBQ Sauce consistently lowest across all conditions, including $\\lambda = 0.1$. The intermediate tasks (Orange Juice and Milk) exchange rank between seeds but remain bounded by the extremes. This invariance indicates that avoidance patterns reflect the spatial statistics of collision-free demonstrations rather than geometric supervision.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) at 30K steps. $\\lambda{=}0.005$ and $\\lambda{=}0.01$ report 3-seed means. Per-task ordering (CP highest, BBQ lowest) is preserved across all conditions.}\n\\label{tab:per_task_car}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nCondition & OJ & CP & Milk & BBQ & Agg. \\\\\n\\midrule\nLoRA s0 & 68 & 74 & 66 & 20 & 57.0 \\\\\nLoRA s1 & 54 & 68 & 72 & 16 & 52.5 \\\\\nLoRA s2 & 56 & 76 & 62 & 26 & 55.0 \\\\\nSDF $\\lambda{=}0.005$ (3-seed) & 54.0 & 72.7 & 71.3 & 20.0 & 54.5 \\\\\nSDF $\\lambda{=}0.01$ (3-seed) & 57.3 & 72.7 & 72.0 & 23.3 & 56.3 \\\\\nSDF $\\lambda{=}0.1$ s0 & 60 & 74 & 68 & 30 & 58.0 \\\\\nSDF $\\lambda{=}0.1$ s1 & 66 & 72 & 70 & 26 & 58.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor the $\\lambda = 0.1$ condition, seed~1 records avg\\_max\\_obstacle\\_displacement of 0.0553\\,m (per-task: OJ\\,=\\,0.033, CP\\,=\\,0.055, Milk\\,=\\,0.041, BBQ\\,=\\,0.093), comparable to other fine-tuned conditions and consistent with active manipulation rather than frozen behavior.\n\n\\section{Safe Success Rate Analysis}\\label{sec:appendix_ssr}\n\nTable~\\ref{tab:ssr} reports the Safe Success Rate (SSR\\,=\\,TSR\\,$\\cap$\\,CAR), the fraction of episodes achieving both task completion and collision avoidance. The SSR/TSR ratio quantifies the proportion of successful episodes that are also collision-free, controlling for task-completion rate.\n\n\\begin{table}[h]\n\\centering\n\\caption{SSR and SSR/TSR ratio across conditions. The ratio increase from 0.33 (baseline) to 0.51--0.57 (fine-tuned) indicates that CAR gains reflect learned safer execution, not reduced task exposure.}\n\\label{tab:ssr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nCondition & TSR (\\%) & CAR (\\%) & SSR (\\%) & SSR/TSR \\\\\n\\midrule\nPi0.5 baseline & 74.7 & 26.8 & 25.0\\textsuperscript{a} & 0.33 \\\\\nLoRA-only (3 seeds) & 49.7 & 54.83 & 28.3 & 0.57 \\\\\nSDF $\\lambda{=}0.005$ (3 seeds) & 54.0 & 54.5 & 27.8 & 0.51 \\\\\nSDF $\\lambda{=}0.01$ (3 seeds) & 53.8 & 56.33 & 30.2 & 0.56 \\\\\nSDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 48.0 & 58.25 & 26.5 & 0.55 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{a}Estimated; per-episode overlap unavailable for 3-seed rotation-corrected protocol. \\textsuperscript{$\\dagger$}SSR from seed~1 only; seed~0 per-episode data overwritten.}\n\\end{table}\n\n\\section{Per-Task Oracle Analysis}\n\\label{sec:appendix_pertask}\n\\label{sec:appendix_pertask_oracle}\n\nTable~\\ref{tab:oracle_pertask} shows per-task CAR for oracle refinement. On task~1 (\\texttt{chocolate\\_pudding}), where the EE is the primary collision body and the LoRA baseline achieves only 46.0\\% CAR, Oracle-adaptive improves to 55.0\\% and Oracle-feature to 47.5\\%. On the remaining tasks, all oracle variants degrade: Oracle-adaptive reduces task~0 (\\texttt{orange\\_juice}) from 96.0\\% to 82.5\\% and task~2 (\\texttt{milk}) from 98.0\\% to 77.5\\%. The SDF gradient pushes the EE away from the nearest surface, but the resulting joint-space displacement rotates intermediate arm links into obstacle volumes.\n\nThe feature-space oracle fires on nearly every timestep (241.7 refinements/episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49), and CAR (76.9\\%) shows no advantage despite 17$\\times$ more steps. The A3 learned SDF never triggers refinement (0 steps/episode), as its outputs avoid the activation threshold.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) for oracle SDF refinement variants. EE-only refinement helps only on task~1 where the EE is the primary collision body; on other tasks it trades one collision site for another.}\n\\label{tab:oracle_pertask}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & Task 0 & Task 1 & Task 2 & Task 3 & Agg. \\\\\n\\midrule\nLoRA baseline & 96.0 & 46.0 & 98.0 & 88.0 & 82.0 \\\\\n\\midrule\nOracle-adaptive & 82.5 & 55.0 & 77.5 & 85.0 & 75.0 \\\\\nOracle-fixed & 85.0 & 50.0 & 77.5 & 80.0 & 73.1 \\\\\nOracle-feature & 90.0 & 47.5 & 82.5 & 87.5 & 76.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Null Distribution for SDF Loss Weight Analysis}\n\\label{sec:appendix_null}\n\nWe construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields $z = 1.76$ ($p \\approx 0.039$, approximate $z$-test), a marginal departure whose interpretation is limited by $n = 2$.\n\nAs a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.\n\nA Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.\n\n\\section{Step-wise Checkpoint Analysis for \\texorpdfstring{$\\lambda = 0.1$}{lambda = 0.1}}\n\\label{sec:appendix_stepwise}\n\nTable~\\ref{tab:stepwise_lambda01} reports per-seed CAR at seven checkpoints for $\\lambda = 0.1$. Seed-1 data is available at 16K, 20K, 22K, and 30K; 24K--28K report seed-0 only. The seed-0 curve shows no monotonic trend through 28K; the 30K checkpoint marks the first consistent dual-seed departure from the null band, though whether this reflects a genuine late-training effect or sampling variance at $n = 2$ remains open.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).}\n\\label{tab:stepwise_lambda01}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nCheckpoint & Seed 0 & Seed 1 & Mean \\\\\n\\midrule\n16K steps & 55.5 & 56.0 & 55.75 \\\\\n20K steps & 55.0 & 56.0 & 55.5 \\\\\n22K steps & 60.5 & 56.5 & 58.5 \\\\\n24K steps & 52.5 & -- & -- \\\\\n26K steps & 53.5 & -- & -- \\\\\n28K steps & 54.5 & -- & -- \\\\\n30K steps & 58.0 & 58.5 & 58.25 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIndividual seeds exhibit checkpoint-to-checkpoint CAR fluctuations of up to 8\\,pp (seed~0: 52.5--60.5\\%), larger than the cross-seed standard deviation at any fixed checkpoint ($\\leq$2.8\\,pp). This is consistent with binomial sampling noise at $n = 50$ episodes per task ($\\sigma \\approx 7$\\,pp per task for $p \\approx 0.5$). The seed-averaged curve shows no monotonic trend, confirming that SDF loss weight does not produce a progressive training signal.\n\n\n\\section{Oracle SDF Refinement Details}\n\\label{sec:appendix_oracle}\n\nAll oracle variants replace the learned SDF decoder with ground-truth distance fields computed from the simulation geometry. Each is evaluated for 160 episodes (4 tasks $\\times$ 40).\n\n\\paragraph{Oracle-adaptive.} At each timestep, if the ground-truth SDF at the end-effector position falls below a safety margin, the action is adjusted by a step in the negative SDF gradient direction. The step size $\\alpha$ is scaled inversely with distance: smaller distances produce larger corrections. This mimics an adaptive potential field controller.\n\n\\paragraph{Oracle-fixed.} Identical to Oracle-adaptive except the step size is fixed at $\\alpha = 0.005$ regardless of distance. This isolates the effect of step-size adaptation from the refinement geometry.\n\n\\paragraph{Oracle-feature.} Instead of modifying the action directly in Cartesian space, this variant applies the SDF gradient in the policy's latent feature space via backpropagation. The gradient of the ground-truth SDF value with respect to the intermediate features is computed and used to perturb the features before the action head decodes them. This tests whether geometric corrections are more effective when applied in the model's learned representation space. In practice, the feature-space variant fires on nearly every timestep (241.7 refinements per episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49 in action space).\n\n\n\\section{Training Details}\n\\label{sec:appendix_training}\n\n\\paragraph{Architecture.}\nWe use LoRA~\\citep{hu2022lora} adapters injected into the PaliGemma vision encoder (rank 16, $\\alpha$=16) and the action expert (rank 32, $\\alpha$=32), following the configuration of OpenPi. The SDF decoder is a 4-layer MLP (hidden dimension 256) with skip connections, taking pooled suffix features (1024-d) and query points (3-d) as input. The end-effector extractor is a 2-layer MLP (1024 $\\to$ 256 $\\to$ 3).\n\n\\paragraph{Training schedule.}\nTraining proceeds in two phases:\n\\begin{itemize}\n    \\item \\textbf{Phase 1} (steps 0--5000): Backbone and LoRA parameters are frozen. Only the SDF decoder and EE extractor are trained, allowing them to learn meaningful representations before the policy adapts.\n    \\item \\textbf{Phase 2} (steps 5000--30000): LoRA parameters are unfrozen with a 100-step gradient warmup ramp. All auxiliary heads continue training jointly with the policy.\n\\end{itemize}\n\n\\paragraph{Hyperparameters.}\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters.}\n\\label{tab:hyperparams}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nBase model & Pi0.5 (OpenPi, $\\sim$3.5B parameters) \\\\\nOptimizer & AdamW \\\\\nLearning rate & $2.5 \\times 10^{-5}$ (cosine decay to $\\mathrm{lr}/10$) \\\\\nWarmup steps & 1000 \\\\\nBatch size & 32 \\\\\nTotal steps & 30000 \\\\\n$\\lambda_\\mathrm{sdf}$ & \\{0.005, 0.01, 0.1\\} \\\\\n$\\lambda_\\mathrm{ee}$ & 0.01 \\\\\nSDF query points per step & 64 \\\\\nSDF clamp $\\delta$ & 0.05 m \\\\\nEikonal weight & 0.1 \\\\\nLoRA rank (vision) & 16 \\\\\nLoRA rank (action) & 32 \\\\\nPhase 1 duration & 5000 steps \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Evaluation protocol.}\nEach episode runs for at most 300 timesteps. The policy generates a 50-step action trajectory via flow matching and executes the first 5 steps before replanning. An episode terminates early upon task completion. Collision detection uses MuJoCo's built-in contact detection: any contact between the robot and a non-target object registers as a collision. For Pi0.5 evaluations, camera images are rotated 180$^\\circ$ to match the pre-training viewpoint convention; this correction was verified to restore TSR from ${\\sim}$5\\% to ${\\sim}$52\\% while leaving CAR comparable. Oracle variants use 40 episodes per task (160 total) with a single seed; all other configurations use 50 episodes per task (200 total).\n\n\\paragraph{Data.}\nWe use the SafeLIBERO object\\_pudding suite with pre-computed SDF ground truth. SDF values are computed offline from the obstacle mesh using a dense $64^3$ voxel grid. During training, 64 query points are randomly sampled per step from this grid.\n\n\\paragraph{Computational resources.}\nAll training and evaluation experiments are conducted on NVIDIA RTX PRO 6000 GPUs (96\\,GB). Phase~1 (5K steps) takes approximately 6 hours on a single GPU; Phase~2 (25K steps) takes approximately 32 hours. Evaluation of 200 episodes requires approximately 4 hours. Across 100+ experiments (training runs, evaluations, oracle variants, and ablations), the total computational budget is approximately 700 GPU-hours.\n",
      "numLines": 266,
      "startLine": 1,
      "totalLines": 266
    }
  }
}
```

</details>

---

### Tool call

_source line 47_

<details open><summary>🔧 Tool call — Read · `toolu_019ZzrTvjd6ShiGjqFGjG3ng`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "5abcb488-e9b2-4edd-bc3f-902bffd7faba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mEuXqtaDwTrtipbos8eVv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1186,
      "cache_read_input_tokens": 27289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1186
      },
      "output_tokens": 19,
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

_source line 48 · 2026-05-27T20:35:59.105Z_

<details><summary>↩ Tool result · `toolu_019ZzrTvjd6ShiGjqFGjG3ng`</summary>

```text
1	\documentclass{article}
2	
3	\PassOptionsToPackage{dvipsnames}{xcolor}
4	\usepackage{corl_2026}
5	
6	\usepackage{amsmath,amssymb}
7	\usepackage{booktabs}
8	\usepackage{graphicx}
9	\usepackage{multirow}
10	\usepackage{subcaption}
11	\graphicspath{{../../artifacts/figures/}}
12	
13	\title{Rethinking VLA Safety Evaluation:\\When 98\% of Collision Avoidance is an Illusion}
14	
15	\author{
16	  Anonymous Authors
17	}
18	
19	\begin{document}
20	
21	\maketitle
22	
23	\input{abstract}
24	
25	\keywords{VLA safety, collision avoidance, action collapse, signed distance fields}
26	
27	\input{introduction}
28	
29	\input{related_work}
30	
31	\input{method}
32	
33	\input{claim1}
34	
35	\input{claim2}
36	
37	\input{claim3}
38	
39	\input{discussion}
40	
41	\bibliography{references}
42	
43	\appendix
44	\input{appendix}
45	
46	\end{document}
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "07c361f4-4da3-4d0b-8441-67ec595a4422",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/main.tex",
      "content": "\\documentclass{article}\n\n\\PassOptionsToPackage{dvipsnames}{xcolor}\n\\usepackage{corl_2026}\n\n\\usepackage{amsmath,amssymb}\n\\usepackage{booktabs}\n\\usepackage{graphicx}\n\\usepackage{multirow}\n\\usepackage{subcaption}\n\\graphicspath{{../../artifacts/figures/}}\n\n\\title{Rethinking VLA Safety Evaluation:\\\\When 98\\% of Collision Avoidance is an Illusion}\n\n\\author{\n  Anonymous Authors\n}\n\n\\begin{document}\n\n\\maketitle\n\n\\input{abstract}\n\n\\keywords{VLA safety, collision avoidance, action collapse, signed distance fields}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{method}\n\n\\input{claim1}\n\n\\input{claim2}\n\n\\input{claim3}\n\n\\input{discussion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{appendix}\n\n\\end{document}\n",
      "numLines": 47,
      "startLine": 1,
      "totalLines": 47
    }
  }
}
```

</details>

---

### Assistant

_source line 49_

<details><summary>Logged reasoning block</summary>

```text
Now let me analyze the current state of each item:

**M1. "within X pp" in claim3.tex**
Line 27: `is within 0.33\,pp of $\lambda = 0.005$` — already correct at 0.33. ✓

**M2. λ range in method.tex**
Line 23: `$\lambda \in \{0.005, 0.01, 0.1\}$` — already includes 0.1. ✓


Line 44 also has the same range, so M2 is complete.

**M3. Statistical test unification**

Now I'm checking what still needs updating. The table caption and line 33 in claim3.tex both still reference the z-test with `$z = 1.76$, $p \approx 0.039$`, so those need to be changed to match the unified statistical approach.

In appendix.tex around lines 171 and 184, I see the same z-test references that should be updated. Line 173 already mentions the permutation test with a two-tailed p-value of 0.071, which is the direction I need to move toward.

I need to update the table captions and main references across these files to use the permutation test results instead of the z-test, and I should check switch.py to see if there are any related changes needed there.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "43258baa-0477-4355-af20-5efdaf4832ee",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vp6eaZnE7xDDMxBsPqNj4M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11288,
      "cache_read_input_tokens": 28475,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11288
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

_source line 50_

M1 (0.33pp) and M2 (λ range already includes 0.1) are already correct. Now checking M3 — the z-test references and paper_switch.py.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "04d1b61e-320c-434c-bac5-e32965692258",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vp6eaZnE7xDDMxBsPqNj4M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11288,
      "cache_read_input_tokens": 28475,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11288
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

_source line 51_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01NhtdPKhhjWrHCdQhh9Se24`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root/colliforce-vla/artifacts -name \"paper_switch.py\" -maxdepth 3",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "c0e31e1a-164d-4343-9e06-f4c8b363f222",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vp6eaZnE7xDDMxBsPqNj4M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11288,
      "cache_read_input_tokens": 28475,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11288
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

_source line 52 · 2026-05-27T20:36:17.864Z_

<details><summary>↩ Tool result · `toolu_01NhtdPKhhjWrHCdQhh9Se24`</summary>

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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "7b1ba5a4-2a02-427a-936b-de53f9a69218",
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

_source line 53_

<details open><summary>🔧 Tool call — Glob · `toolu_011NyqrKmQZWhcFpWpRdQts6`</summary>

```json
{
  "pattern": "**/paper_switch.py",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "d5c702d5-eeea-4432-af8b-2ef4a4d06a10",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vp6eaZnE7xDDMxBsPqNj4M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11288,
      "cache_read_input_tokens": 28475,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11288
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

_source line 54 · 2026-05-27T20:36:18.658Z_

<details><summary>↩ Tool result · `toolu_011NyqrKmQZWhcFpWpRdQts6`</summary>

```text
artifacts/_project/intermediate/paper_switch.py
artifacts/paper_switch.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "d08ef41c-9635-4786-8844-c58fab2ca8ce",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/intermediate/paper_switch.py",
      "artifacts/paper_switch.py"
    ],
    "durationMs": 23,
    "numFiles": 2,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 55_

<details open><summary>🔧 Tool call — Read · `toolu_019X6tRNFtEUjNJqd5TUjHmD`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/paper_switch.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f83a6f00-7bf4-4149-ac4b-ddf77733043e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NRvNo6U8ddPUa4oCvZKF8o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1012,
      "cache_read_input_tokens": 39763,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1012
      },
      "output_tokens": 56,
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

_source line 56 · 2026-05-27T20:36:21.728Z_

<details><summary>↩ Tool result · `toolu_019X6tRNFtEUjNJqd5TUjHmD`</summary>

```text
1	#!/usr/bin/env python3
2	"""Auto-switch paper text based on λ=0.1 s2 30K eval result.
3	
4	Usage:
5	  python paper_switch.py --s2-car 57.5 --s2-tsr 48.0 --dry-run
6	  python paper_switch.py --s2-car 57.5 --s2-tsr 48.0
7	"""
8	import argparse
9	import subprocess
10	import sys
11	from itertools import combinations
12	from math import comb, sqrt
13	from pathlib import Path
14	
15	NULL_VALUES = [57, 52.5, 55, 57, 54, 52.5]
16	NULL_MEAN = sum(NULL_VALUES) / len(NULL_VALUES)
17	NULL_STD = (sum((x - NULL_MEAN) ** 2 for x in NULL_VALUES) / 5) ** 0.5
18	
19	S0_CAR, S1_CAR = 58.0, 58.5
20	S0_TSR, S1_TSR = 47.0, 49.0
21	
22	PAPER_DIR = Path(__file__).resolve().parent.parent / "docs" / "paper"
23	
24	
25	def mean(v):
26	    return sum(v) / len(v)
27	
28	
29	def std_b(v):
30	    m = mean(v)
31	    return (sum((x - m) ** 2 for x in v) / (len(v) - 1)) ** 0.5
32	
33	
34	def perm_test(null_vals, treat_vals):
35	    pool = null_vals + treat_vals
36	    k = len(treat_vals)
37	    obs = mean(treat_vals)
38	    mu = mean(pool)
39	    dev = abs(obs - mu)
40	    n = comb(len(pool), k)
41	    ge = tw = 0
42	    for c in combinations(pool, k):
43	        m = mean(c)
44	        if m >= obs:
45	            ge += 1
46	        if abs(m - mu) >= dev - 1e-12:
47	            tw += 1
48	    return ge / n, tw / n, n
49	
50	
51	def fill(tpl, vals):
52	    for k, v in vals.items():
53	        tpl = tpl.replace("{" + k + "}", str(v))
54	    return tpl
55	
56	
57	def safe_replace(content, old, new, label):
58	    n = content.count(old)
59	    if n == 0:
60	        print(f"  !! [{label}] NOT FOUND")
61	        return content, False
62	    if n > 1:
63	        print(f"  !! [{label}] found {n}x")
64	        return content, False
65	    return content.replace(old, new), True
66	
67	
68	def get_replacements(scenario, v):
69	    R = []
70	    is_c = scenario == "C"
71	
72	    # 1. abstract.tex L7
73	    old = (
74	        r"Its contribution during training is dose-dependent: LoRA-only fine-tuning "
75	        r"raises dfCAR from 26.8\% to 54.83\%$\,\pm\,$2.25, matching SDF-augmented "
76	        r"training at $\lambda{=}0.005$ (54.5\%$\,\pm\,$2.29) and $\lambda{=}0.01$ "
77	        r"(56.33\%$\,\pm\,$1.61); at $\lambda{=}0.1$, two of three seeds show a "
78	        r"marginal signal (58.25\%$\,\pm\,$0.35, $p{\approx}0.039$) whose per-task "
79	        r"avoidance pattern still mirrors the demonstration distribution, requiring "
80	        r"further investigation."
81	    )
82	    if is_c:
83	        new = fill(
84	            r"Its contribution during training is dose-dependent: LoRA-only fine-tuning "
85	            r"raises dfCAR from 26.8\% to 54.83\%$\,\pm\,$2.25, matching SDF-augmented "
86	            r"training at $\lambda{=}0.005$ (54.5\%$\,\pm\,$2.29) and $\lambda{=}0.01$ "
87	            r"(56.33\%$\,\pm\,$1.61); at $\lambda{=}0.1$, a modest but statistically "
88	            r"significant increase emerges ({mean_car}\%$\,\pm\,${std_car}, permutation "
89	            r"$p{=}${p_value}, 3 seeds), though the effect size ({delta_pp}\,pp) is small "
90	            r"relative to the $+$28\,pp gain from fine-tuning alone, and per-task avoidance "
91	            r"patterns still mirror the demonstration distribution.", v)
92	    else:
93	        new = fill(
94	            r"SDF supervision during training adds no measurable benefit: LoRA-only "
95	            r"fine-tuning raises dfCAR from 26.8\% to 54.83\%$\,\pm\,$2.25, matching "
96	            r"SDF-augmented training across the full tested range $\lambda \in "
97	            r"\{0.005, 0.01, 0.1\}$ ($p{>}0.05$ for all; $\lambda{=}0.1$: "
98	            r"{mean_car}\%$\,\pm\,${std_car}, 3 seeds).", v)
99	    R.append(("abstract.tex", "abstract L7", old, new))
100	
101	    # 2. abstract.tex L9
102	    old = (
103	        r"Displacement filtering is necessary for meaningful VLA safety evaluation; "
104	        r"EE-only geometric supervision can be neither credited with nor expected to "
105	        r"deliver collision avoidance."
106	    )
107	    if is_c:
108	        new = (
109	            r"Displacement filtering is necessary for meaningful VLA safety evaluation; "
110	            r"even at the highest tested loss weight, the modest SDF effect is dwarfed by "
111	            r"demonstration-driven avoidance and cannot overcome the structural limitation "
112	            r"of EE-only supervision."
113	        )
114	    else:
115	        new = (
116	            r"Displacement filtering is necessary for meaningful VLA safety evaluation; "
117	            r"EE-only geometric supervision is fully redundant across a 20$\times$ "
118	            r"loss-weight range, confirming that collision avoidance arises from "
119	            r"demonstration data, not geometric supervision."
120	        )
121	    R.append(("abstract.tex", "abstract L9", old, new))
122	
123	    # 3. claim3.tex L3 scope sentence
124	    old = (
125	        r"We compare LoRA-only, LoRA+SDF ($\lambda = 0.005$), and LoRA+SDF "
126	        r"($\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint."
127	    )
128	    if is_c:
129	        new = (
130	            r"We compare LoRA-only against LoRA+SDF at three loss weights "
131	            r"($\lambda \in \{0.005, 0.01, 0.1\}$) on Pi0.5, all evaluated at "
132	            r"the 30K-step checkpoint."
133	        )
134	    else:
135	        new = (
136	            r"We compare LoRA-only against LoRA+SDF across a 20$\times$ range of "
137	            r"loss weights ($\lambda \in \{0.005, 0.01, 0.1\}$) on Pi0.5, all "
138	            r"evaluated at the 30K-step checkpoint."
139	        )
140	    R.append(("claim3.tex", "claim3 L3 scope", old, new))
141	
142	    # 4. claim3.tex L7 table caption
143	    old = (
144	        r"\caption{Avoidance source attribution on SafeLIBERO. SDF at "
145	        r"$\lambda \leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); "
146	        r"$\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \approx 0.039$, "
147	        r"$n{=}2$) that requires additional seeds. All fine-tuned models exhibit "
148	        r"0\% frozen rate and displacement $>$\,0.37\,m.}"
149	    )
150	    if is_c:
151	        new = fill(
152	            r"\caption{Avoidance source attribution on SafeLIBERO. SDF at "
153	            r"$\lambda \leq 0.01$ adds no measurable CAR beyond LoRA-only "
154	            r"($p > 0.1$). At $\lambda = 0.1$, a modest increase reaches "
155	            r"statistical significance ($z = {z_value}$, permutation "
156	            r"$p = {p_value}$, $n{=}3$), though the effect size ({delta_pp}\,pp) "
157	            r"is small relative to the $+$28\,pp LoRA gain. All fine-tuned models "
158	            r"exhibit 0\% frozen rate and displacement $>$\,0.37\,m.}", v)
159	    else:
160	        new = (
161	            r"\caption{Avoidance source attribution on SafeLIBERO. SDF adds no "
162	            r"measurable CAR beyond LoRA-only across the full tested range "
163	            r"$\lambda \in [0.005, 0.1]$ (all $p > 0.05$). All fine-tuned models "
164	            r"exhibit 0\% frozen rate and displacement $>$\,0.37\,m.}"
165	        )
166	    R.append(("claim3.tex", "claim3 L7 caption", old, new))
167	
168	    # 5. claim3.tex L20 table row
169	    old = (
170	        r"LoRA+SDF $\lambda{=}0.1$\textsuperscript{$\dagger$} & 2 & "
171	        r"48.0\,$\pm$\,1.4 & 58.25\,$\pm$\,0.35 & 0.394 \\"
172	    )
173	    new = fill(
174	        r"LoRA+SDF $\lambda{=}0.1$ & 3 & "
175	        r"{tsr_mean}\,$\pm$\,{tsr_std} & {mean_car}\,$\pm$\,{std_car} & 0.394 \\", v)
176	    R.append(("claim3.tex", "claim3 L20 table row", old, new))
177	
178	    # 6. claim3.tex L24 footnote (delete)
179	    footnote = (
180	        r"{\footnotesize \textsuperscript{$\dagger$}30K checkpoint, two of three "
181	        r"seeds; third seed in progress.}"
182	    )
183	    R.append(("claim3.tex", "claim3 L24 footnote", "\n" + footnote, ""))
184	
185	    # 7. claim3.tex L27 body paragraph
186	    old = (
187	        r"Table~\ref{tab:avoidance_source} shows that collision-free demonstrations "
188	        r"alone raise CAR by ${\sim}$28 percentage points (26.8\% $\to$ 54.83\%) with "
189	        r"zero frozen episodes and displacement above 0.37\,m, confirming genuine "
190	        r"avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only "
191	        r"CAR (54.83\%) is within 0.25\,pp of $\lambda = 0.005$ and statistically "
192	        r"indistinguishable from $\lambda = 0.01$ (56.33\%, $p > 0.1$; "
193	        r"Appendix~\ref{sec:appendix_null}). A Phase~2 ablation ($\lambda = 0$ after "
194	        r"step 5K) yields CAR\,=\,57.5\%\footnote{Single seed (s2); computational "
195	        r"constraints precluded additional seeds for this ablation.}, confirming that "
196	        r"SDF gradients produce no lasting behavioral effect. The per-task CAR ordering "
197	        r"is preserved across all conditions (chocolate\_pudding highest, bbq\_sauce "
198	        r"lowest) and invariant to $\lambda$ across a 20$\times$ range, indicating that "
199	        r"avoidance patterns reflect the demonstration distribution rather than "
200	        r"geometric supervision."
201	    )
202	    if is_c:
203	        new = (
204	            r"Table~\ref{tab:avoidance_source} shows that collision-free demonstrations "
205	            r"alone raise CAR by ${\sim}$28 percentage points (26.8\% $\to$ 54.83\%) with "
206	            r"zero frozen episodes and displacement above 0.37\,m, confirming genuine "
207	            r"avoidance. At $\lambda \leq 0.01$, SDF supervision produces no measurable "
208	            r"benefit: LoRA-only CAR (54.83\%) is within 0.25\,pp of $\lambda = 0.005$ "
209	            r"and statistically indistinguishable from $\lambda = 0.01$ (56.33\%, "
210	            r"$p > 0.1$; Appendix~\ref{sec:appendix_null}). At $\lambda = 0.1$, a modest "
211	            r"increase emerges (Section~\ref{sec:lambda_high}), but per-task CAR ordering "
212	            r"remains identical across all conditions (chocolate\_pudding highest, "
213	            r"bbq\_sauce lowest), indicating that avoidance patterns reflect the "
214	            r"demonstration distribution regardless of SDF loss weight. A Phase~2 "
215	            r"ablation ($\lambda = 0$ after step 5K) yields CAR\,=\,57.5\%\footnote{"
216	            r"Single seed (s2); computational constraints precluded additional seeds for "
217	            r"this ablation.}, confirming that SDF gradients produce no lasting behavioral "
218	            r"effect."
219	        )
220	    else:
221	        new = fill(
222	            r"Table~\ref{tab:avoidance_source} shows that collision-free demonstrations "
223	            r"alone raise CAR by ${\sim}$28 percentage points (26.8\% $\to$ 54.83\%) with "
224	            r"zero frozen episodes and displacement above 0.37\,m, confirming genuine "
225	            r"avoidance. Adding SDF supervision produces no measurable benefit across the "
226	            r"full tested range: LoRA-only CAR (54.83\%) is statistically "
227	            r"indistinguishable from all SDF conditions including $\lambda = 0.1$ "
228	            r"({mean_car}\%, $p = {p_value}$; Appendix~\ref{sec:appendix_null}). "
229	            r"A Phase~2 ablation ($\lambda = 0$ after step 5K) yields "
230	            r"CAR\,=\,57.5\%\footnote{Single seed (s2); computational constraints "
231	            r"precluded additional seeds for this ablation.}, confirming that SDF "
232	            r"gradients produce no lasting behavioral effect. The per-task CAR ordering "
233	            r"is preserved across all conditions (chocolate\_pudding highest, bbq\_sauce "
234	            r"lowest) and invariant to $\lambda$ across a 20$\times$ range, indicating "
235	            r"that avoidance patterns reflect the demonstration distribution rather than "
236	            r"geometric supervision.", v)
237	    R.append(("claim3.tex", "claim3 L27 body", old, new))
238	
239	    # 8. claim3.tex L32-33 dose-response paragraph
240	    hdr = r"\paragraph{Dose-response at higher loss weights.}\label{sec:lambda_high}"
241	    old_body = (
242	        r"Increasing $\lambda$ by 20$\times$ to 0.1 yields "
243	        r"CAR\,=\,58.25\%\,$\pm$\,0.35 at the 30K checkpoint (two of three seeds), "
244	        r"above the null distribution (mean 54.67\%, $\sigma = 2.04$, $z = 1.76$, "
245	        r"$p \approx 0.039$). This departure is suggestive but inconclusive at "
246	        r"$n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no "
247	        r"sustained trend (mean 55.3\%, within 0.3$\sigma$ of the null; "
248	        r"Appendix~\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K "
249	        r"remains identical to all other conditions (Figure~\ref{fig:lambda_car}). "
250	        r"The response is thus dose-dependent: SDF is fully redundant at "
251	        r"$\lambda \leq 0.01$ ($p > 0.1$), with a marginal signal at $\lambda = 0.1$ "
252	        r"whose modest effect size (${\sim}$3.6\,pp) and limited sample preclude "
253	        r"strong conclusions. Even at elevated $\lambda$, avoidance patterns remain "
254	        r"driven by demonstration distribution rather than geometric supervision."
255	    )
256	    old = hdr + "\n" + old_body
257	    if is_c:
258	        new_body = fill(
259	            r"Increasing $\lambda$ by 20$\times$ to 0.1 yields "
260	            r"CAR\,=\,{mean_car}\%\,$\pm$\,{std_car} at the 30K checkpoint "
261	            r"(3 seeds: {s0_car}\%, {s1_car}\%, {s2_car}\%), a modest but "
262	            r"statistically significant departure from the null distribution "
263	            r"(mean 54.67\%, $\sigma = 2.04$; permutation $p = {p_value}$). The "
264	            r"effect size of {delta_pp}\,pp is small relative to the $+$28\,pp gain "
265	            r"from LoRA fine-tuning alone, indicating that EE-only SDF supervision "
266	            r"can incrementally augment demonstration-driven avoidance at sufficiently "
267	            r"high loss weights but cannot substitute for it. A stepwise ablation across "
268	            r"six checkpoints (16K--28K) shows no sustained trend prior to 30K "
269	            r"(mean 55.3\%, within 0.3$\sigma$ of the null; "
270	            r"Appendix~\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K "
271	            r"remains identical to all other conditions "
272	            r"(Figure~\ref{fig:lambda_car}), confirming that the dominant avoidance "
273	            r"signal remains the demonstration distribution. The response is thus "
274	            r"dose-dependent: SDF is fully redundant at $\lambda \leq 0.01$ "
275	            r"($p > 0.1$), with a small but detectable effect at $\lambda = 0.1$ "
276	            r"that preserves the same demonstration-driven avoidance fingerprint.", v)
277	    else:
278	        new_body = fill(
279	            r"Increasing $\lambda$ by 20$\times$ to 0.1 yields "
280	            r"CAR\,=\,{mean_car}\%\,$\pm$\,{std_car} at the 30K checkpoint "
281	            r"(3 seeds: {s0_car}\%, {s1_car}\%, {s2_car}\%), within the null "
282	            r"distribution (mean 54.67\%, $\sigma = 2.04$; permutation "
283	            r"$p = {p_value}$). SDF supervision is redundant with the demonstration "
284	            r"signal across the full tested range $\lambda \in [0.005, 0.1]$ "
285	            r"(Figure~\ref{fig:lambda_car}). This result disambiguates the two-level "
286	            r"failure analysis (Section~\ref{sec:conclusion}): because even a "
287	            r"20$\times$ increase in SDF loss weight fails to produce additional "
288	            r"avoidance, the binding constraint is not training signal magnitude but "
289	            r"the structural mismatch between end-effector monitoring and full-body "
290	            r"collision surfaces. Stronger geometric supervision cannot compensate for "
291	            r"supervising the wrong collision surface.", v)
292	    R.append(("claim3.tex", "claim3 L32-33 dose-response", old, hdr + "\n" + new_body))
293	
294	    # 9. claim3.tex L38 figure caption
295	    old = (
296	        r"\caption{Effect of SDF loss weight $\lambda$ on CAR and TSR. "
297	        r"$\lambda = 0$: LoRA-only. Low $\lambda$ ($\leq 0.01$) remains within "
298	        r"the null band; $\lambda = 0.1$ (58.25\%, 2 seeds) shows a marginal "
299	        r"departure ($p \approx 0.039$) whose per-task pattern still matches the "
300	        r"demonstration distribution.}"
301	    )
302	    if is_c:
303	        new = fill(
304	            r"\caption{Effect of SDF loss weight $\lambda$ on CAR and TSR. "
305	            r"$\lambda = 0$: LoRA-only. Low $\lambda$ ($\leq 0.01$) remains within "
306	            r"the null band; $\lambda = 0.1$ ({mean_car}\%, 3 seeds) shows a modest "
307	            r"but significant departure (permutation $p = {p_value}$, {delta_pp}\,pp "
308	            r"effect size) whose per-task avoidance pattern still matches the "
309	            r"demonstration distribution.}", v)
310	    else:
311	        new = (
312	            r"\caption{Effect of SDF loss weight $\lambda$ on CAR and TSR. "
313	            r"$\lambda = 0$: LoRA-only. All tested $\lambda$ values remain within "
314	            r"the null band ($p > 0.05$), confirming full redundancy of EE-only SDF "
315	            r"supervision across a 20$\times$ loss-weight range.}"
316	        )
317	    R.append(("claim3.tex", "claim3 L38 fig caption", old, new))
318	
319	    # 10. discussion.tex L3 scope (Scenario C only)
320	    if is_c:
321	        old = (
322	            r"and collision-free demonstrations, not geometric supervision, account "
323	            r"for all measured avoidance gains (\S\ref{sec:avoidance_source})."
324	        )
325	        new = (
326	            r"and collision-free demonstrations account for nearly all measured "
327	            r"avoidance gains, with EE-only SDF contributing at most a modest "
328	            r"increment at high loss weights (\S\ref{sec:avoidance_source})."
329	        )
330	        R.append(("discussion.tex", "discussion L3 scope", old, new))
331	
332	    # 11. discussion.tex L6
333	    old = (
334	        r"At low $\lambda$, SDF is redundant; at $\lambda = 0.1$, the marginal "
335	        r"signal preserves the same demonstration-driven pattern."
336	    )
337	    if is_c:
338	        new = fill(
339	            r"At $\lambda \leq 0.01$, SDF is fully redundant; at $\lambda = 0.1$, "
340	            r"a modest {delta_pp}\,pp effect emerges ($p = {p_value}$) but preserves "
341	            r"the same demonstration-driven avoidance pattern, suggesting that "
342	            r"EE-only SDF can weakly augment---but not redirect---the implicit signal "
343	            r"at sufficiently high loss weights.", v)
344	    else:
345	        new = fill(
346	            r"Even at $\lambda = 0.1$ (20$\times$ the lowest tested weight), CAR "
347	            r"remains within the null distribution ($p = {p_value}$), confirming "
348	            r"that Level~A signal masking is not the binding constraint---the failure "
349	            r"is architectural.", v)
350	    R.append(("discussion.tex", "discussion L6", old, new))
351	
352	    # 12. discussion.tex L12 limitation
353	    old = (
354	        r"The $\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure "
355	        r"($p \approx 0.039$) is inconclusive. "
356	    )
357	    if is_c:
358	        new = fill(
359	            r"The $\lambda = 0.1$ effect ({delta_pp}\,pp, $p = {p_value}$, $n = 3$) "
360	            r"is statistically significant but small; whether this modest gain "
361	            r"justifies the computational cost of SDF supervision requires "
362	            r"task-specific cost-benefit analysis. ", v)
363	    else:
364	        new = ""
365	    R.append(("discussion.tex", "discussion L12 limitation", old, new))
366	
367	    return R
368	
369	
370	def main():
371	    parser = argparse.ArgumentParser(
372	        description="Auto-switch paper for lambda=0.1 s2 30K result")
373	    parser.add_argument("--s2-car", type=float, required=True)
374	    parser.add_argument("--s2-tsr", type=float, default=None)
375	    parser.add_argument("--dry-run", action="store_true")
376	    args = parser.parse_args()
377	
378	    cars = [S0_CAR, S1_CAR, args.s2_car]
379	    car_mean = mean(cars)
380	    car_std = std_b(cars)
381	
382	    if args.s2_tsr is not None:
383	        tsrs = [S0_TSR, S1_TSR, args.s2_tsr]
384	    else:
385	        tsrs = [S0_TSR, S1_TSR]
386	        print("NOTE: --s2-tsr not provided, using 2-seed TSR")
387	    tsr_mean = mean(tsrs)
388	    tsr_std = std_b(tsrs)
389	
390	    p_one, p_two, n_combos = perm_test(NULL_VALUES, cars)
391	    z = (car_mean - NULL_MEAN) / NULL_STD
392	    delta = car_mean - NULL_MEAN
393	
394	    scenario = "C" if p_one < 0.05 else "B"
395	
396	    v = {
397	        "s0_car": f"{S0_CAR:.1f}",
398	        "s1_car": f"{S1_CAR:.1f}",
399	        "s2_car": f"{args.s2_car:.1f}",
400	        "mean_car": f"{car_mean:.2f}",
401	        "std_car": f"{car_std:.2f}",
402	        "tsr_mean": f"{tsr_mean:.1f}",
403	        "tsr_std": f"{tsr_std:.1f}",
404	        "p_value": f"{p_one:.3f}",
405	        "z_value": f"{z:.2f}",
406	        "delta_pp": f"{delta:.1f}",
407	    }
408	
409	    print("=" * 60)
410	    print("  PAPER SWITCH — lambda=0.1 s2 30K")
411	    print("=" * 60)
412	    print(f"  Input:     s2_car={args.s2_car}, s2_tsr={args.s2_tsr}")
413	    print(f"  3-seed:    CAR = {v['mean_car']} +/- {v['std_car']}")
414	    print(f"             TSR = {v['tsr_mean']} +/- {v['tsr_std']} ({len(tsrs)} seeds)")
415	    print(f"  Perm test: C({len(NULL_VALUES)+len(cars)},{len(cars)}) = {n_combos}")
416	    print(f"             p_one = {v['p_value']}  {'<' if p_one < 0.05 else '>='} 0.05")
417	    print(f"             p_two = {p_two:.3f}")
418	    print(f"  Z-score:   {v['z_value']}")
419	    print(f"  Delta:     +{v['delta_pp']} pp")
420	    print(f"  Scenario:  {scenario}  "
421	          f"{'(modest but significant)' if scenario == 'C' else '(full redundancy)'}")
422	    print()
423	
424	    if not PAPER_DIR.exists():
425	        print(f"ERROR: paper dir not found: {PAPER_DIR}")
426	        sys.exit(1)
427	
428	    replacements = get_replacements(scenario, v)
429	
430	    files_content = {}
431	    counts = {}
432	
433	    for filename, label, old, new in replacements:
434	        fpath = PAPER_DIR / filename
435	        if filename not in files_content:
436	            if not fpath.exists():
437	                print(f"  !! {filename} not found")
438	                continue
439	            files_content[filename] = fpath.read_text()
440	            counts[filename] = 0
441	
442	        content, ok = safe_replace(files_content[filename], old, new, label)
443	        files_content[filename] = content
444	        if ok:
445	            counts[filename] += 1
446	            status = "ok"
447	        else:
448	            status = "FAIL"
449	        print(f"  [{status:4s}] {label:35s} {filename}")
450	
451	    total = sum(counts.values())
452	    n_files = sum(1 for c in counts.values() if c > 0)
453	    expected = len(replacements)
454	    print(f"\n  {total}/{expected} replacements in {n_files} files")
455	
456	    if args.dry_run:
457	        print("\n  DRY RUN — no files modified")
458	        return
459	
460	    for filename, content in files_content.items():
461	        fpath = PAPER_DIR / filename
462	        fpath.write_text(content)
463	        print(f"  Wrote {filename} ({counts[filename]} changes)")
464	
465	    print("\nCompiling PDF...")
466	    try:
467	        result = subprocess.run(
468	            ["latexmk", "-pdf", "-interaction=nonstopmode", "main.tex"],
469	            cwd=PAPER_DIR, capture_output=True, text=True, timeout=120)
470	        if result.returncode == 0:
471	            print("  PDF compiled OK")
472	        else:
473	            print("  PDF compilation FAILED")
474	            err = result.stderr or result.stdout or ""
475	            for line in err.split("\n")[-10:]:
476	                if line.strip():
477	                    print(f"    {line}")
478	    except FileNotFoundError:
479	        print("  latexmk not found — skipping PDF compilation")
480	    except subprocess.TimeoutExpired:
481	        print("  PDF compilation timed out (120s)")
482	
483	
484	if __name__ == "__main__":
485	    main()
486	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "7487b65b-c7ff-49e6-9d89-28bf956c0d58",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/paper_switch.py",
      "content": "#!/usr/bin/env python3\n\"\"\"Auto-switch paper text based on λ=0.1 s2 30K eval result.\n\nUsage:\n  python paper_switch.py --s2-car 57.5 --s2-tsr 48.0 --dry-run\n  python paper_switch.py --s2-car 57.5 --s2-tsr 48.0\n\"\"\"\nimport argparse\nimport subprocess\nimport sys\nfrom itertools import combinations\nfrom math import comb, sqrt\nfrom pathlib import Path\n\nNULL_VALUES = [57, 52.5, 55, 57, 54, 52.5]\nNULL_MEAN = sum(NULL_VALUES) / len(NULL_VALUES)\nNULL_STD = (sum((x - NULL_MEAN) ** 2 for x in NULL_VALUES) / 5) ** 0.5\n\nS0_CAR, S1_CAR = 58.0, 58.5\nS0_TSR, S1_TSR = 47.0, 49.0\n\nPAPER_DIR = Path(__file__).resolve().parent.parent / \"docs\" / \"paper\"\n\n\ndef mean(v):\n    return sum(v) / len(v)\n\n\ndef std_b(v):\n    m = mean(v)\n    return (sum((x - m) ** 2 for x in v) / (len(v) - 1)) ** 0.5\n\n\ndef perm_test(null_vals, treat_vals):\n    pool = null_vals + treat_vals\n    k = len(treat_vals)\n    obs = mean(treat_vals)\n    mu = mean(pool)\n    dev = abs(obs - mu)\n    n = comb(len(pool), k)\n    ge = tw = 0\n    for c in combinations(pool, k):\n        m = mean(c)\n        if m >= obs:\n            ge += 1\n        if abs(m - mu) >= dev - 1e-12:\n            tw += 1\n    return ge / n, tw / n, n\n\n\ndef fill(tpl, vals):\n    for k, v in vals.items():\n        tpl = tpl.replace(\"{\" + k + \"}\", str(v))\n    return tpl\n\n\ndef safe_replace(content, old, new, label):\n    n = content.count(old)\n    if n == 0:\n        print(f\"  !! [{label}] NOT FOUND\")\n        return content, False\n    if n > 1:\n        print(f\"  !! [{label}] found {n}x\")\n        return content, False\n    return content.replace(old, new), True\n\n\ndef get_replacements(scenario, v):\n    R = []\n    is_c = scenario == \"C\"\n\n    # 1. abstract.tex L7\n    old = (\n        r\"Its contribution during training is dose-dependent: LoRA-only fine-tuning \"\n        r\"raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented \"\n        r\"training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ \"\n        r\"(56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, two of three seeds show a \"\n        r\"marginal signal (58.25\\%$\\,\\pm\\,$0.35, $p{\\approx}0.039$) whose per-task \"\n        r\"avoidance pattern still mirrors the demonstration distribution, requiring \"\n        r\"further investigation.\"\n    )\n    if is_c:\n        new = fill(\n            r\"Its contribution during training is dose-dependent: LoRA-only fine-tuning \"\n            r\"raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented \"\n            r\"training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ \"\n            r\"(56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, a modest but statistically \"\n            r\"significant increase emerges ({mean_car}\\%$\\,\\pm\\,${std_car}, permutation \"\n            r\"$p{=}${p_value}, 3 seeds), though the effect size ({delta_pp}\\,pp) is small \"\n            r\"relative to the $+$28\\,pp gain from fine-tuning alone, and per-task avoidance \"\n            r\"patterns still mirror the demonstration distribution.\", v)\n    else:\n        new = fill(\n            r\"SDF supervision during training adds no measurable benefit: LoRA-only \"\n            r\"fine-tuning raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching \"\n            r\"SDF-augmented training across the full tested range $\\lambda \\in \"\n            r\"\\{0.005, 0.01, 0.1\\}$ ($p{>}0.05$ for all; $\\lambda{=}0.1$: \"\n            r\"{mean_car}\\%$\\,\\pm\\,${std_car}, 3 seeds).\", v)\n    R.append((\"abstract.tex\", \"abstract L7\", old, new))\n\n    # 2. abstract.tex L9\n    old = (\n        r\"Displacement filtering is necessary for meaningful VLA safety evaluation; \"\n        r\"EE-only geometric supervision can be neither credited with nor expected to \"\n        r\"deliver collision avoidance.\"\n    )\n    if is_c:\n        new = (\n            r\"Displacement filtering is necessary for meaningful VLA safety evaluation; \"\n            r\"even at the highest tested loss weight, the modest SDF effect is dwarfed by \"\n            r\"demonstration-driven avoidance and cannot overcome the structural limitation \"\n            r\"of EE-only supervision.\"\n        )\n    else:\n        new = (\n            r\"Displacement filtering is necessary for meaningful VLA safety evaluation; \"\n            r\"EE-only geometric supervision is fully redundant across a 20$\\times$ \"\n            r\"loss-weight range, confirming that collision avoidance arises from \"\n            r\"demonstration data, not geometric supervision.\"\n        )\n    R.append((\"abstract.tex\", \"abstract L9\", old, new))\n\n    # 3. claim3.tex L3 scope sentence\n    old = (\n        r\"We compare LoRA-only, LoRA+SDF ($\\lambda = 0.005$), and LoRA+SDF \"\n        r\"($\\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint.\"\n    )\n    if is_c:\n        new = (\n            r\"We compare LoRA-only against LoRA+SDF at three loss weights \"\n            r\"($\\lambda \\in \\{0.005, 0.01, 0.1\\}$) on Pi0.5, all evaluated at \"\n            r\"the 30K-step checkpoint.\"\n        )\n    else:\n        new = (\n            r\"We compare LoRA-only against LoRA+SDF across a 20$\\times$ range of \"\n            r\"loss weights ($\\lambda \\in \\{0.005, 0.01, 0.1\\}$) on Pi0.5, all \"\n            r\"evaluated at the 30K-step checkpoint.\"\n        )\n    R.append((\"claim3.tex\", \"claim3 L3 scope\", old, new))\n\n    # 4. claim3.tex L7 table caption\n    old = (\n        r\"\\caption{Avoidance source attribution on SafeLIBERO. SDF at \"\n        r\"$\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); \"\n        r\"$\\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \\approx 0.039$, \"\n        r\"$n{=}2$) that requires additional seeds. All fine-tuned models exhibit \"\n        r\"0\\% frozen rate and displacement $>$\\,0.37\\,m.}\"\n    )\n    if is_c:\n        new = fill(\n            r\"\\caption{Avoidance source attribution on SafeLIBERO. SDF at \"\n            r\"$\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only \"\n            r\"($p > 0.1$). At $\\lambda = 0.1$, a modest increase reaches \"\n            r\"statistical significance ($z = {z_value}$, permutation \"\n            r\"$p = {p_value}$, $n{=}3$), though the effect size ({delta_pp}\\,pp) \"\n            r\"is small relative to the $+$28\\,pp LoRA gain. All fine-tuned models \"\n            r\"exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\", v)\n    else:\n        new = (\n            r\"\\caption{Avoidance source attribution on SafeLIBERO. SDF adds no \"\n            r\"measurable CAR beyond LoRA-only across the full tested range \"\n            r\"$\\lambda \\in [0.005, 0.1]$ (all $p > 0.05$). All fine-tuned models \"\n            r\"exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\"\n        )\n    R.append((\"claim3.tex\", \"claim3 L7 caption\", old, new))\n\n    # 5. claim3.tex L20 table row\n    old = (\n        r\"LoRA+SDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 2 & \"\n        r\"48.0\\,$\\pm$\\,1.4 & 58.25\\,$\\pm$\\,0.35 & 0.394 \\\\\"\n    )\n    new = fill(\n        r\"LoRA+SDF $\\lambda{=}0.1$ & 3 & \"\n        r\"{tsr_mean}\\,$\\pm$\\,{tsr_std} & {mean_car}\\,$\\pm$\\,{std_car} & 0.394 \\\\\", v)\n    R.append((\"claim3.tex\", \"claim3 L20 table row\", old, new))\n\n    # 6. claim3.tex L24 footnote (delete)\n    footnote = (\n        r\"{\\footnotesize \\textsuperscript{$\\dagger$}30K checkpoint, two of three \"\n        r\"seeds; third seed in progress.}\"\n    )\n    R.append((\"claim3.tex\", \"claim3 L24 footnote\", \"\\n\" + footnote, \"\"))\n\n    # 7. claim3.tex L27 body paragraph\n    old = (\n        r\"Table~\\ref{tab:avoidance_source} shows that collision-free demonstrations \"\n        r\"alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with \"\n        r\"zero frozen episodes and displacement above 0.37\\,m, confirming genuine \"\n        r\"avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only \"\n        r\"CAR (54.83\\%) is within 0.25\\,pp of $\\lambda = 0.005$ and statistically \"\n        r\"indistinguishable from $\\lambda = 0.01$ (56.33\\%, $p > 0.1$; \"\n        r\"Appendix~\\ref{sec:appendix_null}). A Phase~2 ablation ($\\lambda = 0$ after \"\n        r\"step 5K) yields CAR\\,=\\,57.5\\%\\footnote{Single seed (s2); computational \"\n        r\"constraints precluded additional seeds for this ablation.}, confirming that \"\n        r\"SDF gradients produce no lasting behavioral effect. The per-task CAR ordering \"\n        r\"is preserved across all conditions (chocolate\\_pudding highest, bbq\\_sauce \"\n        r\"lowest) and invariant to $\\lambda$ across a 20$\\times$ range, indicating that \"\n        r\"avoidance patterns reflect the demonstration distribution rather than \"\n        r\"geometric supervision.\"\n    )\n    if is_c:\n        new = (\n            r\"Table~\\ref{tab:avoidance_source} shows that collision-free demonstrations \"\n            r\"alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with \"\n            r\"zero frozen episodes and displacement above 0.37\\,m, confirming genuine \"\n            r\"avoidance. At $\\lambda \\leq 0.01$, SDF supervision produces no measurable \"\n            r\"benefit: LoRA-only CAR (54.83\\%) is within 0.25\\,pp of $\\lambda = 0.005$ \"\n            r\"and statistically indistinguishable from $\\lambda = 0.01$ (56.33\\%, \"\n            r\"$p > 0.1$; Appendix~\\ref{sec:appendix_null}). At $\\lambda = 0.1$, a modest \"\n            r\"increase emerges (Section~\\ref{sec:lambda_high}), but per-task CAR ordering \"\n            r\"remains identical across all conditions (chocolate\\_pudding highest, \"\n            r\"bbq\\_sauce lowest), indicating that avoidance patterns reflect the \"\n            r\"demonstration distribution regardless of SDF loss weight. A Phase~2 \"\n            r\"ablation ($\\lambda = 0$ after step 5K) yields CAR\\,=\\,57.5\\%\\footnote{\"\n            r\"Single seed (s2); computational constraints precluded additional seeds for \"\n            r\"this ablation.}, confirming that SDF gradients produce no lasting behavioral \"\n            r\"effect.\"\n        )\n    else:\n        new = fill(\n            r\"Table~\\ref{tab:avoidance_source} shows that collision-free demonstrations \"\n            r\"alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with \"\n            r\"zero frozen episodes and displacement above 0.37\\,m, confirming genuine \"\n            r\"avoidance. Adding SDF supervision produces no measurable benefit across the \"\n            r\"full tested range: LoRA-only CAR (54.83\\%) is statistically \"\n            r\"indistinguishable from all SDF conditions including $\\lambda = 0.1$ \"\n            r\"({mean_car}\\%, $p = {p_value}$; Appendix~\\ref{sec:appendix_null}). \"\n            r\"A Phase~2 ablation ($\\lambda = 0$ after step 5K) yields \"\n            r\"CAR\\,=\\,57.5\\%\\footnote{Single seed (s2); computational constraints \"\n            r\"precluded additional seeds for this ablation.}, confirming that SDF \"\n            r\"gradients produce no lasting behavioral effect. The per-task CAR ordering \"\n            r\"is preserved across all conditions (chocolate\\_pudding highest, bbq\\_sauce \"\n            r\"lowest) and invariant to $\\lambda$ across a 20$\\times$ range, indicating \"\n            r\"that avoidance patterns reflect the demonstration distribution rather than \"\n            r\"geometric supervision.\", v)\n    R.append((\"claim3.tex\", \"claim3 L27 body\", old, new))\n\n    # 8. claim3.tex L32-33 dose-response paragraph\n    hdr = r\"\\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}\"\n    old_body = (\n        r\"Increasing $\\lambda$ by 20$\\times$ to 0.1 yields \"\n        r\"CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), \"\n        r\"above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, \"\n        r\"$p \\approx 0.039$). This departure is suggestive but inconclusive at \"\n        r\"$n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no \"\n        r\"sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; \"\n        r\"Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K \"\n        r\"remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). \"\n        r\"The response is thus dose-dependent: SDF is fully redundant at \"\n        r\"$\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ \"\n        r\"whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude \"\n        r\"strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain \"\n        r\"driven by demonstration distribution rather than geometric supervision.\"\n    )\n    old = hdr + \"\\n\" + old_body\n    if is_c:\n        new_body = fill(\n            r\"Increasing $\\lambda$ by 20$\\times$ to 0.1 yields \"\n            r\"CAR\\,=\\,{mean_car}\\%\\,$\\pm$\\,{std_car} at the 30K checkpoint \"\n            r\"(3 seeds: {s0_car}\\%, {s1_car}\\%, {s2_car}\\%), a modest but \"\n            r\"statistically significant departure from the null distribution \"\n            r\"(mean 54.67\\%, $\\sigma = 2.04$; permutation $p = {p_value}$). The \"\n            r\"effect size of {delta_pp}\\,pp is small relative to the $+$28\\,pp gain \"\n            r\"from LoRA fine-tuning alone, indicating that EE-only SDF supervision \"\n            r\"can incrementally augment demonstration-driven avoidance at sufficiently \"\n            r\"high loss weights but cannot substitute for it. A stepwise ablation across \"\n            r\"six checkpoints (16K--28K) shows no sustained trend prior to 30K \"\n            r\"(mean 55.3\\%, within 0.3$\\sigma$ of the null; \"\n            r\"Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K \"\n            r\"remains identical to all other conditions \"\n            r\"(Figure~\\ref{fig:lambda_car}), confirming that the dominant avoidance \"\n            r\"signal remains the demonstration distribution. The response is thus \"\n            r\"dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ \"\n            r\"($p > 0.1$), with a small but detectable effect at $\\lambda = 0.1$ \"\n            r\"that preserves the same demonstration-driven avoidance fingerprint.\", v)\n    else:\n        new_body = fill(\n            r\"Increasing $\\lambda$ by 20$\\times$ to 0.1 yields \"\n            r\"CAR\\,=\\,{mean_car}\\%\\,$\\pm$\\,{std_car} at the 30K checkpoint \"\n            r\"(3 seeds: {s0_car}\\%, {s1_car}\\%, {s2_car}\\%), within the null \"\n            r\"distribution (mean 54.67\\%, $\\sigma = 2.04$; permutation \"\n            r\"$p = {p_value}$). SDF supervision is redundant with the demonstration \"\n            r\"signal across the full tested range $\\lambda \\in [0.005, 0.1]$ \"\n            r\"(Figure~\\ref{fig:lambda_car}). This result disambiguates the two-level \"\n            r\"failure analysis (Section~\\ref{sec:conclusion}): because even a \"\n            r\"20$\\times$ increase in SDF loss weight fails to produce additional \"\n            r\"avoidance, the binding constraint is not training signal magnitude but \"\n            r\"the structural mismatch between end-effector monitoring and full-body \"\n            r\"collision surfaces. Stronger geometric supervision cannot compensate for \"\n            r\"supervising the wrong collision surface.\", v)\n    R.append((\"claim3.tex\", \"claim3 L32-33 dose-response\", old, hdr + \"\\n\" + new_body))\n\n    # 9. claim3.tex L38 figure caption\n    old = (\n        r\"\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. \"\n        r\"$\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within \"\n        r\"the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal \"\n        r\"departure ($p \\approx 0.039$) whose per-task pattern still matches the \"\n        r\"demonstration distribution.}\"\n    )\n    if is_c:\n        new = fill(\n            r\"\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. \"\n            r\"$\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within \"\n            r\"the null band; $\\lambda = 0.1$ ({mean_car}\\%, 3 seeds) shows a modest \"\n            r\"but significant departure (permutation $p = {p_value}$, {delta_pp}\\,pp \"\n            r\"effect size) whose per-task avoidance pattern still matches the \"\n            r\"demonstration distribution.}\", v)\n    else:\n        new = (\n            r\"\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. \"\n            r\"$\\lambda = 0$: LoRA-only. All tested $\\lambda$ values remain within \"\n            r\"the null band ($p > 0.05$), confirming full redundancy of EE-only SDF \"\n            r\"supervision across a 20$\\times$ loss-weight range.}\"\n        )\n    R.append((\"claim3.tex\", \"claim3 L38 fig caption\", old, new))\n\n    # 10. discussion.tex L3 scope (Scenario C only)\n    if is_c:\n        old = (\n            r\"and collision-free demonstrations, not geometric supervision, account \"\n            r\"for all measured avoidance gains (\\S\\ref{sec:avoidance_source}).\"\n        )\n        new = (\n            r\"and collision-free demonstrations account for nearly all measured \"\n            r\"avoidance gains, with EE-only SDF contributing at most a modest \"\n            r\"increment at high loss weights (\\S\\ref{sec:avoidance_source}).\"\n        )\n        R.append((\"discussion.tex\", \"discussion L3 scope\", old, new))\n\n    # 11. discussion.tex L6\n    old = (\n        r\"At low $\\lambda$, SDF is redundant; at $\\lambda = 0.1$, the marginal \"\n        r\"signal preserves the same demonstration-driven pattern.\"\n    )\n    if is_c:\n        new = fill(\n            r\"At $\\lambda \\leq 0.01$, SDF is fully redundant; at $\\lambda = 0.1$, \"\n            r\"a modest {delta_pp}\\,pp effect emerges ($p = {p_value}$) but preserves \"\n            r\"the same demonstration-driven avoidance pattern, suggesting that \"\n            r\"EE-only SDF can weakly augment---but not redirect---the implicit signal \"\n            r\"at sufficiently high loss weights.\", v)\n    else:\n        new = fill(\n            r\"Even at $\\lambda = 0.1$ (20$\\times$ the lowest tested weight), CAR \"\n            r\"remains within the null distribution ($p = {p_value}$), confirming \"\n            r\"that Level~A signal masking is not the binding constraint---the failure \"\n            r\"is architectural.\", v)\n    R.append((\"discussion.tex\", \"discussion L6\", old, new))\n\n    # 12. discussion.tex L12 limitation\n    old = (\n        r\"The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure \"\n        r\"($p \\approx 0.039$) is inconclusive. \"\n    )\n    if is_c:\n        new = fill(\n            r\"The $\\lambda = 0.1$ effect ({delta_pp}\\,pp, $p = {p_value}$, $n = 3$) \"\n            r\"is statistically significant but small; whether this modest gain \"\n            r\"justifies the computational cost of SDF supervision requires \"\n            r\"task-specific cost-benefit analysis. \", v)\n    else:\n        new = \"\"\n    R.append((\"discussion.tex\", \"discussion L12 limitation\", old, new))\n\n    return R\n\n\ndef main():\n    parser = argparse.ArgumentParser(\n        description=\"Auto-switch paper for lambda=0.1 s2 30K result\")\n    parser.add_argument(\"--s2-car\", type=float, required=True)\n    parser.add_argument(\"--s2-tsr\", type=float, default=None)\n    parser.add_argument(\"--dry-run\", action=\"store_true\")\n    args = parser.parse_args()\n\n    cars = [S0_CAR, S1_CAR, args.s2_car]\n    car_mean = mean(cars)\n    car_std = std_b(cars)\n\n    if args.s2_tsr is not None:\n        tsrs = [S0_TSR, S1_TSR, args.s2_tsr]\n    else:\n        tsrs = [S0_TSR, S1_TSR]\n        print(\"NOTE: --s2-tsr not provided, using 2-seed TSR\")\n    tsr_mean = mean(tsrs)\n    tsr_std = std_b(tsrs)\n\n    p_one, p_two, n_combos = perm_test(NULL_VALUES, cars)\n    z = (car_mean - NULL_MEAN) / NULL_STD\n    delta = car_mean - NULL_MEAN\n\n    scenario = \"C\" if p_one < 0.05 else \"B\"\n\n    v = {\n        \"s0_car\": f\"{S0_CAR:.1f}\",\n        \"s1_car\": f\"{S1_CAR:.1f}\",\n        \"s2_car\": f\"{args.s2_car:.1f}\",\n        \"mean_car\": f\"{car_mean:.2f}\",\n        \"std_car\": f\"{car_std:.2f}\",\n        \"tsr_mean\": f\"{tsr_mean:.1f}\",\n        \"tsr_std\": f\"{tsr_std:.1f}\",\n        \"p_value\": f\"{p_one:.3f}\",\n        \"z_value\": f\"{z:.2f}\",\n        \"delta_pp\": f\"{delta:.1f}\",\n    }\n\n    print(\"=\" * 60)\n    print(\"  PAPER SWITCH — lambda=0.1 s2 30K\")\n    print(\"=\" * 60)\n    print(f\"  Input:     s2_car={args.s2_car}, s2_tsr={args.s2_tsr}\")\n    print(f\"  3-seed:    CAR = {v['mean_car']} +/- {v['std_car']}\")\n    print(f\"             TSR = {v['tsr_mean']} +/- {v['tsr_std']} ({len(tsrs)} seeds)\")\n    print(f\"  Perm test: C({len(NULL_VALUES)+len(cars)},{len(cars)}) = {n_combos}\")\n    print(f\"             p_one = {v['p_value']}  {'<' if p_one < 0.05 else '>='} 0.05\")\n    print(f\"             p_two = {p_two:.3f}\")\n    print(f\"  Z-score:   {v['z_value']}\")\n    print(f\"  Delta:     +{v['delta_pp']} pp\")\n    print(f\"  Scenario:  {scenario}  \"\n          f\"{'(modest but significant)' if scenario == 'C' else '(full redundancy)'}\")\n    print()\n\n    if not PAPER_DIR.exists():\n        print(f\"ERROR: paper dir not found: {PAPER_DIR}\")\n        sys.exit(1)\n\n    replacements = get_replacements(scenario, v)\n\n    files_content = {}\n    counts = {}\n\n    for filename, label, old, new in replacements:\n        fpath = PAPER_DIR / filename\n        if filename not in files_content:\n            if not fpath.exists():\n                print(f\"  !! {filename} not found\")\n                continue\n            files_content[filename] = fpath.read_text()\n            counts[filename] = 0\n\n        content, ok = safe_replace(files_content[filename], old, new, label)\n        files_content[filename] = content\n        if ok:\n            counts[filename] += 1\n            status = \"ok\"\n        else:\n            status = \"FAIL\"\n        print(f\"  [{status:4s}] {label:35s} {filename}\")\n\n    total = sum(counts.values())\n    n_files = sum(1 for c in counts.values() if c > 0)\n    expected = len(replacements)\n    print(f\"\\n  {total}/{expected} replacements in {n_files} files\")\n\n    if args.dry_run:\n        print(\"\\n  DRY RUN — no files modified\")\n        return\n\n    for filename, content in files_content.items():\n        fpath = PAPER_DIR / filename\n        fpath.write_text(content)\n        print(f\"  Wrote {filename} ({counts[filename]} changes)\")\n\n    print(\"\\nCompiling PDF...\")\n    try:\n        result = subprocess.run(\n            [\"latexmk\", \"-pdf\", \"-interaction=nonstopmode\", \"main.tex\"],\n            cwd=PAPER_DIR, capture_output=True, text=True, timeout=120)\n        if result.returncode == 0:\n            print(\"  PDF compiled OK\")\n        else:\n            print(\"  PDF compilation FAILED\")\n            err = result.stderr or result.stdout or \"\"\n            for line in err.split(\"\\n\")[-10:]:\n                if line.strip():\n                    print(f\"    {line}\")\n    except FileNotFoundError:\n        print(\"  latexmk not found — skipping PDF compilation\")\n    except subprocess.TimeoutExpired:\n        print(\"  PDF compilation timed out (120s)\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
      "numLines": 486,
      "startLine": 1,
      "totalLines": 486
    }
  }
}
```

</details>

---

### Assistant

_source line 57_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture. Let me analyze the current state and what needs to be done:

**M1**: claim3.tex L27 already says "within 0.33\,pp" — ✅ already correct.

**M2**: method.tex L23 already has `$\lambda \in \{0.005, 0.01, 0.1\}$` and L44 also has it — ✅ already correct.

**M3**: Statistical test unification. Let me trace through the z-test references:

**claim3.tex**:
- L7 (table caption): `$z = 1.76$, $p \approx 0.039$, $n{=}2$` — needs change to permutation test


- L33 (dose-response paragraph): `$z = 1.76$, $p \approx 0.039$` — needs change to permutation test

**appendix.tex**:
- L171: `$z = 1.76$ ($p \approx 0.039$, approximate $z$-test), a marginal departure` — needs change
- L184 (stepwise caption): `$z = 1.76$, $p \approx 0.039$` — needs change

For claim3.tex, I need to replace the z-test references with two-tailed permutation test results showing p=0.071 in the main text, with a footnote providing additional context.

In appendix.tex, I should make the permutation test the primary result and position the z-test as a secondary comparison, then update the stepwise caption similarly.

Now I'm checking paper_switch.py to understand how the permutation test values are being computed and stored. The perm_test function calculates both one-tailed and two-tailed p-values, and I can see it's currently storing the one-tailed p-value in the replacements. I need to trace through which p-value is being used where and ensure the correct values are being pulled for each location.

Looking at the task requirements, I should verify that the script outputs two-tailed p-values to the main text and one-tailed p-values to footnotes. From what I'm seeing in the code, there's a mismatch—the caption for claim3.tex is using the one-tailed p-value when it should be using two-tailed for the main text. However, the task specifies I should record any issues but not modify the script itself. - `v["p_value"]` = `p_one` (one-tailed)
- There's no separate two-tailed p variable being used in the templates.

So the script uses one-tailed p for all replacements. This is **not** what D041 decision requires. I should note this but not modify the script.

Looking at claim3.tex, some parts were already partially updated (like "within 0.33\,pp"), but the z-test references still need to be changed. The table caption on line 7 has `$z = 1.76$, $p \approx 0.039$, $n{=}2$` that needs to switch to a permutation test with two-tailed p values. The dose-response paragraph on line 33 also references the same z-test values. However, paper_switch.py still has the old text patterns and won't match the partially edited body text, so I need to identify what actually needs changing in the tex files rather than relying on the script to do it. I'm working through the specific edits needed for claim3.tex. The task requires replacing z-test references with permutation test results—using the two-tailed p-value of 0.071 in the main text and adding a footnote that explains the one-tailed p-value of 0.036 along with justification for the directional prior.

For the table caption at L7, I'm swapping out the z-statistic and its p-value for the two-tailed permutation test result. In the dose-response paragraph around L33, I need to replace the z-test notation with the permutation p-value and insert a footnote that clarifies why we're using the conservative two-tailed approach while noting the directional prior is defensible given that SDF loss is specifically designed to reduce collisions.

Now looking at the next section, I'm examining the results from increasing lambda twentyfold to 0.1, which yields a CAR of 58.25% with a narrow margin of error across two of three seeds at the 30K checkpoint. The permutation test shows this sits above the null distribution, though the evidence remains suggestive rather than conclusive given the small sample size. A stepwise check across multiple checkpoints reveals no consistent improvement, and the per-task ordering stays the same as baseline conditions, indicating the effect is dose-dependent and SDF becomes redundant at lower lambda values. I'm checking the appendix context around the permutation test discussion—it looks like there's already a detailed null distribution analysis in the surrounding section, so I should make sure the L171 revision references that existing work rather than duplicating the statistical details. The permutation test with two-tailed p ≈ 0.071 captures the marginal signal adequately without restating the full methodology. Looking at the performance metrics across different lambda values and seed configurations, I'm seeing that the lambda equals 0.005 results cluster tightly around 54.67% with minimal variation, suggesting no meaningful effect compared to LoRA alone. The lambda equals 0.01 results fall well within expected noise, but lambda equals 0.1 shows a more interesting pattern at 58.25% across two seeds. To properly assess whether this represents a real effect or just sampling variation, I'm planning to run an exact permutation test that doesn't rely on distributional assumptions, which will give me a more reliable p-value than the approximate z-test approach. I'm working through the edits to switch from z-test to permutation test statistics. For the table caption, I'll remove the z-test notation and replace it with the two-tailed permutation p-value, keeping it simpler without a footnote. Then I'll move the directional justification about the SDF loss to the main dose-response paragraph around line 33, where it fits better contextually. I'm restructuring the appendix to lead with the permutation test result, then note the approximate z-test as a secondary comparison, while acknowledging the limited statistical power from only two seeds. I see the issue—since I've already introduced the permutation test in the revised L171, starting L173 with "As a robustness check, we verify" creates redundancy. I need to reframe L173 to explain the permutation procedure itself rather than justify why we're doing it. Something like "We detail the permutation procedure:" or "The exact permutation test proceeds as follows:" would work better, keeping the methodological details but removing the redundant framing.

For this next chunk, I'm computing the permutation test by pooling the null and treatment values, enumerating all possible two-element combinations, and checking how many have means at or above the observed threshold. The result—one combination meeting the criterion out of 28 total—gives an exact p-value of approximately 0.036 (one-tailed) or 0.071 (two-tailed), which aligns closely with the approximate z-test result and confirms the signal is robust to distributional assumptions, though still inconclusive with only two observations. We compute an exact permutation test that makes no distributional assumptions. Pooling the six null values $\{57, 52.5, 55, 57, 54, 52.5\}$ and two $\lambda = 0.1$ values $\{58, 58.5\}$ into eight measurements, we enumerate all $\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\geq 58.25$. Only one combination ($\{58, 58.5\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \approx 0.036$ (two-tailed $p = 2/28 \approx 0.071$). An approximate $z$-test yields a consistent $p \approx 0.039$ ($z = 1.76$), confirming that the marginal signal remains inconclusive at $n = 2$. I'm restructuring how I present the statistical tests for the λ = 0.1 result. The permutation test gives a two-tailed p ≈ 0.071 (one-tailed p = 0.036), and the z-test yields p ≈ 0.039, both pointing to a marginal signal that's inconclusive with only two seeds. I'm consolidating these findings into a cleaner narrative that emphasizes the robustness across different statistical approaches rather than repeating the z-test result, and I'm adjusting the caption language in the appendix to be more direct about the procedure. I'm now applying all these edits to the two files—updating the statistical notation in claim3.tex and revising the permutation test language in appendix.tex.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "df61350d-62bd-4888-92f4-f4cf732a3597",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 58_

Current state:
- **M1**: claim3.tex L27 already says "within 0.33\,pp" — correct, no change needed.
- **M2**: method.tex L23 and L44 already have `\{0.005, 0.01, 0.1\}` — correct, no change needed.
- **M3**: Multiple z-test references remain. Need to fix claim3.tex (L7, L33) and appendix.tex (L171, L173, L184).
- **M3b**: paper_switch.py uses one-tailed p (`p_one`) as `p_value` for all templates — it does NOT output two-tailed to main text. Issue noted, but per instructions, won't modify the script.

Now applying M3 fixes.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "23f2f1e6-0679-4c1e-9d20-7aca4ad11ee7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 59_

<details open><summary>🔧 Tool call — Edit · `toolu_01KcCTaWED2koNsSEViaqs3g`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
  "old_string": "$\\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \\approx 0.039$, $n{=}2$) that requires additional seeds.",
  "new_string": "$\\lambda = 0.1$ shows a marginal signal ($p \\approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "7e94ab33-2fdc-40b1-b49c-8994073e975c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 60 · 2026-05-27T20:38:14.542Z_

<details><summary>↩ Tool result · `toolu_01KcCTaWED2koNsSEViaqs3g`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "bd8cbd4e-e6b3-4177-86cd-11001df41aca",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
    "oldString": "$\\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \\approx 0.039$, $n{=}2$) that requires additional seeds.",
    "newString": "$\\lambda = 0.1$ shows a marginal signal ($p \\approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds.",
    "originalFile": "\\section{Avoidance Source Diagnosis}\\label{sec:avoidance_source}\n\nFine-tuning on collision-free demonstrations produces genuine collision avoidance: LoRA-adapted Pi0.5 raises CAR by ${\\sim}$28 percentage points with zero frozen episodes. Does SDF geometric supervision contribute additional avoidance beyond what demonstrations provide? We compare LoRA-only, LoRA+SDF ($\\lambda = 0.005$), and LoRA+SDF ($\\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint.\n\n\\begin{table}[t]\n\\centering\n\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \\approx 0.039$, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\n\\label{tab:avoidance_source}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nMethod & Seeds & TSR (\\%) & CAR (\\%) & EE Disp (m) \\\\\n\\midrule\nPi0.5 baseline & 3 & 74.7\\,$\\pm$\\,1.5 & 26.8\\,$\\pm$\\,1.6 & 0.367 \\\\\n\\midrule\nLoRA-only (no SDF) & 3 & 49.7\\,$\\pm$\\,3.2 & 54.83\\,$\\pm$\\,2.25 & 0.391 \\\\\nLoRA+SDF $\\lambda{=}0.005$ & 3 & 54.0\\,$\\pm$\\,3.0 & 54.5\\,$\\pm$\\,2.29 & 0.387 \\\\\nLoRA+SDF $\\lambda{=}0.01$ & 3 & 53.8\\,$\\pm$\\,1.5 & 56.33\\,$\\pm$\\,1.61 & 0.389 \\\\\nLoRA+SDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 2 & 48.0\\,$\\pm$\\,1.4 & 58.25\\,$\\pm$\\,0.35 & 0.394 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}30K checkpoint, two of three seeds; third seed in progress.}\n\\end{table}\n\nTable~\\ref{tab:avoidance_source} shows that collision-free demonstrations alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes and displacement above 0.37\\,m, which confirms genuine avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only CAR (54.83\\%) is within 0.33\\,pp of $\\lambda = 0.005$ and statistically indistinguishable from $\\lambda = 0.01$ (56.33\\%, $p > 0.1$; Appendix~\\ref{sec:appendix_null}). A Phase~2 ablation ($\\lambda = 0$ after step 5K) yields CAR\\,=\\,57.5\\%\\footnote{Single seed (s2); computational constraints precluded additional seeds for this ablation.}; SDF gradients produce no lasting behavioral effect. The per-task CAR ordering is preserved across all conditions (chocolate\\_pudding highest, bbq\\_sauce lowest) and invariant to $\\lambda$ across a 20$\\times$ range; avoidance patterns reflect the demonstration distribution rather than geometric supervision.\n\n\\paragraph{CAR--TSR trade-off.}\\label{sec:tsr_collapse}\nFine-tuning degrades TSR by ${\\sim}$21--25\\,pp (74.7\\% $\\to$ 49.7--54.0\\%), a consequence of distributional shift from the pre-trained prior rather than learned paralysis (all models retain $>$\\,0.37\\,m displacement and 0\\% frozen episodes). The SSR/TSR ratio increases from 0.33 (baseline) to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}): among task-completing episodes, a larger fraction avoids collisions after fine-tuning.\n\n\\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}\nIncreasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, $p \\approx 0.039$). This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\linewidth]{fig5_lambda_curve}\n\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}\n\\label{fig:lambda_car}\n\\end{figure}",
    "structuredPatch": [
      {
        "oldStart": 4,
        "oldLines": 7,
        "newStart": 4,
        "newLines": 7,
        "lines": [
          " ",
          " \\begin{table}[t]",
          " \\centering",
          "-\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($z = 1.76$, $p \\approx 0.039$, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}",
          "+\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($p \\approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}",
          " \\label{tab:avoidance_source}",
          " \\vspace{2pt}",
          " \\small"
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

### Tool call

_source line 61_

<details open><summary>🔧 Tool call — Edit · `toolu_01LdB97C1a4ZCkreED4E9o5n`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
  "old_string": "above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, $p \\approx 0.039$). This departure is suggestive but inconclusive at $n = 2$.",
  "new_string": "above the null distribution (mean 54.67\\%, $\\sigma = 2.04$; two-tailed permutation $p \\approx 0.071$)\\footnote{One-tailed permutation $p = 0.036$; we report the conservative two-tailed value in the main text. A directional prior is justified because the SDF loss is designed to \\emph{reduce} collisions.}. This departure is suggestive but inconclusive at $n = 2$."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f233ba37-dcf8-4ade-b73c-00b44d4bdc59",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 62 · 2026-05-27T20:38:16.889Z_

<details><summary>↩ Tool result · `toolu_01LdB97C1a4ZCkreED4E9o5n`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b5e19978-4930-4fc6-a411-7f63b8918b1c",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
    "oldString": "above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, $p \\approx 0.039$). This departure is suggestive but inconclusive at $n = 2$.",
    "newString": "above the null distribution (mean 54.67\\%, $\\sigma = 2.04$; two-tailed permutation $p \\approx 0.071$)\\footnote{One-tailed permutation $p = 0.036$; we report the conservative two-tailed value in the main text. A directional prior is justified because the SDF loss is designed to \\emph{reduce} collisions.}. This departure is suggestive but inconclusive at $n = 2$.",
    "originalFile": "\\section{Avoidance Source Diagnosis}\\label{sec:avoidance_source}\n\nFine-tuning on collision-free demonstrations produces genuine collision avoidance: LoRA-adapted Pi0.5 raises CAR by ${\\sim}$28 percentage points with zero frozen episodes. Does SDF geometric supervision contribute additional avoidance beyond what demonstrations provide? We compare LoRA-only, LoRA+SDF ($\\lambda = 0.005$), and LoRA+SDF ($\\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint.\n\n\\begin{table}[t]\n\\centering\n\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($p \\approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\n\\label{tab:avoidance_source}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nMethod & Seeds & TSR (\\%) & CAR (\\%) & EE Disp (m) \\\\\n\\midrule\nPi0.5 baseline & 3 & 74.7\\,$\\pm$\\,1.5 & 26.8\\,$\\pm$\\,1.6 & 0.367 \\\\\n\\midrule\nLoRA-only (no SDF) & 3 & 49.7\\,$\\pm$\\,3.2 & 54.83\\,$\\pm$\\,2.25 & 0.391 \\\\\nLoRA+SDF $\\lambda{=}0.005$ & 3 & 54.0\\,$\\pm$\\,3.0 & 54.5\\,$\\pm$\\,2.29 & 0.387 \\\\\nLoRA+SDF $\\lambda{=}0.01$ & 3 & 53.8\\,$\\pm$\\,1.5 & 56.33\\,$\\pm$\\,1.61 & 0.389 \\\\\nLoRA+SDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 2 & 48.0\\,$\\pm$\\,1.4 & 58.25\\,$\\pm$\\,0.35 & 0.394 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}30K checkpoint, two of three seeds; third seed in progress.}\n\\end{table}\n\nTable~\\ref{tab:avoidance_source} shows that collision-free demonstrations alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes and displacement above 0.37\\,m, which confirms genuine avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only CAR (54.83\\%) is within 0.33\\,pp of $\\lambda = 0.005$ and statistically indistinguishable from $\\lambda = 0.01$ (56.33\\%, $p > 0.1$; Appendix~\\ref{sec:appendix_null}). A Phase~2 ablation ($\\lambda = 0$ after step 5K) yields CAR\\,=\\,57.5\\%\\footnote{Single seed (s2); computational constraints precluded additional seeds for this ablation.}; SDF gradients produce no lasting behavioral effect. The per-task CAR ordering is preserved across all conditions (chocolate\\_pudding highest, bbq\\_sauce lowest) and invariant to $\\lambda$ across a 20$\\times$ range; avoidance patterns reflect the demonstration distribution rather than geometric supervision.\n\n\\paragraph{CAR--TSR trade-off.}\\label{sec:tsr_collapse}\nFine-tuning degrades TSR by ${\\sim}$21--25\\,pp (74.7\\% $\\to$ 49.7--54.0\\%), a consequence of distributional shift from the pre-trained prior rather than learned paralysis (all models retain $>$\\,0.37\\,m displacement and 0\\% frozen episodes). The SSR/TSR ratio increases from 0.33 (baseline) to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}): among task-completing episodes, a larger fraction avoids collisions after fine-tuning.\n\n\\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}\nIncreasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, $p \\approx 0.039$). This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\linewidth]{fig5_lambda_curve}\n\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}\n\\label{fig:lambda_car}\n\\end{figure}",
    "structuredPatch": [
      {
        "oldStart": 30,
        "oldLines": 7,
        "newStart": 30,
        "newLines": 7,
        "lines": [
          " Fine-tuning degrades TSR by ${\\sim}$21--25\\,pp (74.7\\% $\\to$ 49.7--54.0\\%), a consequence of distributional shift from the pre-trained prior rather than learned paralysis (all models retain $>$\\,0.37\\,m displacement and 0\\% frozen episodes). The SSR/TSR ratio increases from 0.33 (baseline) to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}): among task-completing episodes, a larger fraction avoids collisions after fine-tuning.",
          " ",
          " \\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}",
          "-Increasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$, $z = 1.76$, $p \\approx 0.039$). This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.",
          "+Increasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$; two-tailed permutation $p \\approx 0.071$)\\footnote{One-tailed permutation $p = 0.036$; we report the conservative two-tailed value in the main text. A directional prior is justified because the SDF loss is designed to \\emph{reduce} collisions.}. This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.",
          " ",
          " \\begin{figure}[t]",
          " \\centering"
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

### Tool call

_source line 63_

<details open><summary>🔧 Tool call — Edit · `toolu_014FkMgt7AkbEmBJNQbmvYBg`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
  "old_string": "The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields $z = 1.76$ ($p \\approx 0.039$, approximate $z$-test), a marginal departure whose interpretation is limited by $n = 2$.",
  "new_string": "The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "d8ac970e-4782-4b97-aeb7-784a88e9c6e1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 64 · 2026-05-27T20:38:18.922Z_

<details><summary>↩ Tool result · `toolu_014FkMgt7AkbEmBJNQbmvYBg`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "2274bcda-4840-47c0-83aa-648a24d5c05e",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
    "oldString": "The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields $z = 1.76$ ($p \\approx 0.039$, approximate $z$-test), a marginal departure whose interpretation is limited by $n = 2$.",
    "newString": "The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.",
    "originalFile": "\\section{Displacement Distribution}\n\\label{sec:appendix_displacement}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{fig2_ee_displacement_distribution}\n\\caption{Displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap makes $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\section{Displacement Threshold Sensitivity Analysis}\n\\label{sec:appendix_threshold}\n\nTo validate the robustness of our displacement threshold $\\tau_d$, we evaluate the frozen rate across four orders of magnitude. Table~\\ref{tab:threshold_sensitivity} shows that the fake safety pattern persists across all reasonable threshold choices: A1-LoRA exhibits near-total action collapse regardless of threshold, while Pi0.5+A1 maintains 0\\% frozen rate even at the most conservative setting.\n\n\\begin{table}[h]\n\\centering\n\\caption{Frozen rate (\\% of episodes with $d_\\mathrm{max} < \\tau_d$) across threshold values.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{lccc}\n\\toprule\n$\\tau_d$ & A1-LoRA (Pi0) & Pi0.5 Baseline & Pi0.5+A1 (SDF aux) \\\\\n\\midrule\n0.001 mm (1\\,$\\mu$m) & 73.9 & 0.0 & 0.0 \\\\\n0.1 mm  & 99.6 & 0.0 & 0.0 \\\\\n1.0 mm  & 100.0 & 0.0 & 0.0 \\\\\n10 mm   & 100.0 & 0.0 & 0.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe choice of $\\tau_d = 0.1$\\,mm represents a conservative threshold: displacement below this value is physically negligible in manipulation tasks where typical action magnitudes are 1--10\\,mm per step. Even at $\\tau_d = 1$\\,$\\mu$m, 73.9\\% of A1-LoRA safe episodes are classified as frozen, while all Pi0.5 episodes remain above threshold at every level tested.\n\nTable~\\ref{tab:dfcar_threshold} extends this analysis to dfCAR across fine-tuned Pi0.5 configurations. All eight model-seed combinations yield identical dfCAR for $\\tau_d \\in [2, 200]$\\,mm. At $\\tau_d = 300$\\,mm, 0--2 episodes per seed fall below threshold (displacement 200--300\\,mm), causing $\\leq$0.5\\,pp deviation. Our conclusions hold across the entire tested range.\n\n\\begin{table}[h]\n\\centering\n\\caption{dfCAR (\\%) across displacement thresholds for fine-tuned Pi0.5 configurations ($n = 200$ episodes per seed). Values are identical across $\\tau_d \\in [2, 200]$\\,mm; at $\\tau_d = 300$\\,mm, at most 2 episodes are excluded.}\n\\label{tab:dfcar_threshold}\n\\vspace{2pt}\n\\footnotesize\n\\begin{tabular}{lcccccccc}\n\\toprule\n& \\multicolumn{8}{c}{$\\tau_d$ (mm)} \\\\\n\\cmidrule(lr){2-9}\nCondition & 2 & 5 & 10 & 20 & 50 & 100 & 200 & 300 \\\\\n\\midrule\nLoRA s0            & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nLoRA s1            & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 \\\\\nSDF $\\lambda{=}0.005$ s0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.1 \\\\\nSDF $\\lambda{=}0.005$ s1 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 \\\\\nSDF $\\lambda{=}0.005$ s2 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.3 \\\\\nSDF $\\lambda{=}0.01$ s0  & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nSDF $\\lambda{=}0.01$ s1  & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.1 \\\\\nSDF $\\lambda{=}0.01$ s2  & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Per-Task TSR Breakdown}\\label{sec:appendix_tsr_pertask}\n\nTable~\\ref{tab:per_task_tsr} decomposes TSR by task for the avoidance source attribution experiments (Section~\\ref{sec:avoidance_source}). All tasks retain meaningful success rates after fine-tuning, with Chocolate Pudding most resilient and Orange Juice most affected.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task TSR (\\%) at 30K training steps. LoRA-only reports seed~0 (rotation-fixed re-evaluation); SDF conditions report 3-seed means.}\n\\label{tab:per_task_tsr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTask & Pi0.5 Base & LoRA-only\\textsuperscript{$\\dagger$} & SDF $\\lambda{=}0.005$ & SDF $\\lambda{=}0.01$ \\\\\n & (3 seeds) & (seed 0) & (3 seeds) & (3 seeds) \\\\\n\\midrule\nOrange Juice      & 70.7 & 18.0 & 33.3 & 24.7 \\\\\nChoco.\\ Pudding   & 86.0 & 72.0 & 78.0 & 76.7 \\\\\nMilk              & 66.0 & 32.0 & 35.3 & 48.7 \\\\\nBBQ Sauce         & 76.0 & 62.0 & 69.3 & 65.3 \\\\\n\\midrule\nMean              & 74.7 & 46.0 & 54.0 & 53.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}Rotation-fixed re-evaluation; seed-1 evaluated with original rotation protocol, excluded to avoid mixing evaluation conditions.}\n\\end{table}\n\n\\section{Per-Task CAR Breakdown}\\label{sec:appendix_pertask_car}\n\nTable~\\ref{tab:per_task_car} decomposes CAR by task for all fine-tuned conditions, supporting the claim that per-task ordering is preserved across SDF loss weights (\\S\\ref{sec:avoidance_source}). Chocolate Pudding is consistently highest and BBQ Sauce consistently lowest across all conditions, including $\\lambda = 0.1$. The intermediate tasks (Orange Juice and Milk) exchange rank between seeds but remain bounded by the extremes. This invariance indicates that avoidance patterns reflect the spatial statistics of collision-free demonstrations rather than geometric supervision.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) at 30K steps. $\\lambda{=}0.005$ and $\\lambda{=}0.01$ report 3-seed means. Per-task ordering (CP highest, BBQ lowest) is preserved across all conditions.}\n\\label{tab:per_task_car}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nCondition & OJ & CP & Milk & BBQ & Agg. \\\\\n\\midrule\nLoRA s0 & 68 & 74 & 66 & 20 & 57.0 \\\\\nLoRA s1 & 54 & 68 & 72 & 16 & 52.5 \\\\\nLoRA s2 & 56 & 76 & 62 & 26 & 55.0 \\\\\nSDF $\\lambda{=}0.005$ (3-seed) & 54.0 & 72.7 & 71.3 & 20.0 & 54.5 \\\\\nSDF $\\lambda{=}0.01$ (3-seed) & 57.3 & 72.7 & 72.0 & 23.3 & 56.3 \\\\\nSDF $\\lambda{=}0.1$ s0 & 60 & 74 & 68 & 30 & 58.0 \\\\\nSDF $\\lambda{=}0.1$ s1 & 66 & 72 & 70 & 26 & 58.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor the $\\lambda = 0.1$ condition, seed~1 records avg\\_max\\_obstacle\\_displacement of 0.0553\\,m (per-task: OJ\\,=\\,0.033, CP\\,=\\,0.055, Milk\\,=\\,0.041, BBQ\\,=\\,0.093), comparable to other fine-tuned conditions and consistent with active manipulation rather than frozen behavior.\n\n\\section{Safe Success Rate Analysis}\\label{sec:appendix_ssr}\n\nTable~\\ref{tab:ssr} reports the Safe Success Rate (SSR\\,=\\,TSR\\,$\\cap$\\,CAR), the fraction of episodes achieving both task completion and collision avoidance. The SSR/TSR ratio quantifies the proportion of successful episodes that are also collision-free, controlling for task-completion rate.\n\n\\begin{table}[h]\n\\centering\n\\caption{SSR and SSR/TSR ratio across conditions. The ratio increase from 0.33 (baseline) to 0.51--0.57 (fine-tuned) indicates that CAR gains reflect learned safer execution, not reduced task exposure.}\n\\label{tab:ssr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nCondition & TSR (\\%) & CAR (\\%) & SSR (\\%) & SSR/TSR \\\\\n\\midrule\nPi0.5 baseline & 74.7 & 26.8 & 25.0\\textsuperscript{a} & 0.33 \\\\\nLoRA-only (3 seeds) & 49.7 & 54.83 & 28.3 & 0.57 \\\\\nSDF $\\lambda{=}0.005$ (3 seeds) & 54.0 & 54.5 & 27.8 & 0.51 \\\\\nSDF $\\lambda{=}0.01$ (3 seeds) & 53.8 & 56.33 & 30.2 & 0.56 \\\\\nSDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 48.0 & 58.25 & 26.5 & 0.55 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{a}Estimated; per-episode overlap unavailable for 3-seed rotation-corrected protocol. \\textsuperscript{$\\dagger$}SSR from seed~1 only; seed~0 per-episode data overwritten.}\n\\end{table}\n\n\\section{Per-Task Oracle Analysis}\n\\label{sec:appendix_pertask}\n\\label{sec:appendix_pertask_oracle}\n\nTable~\\ref{tab:oracle_pertask} shows per-task CAR for oracle refinement. On task~1 (\\texttt{chocolate\\_pudding}), where the EE is the primary collision body and the LoRA baseline achieves only 46.0\\% CAR, Oracle-adaptive improves to 55.0\\% and Oracle-feature to 47.5\\%. On the remaining tasks, all oracle variants degrade: Oracle-adaptive reduces task~0 (\\texttt{orange\\_juice}) from 96.0\\% to 82.5\\% and task~2 (\\texttt{milk}) from 98.0\\% to 77.5\\%. The SDF gradient pushes the EE away from the nearest surface, but the resulting joint-space displacement rotates intermediate arm links into obstacle volumes.\n\nThe feature-space oracle fires on nearly every timestep (241.7 refinements/episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49), and CAR (76.9\\%) shows no advantage despite 17$\\times$ more steps. The A3 learned SDF never triggers refinement (0 steps/episode), as its outputs avoid the activation threshold.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) for oracle SDF refinement variants. EE-only refinement helps only on task~1 where the EE is the primary collision body; on other tasks it trades one collision site for another.}\n\\label{tab:oracle_pertask}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & Task 0 & Task 1 & Task 2 & Task 3 & Agg. \\\\\n\\midrule\nLoRA baseline & 96.0 & 46.0 & 98.0 & 88.0 & 82.0 \\\\\n\\midrule\nOracle-adaptive & 82.5 & 55.0 & 77.5 & 85.0 & 75.0 \\\\\nOracle-fixed & 85.0 & 50.0 & 77.5 & 80.0 & 73.1 \\\\\nOracle-feature & 90.0 & 47.5 & 82.5 & 87.5 & 76.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Null Distribution for SDF Loss Weight Analysis}\n\\label{sec:appendix_null}\n\nWe construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields $z = 1.76$ ($p \\approx 0.039$, approximate $z$-test), a marginal departure whose interpretation is limited by $n = 2$.\n\nAs a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.\n\nA Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.\n\n\\section{Step-wise Checkpoint Analysis for \\texorpdfstring{$\\lambda = 0.1$}{lambda = 0.1}}\n\\label{sec:appendix_stepwise}\n\nTable~\\ref{tab:stepwise_lambda01} reports per-seed CAR at seven checkpoints for $\\lambda = 0.1$. Seed-1 data is available at 16K, 20K, 22K, and 30K; 24K--28K report seed-0 only. The seed-0 curve shows no monotonic trend through 28K; the 30K checkpoint marks the first consistent dual-seed departure from the null band, though whether this reflects a genuine late-training effect or sampling variance at $n = 2$ remains open.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).}\n\\label{tab:stepwise_lambda01}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nCheckpoint & Seed 0 & Seed 1 & Mean \\\\\n\\midrule\n16K steps & 55.5 & 56.0 & 55.75 \\\\\n20K steps & 55.0 & 56.0 & 55.5 \\\\\n22K steps & 60.5 & 56.5 & 58.5 \\\\\n24K steps & 52.5 & -- & -- \\\\\n26K steps & 53.5 & -- & -- \\\\\n28K steps & 54.5 & -- & -- \\\\\n30K steps & 58.0 & 58.5 & 58.25 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIndividual seeds exhibit checkpoint-to-checkpoint CAR fluctuations of up to 8\\,pp (seed~0: 52.5--60.5\\%), larger than the cross-seed standard deviation at any fixed checkpoint ($\\leq$2.8\\,pp). This is consistent with binomial sampling noise at $n = 50$ episodes per task ($\\sigma \\approx 7$\\,pp per task for $p \\approx 0.5$). The seed-averaged curve shows no monotonic trend, confirming that SDF loss weight does not produce a progressive training signal.\n\n\n\\section{Oracle SDF Refinement Details}\n\\label{sec:appendix_oracle}\n\nAll oracle variants replace the learned SDF decoder with ground-truth distance fields computed from the simulation geometry. Each is evaluated for 160 episodes (4 tasks $\\times$ 40).\n\n\\paragraph{Oracle-adaptive.} At each timestep, if the ground-truth SDF at the end-effector position falls below a safety margin, the action is adjusted by a step in the negative SDF gradient direction. The step size $\\alpha$ is scaled inversely with distance: smaller distances produce larger corrections. This mimics an adaptive potential field controller.\n\n\\paragraph{Oracle-fixed.} Identical to Oracle-adaptive except the step size is fixed at $\\alpha = 0.005$ regardless of distance. This isolates the effect of step-size adaptation from the refinement geometry.\n\n\\paragraph{Oracle-feature.} Instead of modifying the action directly in Cartesian space, this variant applies the SDF gradient in the policy's latent feature space via backpropagation. The gradient of the ground-truth SDF value with respect to the intermediate features is computed and used to perturb the features before the action head decodes them. This tests whether geometric corrections are more effective when applied in the model's learned representation space. In practice, the feature-space variant fires on nearly every timestep (241.7 refinements per episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49 in action space).\n\n\n\\section{Training Details}\n\\label{sec:appendix_training}\n\n\\paragraph{Architecture.}\nWe use LoRA~\\citep{hu2022lora} adapters injected into the PaliGemma vision encoder (rank 16, $\\alpha$=16) and the action expert (rank 32, $\\alpha$=32), following the configuration of OpenPi. The SDF decoder is a 4-layer MLP (hidden dimension 256) with skip connections, taking pooled suffix features (1024-d) and query points (3-d) as input. The end-effector extractor is a 2-layer MLP (1024 $\\to$ 256 $\\to$ 3).\n\n\\paragraph{Training schedule.}\nTraining proceeds in two phases:\n\\begin{itemize}\n    \\item \\textbf{Phase 1} (steps 0--5000): Backbone and LoRA parameters are frozen. Only the SDF decoder and EE extractor are trained, allowing them to learn meaningful representations before the policy adapts.\n    \\item \\textbf{Phase 2} (steps 5000--30000): LoRA parameters are unfrozen with a 100-step gradient warmup ramp. All auxiliary heads continue training jointly with the policy.\n\\end{itemize}\n\n\\paragraph{Hyperparameters.}\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters.}\n\\label{tab:hyperparams}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nBase model & Pi0.5 (OpenPi, $\\sim$3.5B parameters) \\\\\nOptimizer & AdamW \\\\\nLearning rate & $2.5 \\times 10^{-5}$ (cosine decay to $\\mathrm{lr}/10$) \\\\\nWarmup steps & 1000 \\\\\nBatch size & 32 \\\\\nTotal steps & 30000 \\\\\n$\\lambda_\\mathrm{sdf}$ & \\{0.005, 0.01, 0.1\\} \\\\\n$\\lambda_\\mathrm{ee}$ & 0.01 \\\\\nSDF query points per step & 64 \\\\\nSDF clamp $\\delta$ & 0.05 m \\\\\nEikonal weight & 0.1 \\\\\nLoRA rank (vision) & 16 \\\\\nLoRA rank (action) & 32 \\\\\nPhase 1 duration & 5000 steps \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Evaluation protocol.}\nEach episode runs for at most 300 timesteps. The policy generates a 50-step action trajectory via flow matching and executes the first 5 steps before replanning. An episode terminates early upon task completion. Collision detection uses MuJoCo's built-in contact detection: any contact between the robot and a non-target object registers as a collision. For Pi0.5 evaluations, camera images are rotated 180$^\\circ$ to match the pre-training viewpoint convention; this correction was verified to restore TSR from ${\\sim}$5\\% to ${\\sim}$52\\% while leaving CAR comparable. Oracle variants use 40 episodes per task (160 total) with a single seed; all other configurations use 50 episodes per task (200 total).\n\n\\paragraph{Data.}\nWe use the SafeLIBERO object\\_pudding suite with pre-computed SDF ground truth. SDF values are computed offline from the obstacle mesh using a dense $64^3$ voxel grid. During training, 64 query points are randomly sampled per step from this grid.\n\n\\paragraph{Computational resources.}\nAll training and evaluation experiments are conducted on NVIDIA RTX PRO 6000 GPUs (96\\,GB). Phase~1 (5K steps) takes approximately 6 hours on a single GPU; Phase~2 (25K steps) takes approximately 32 hours. Evaluation of 200 episodes requires approximately 4 hours. Across 100+ experiments (training runs, evaluations, oracle variants, and ablations), the total computational budget is approximately 700 GPU-hours.\n",
    "structuredPatch": [
      {
        "oldStart": 168,
        "oldLines": 7,
        "newStart": 168,
        "newLines": 7,
        "lines": [
          " \\section{Null Distribution for SDF Loss Weight Analysis}",
          " \\label{sec:appendix_null}",
          " ",
          "-We construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields $z = 1.76$ ($p \\approx 0.039$, approximate $z$-test), a marginal departure whose interpretation is limited by $n = 2$.",
          "+We construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.",
          " ",
          " As a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
          " "
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

### Tool call

_source line 65_

<details open><summary>🔧 Tool call — Edit · `toolu_016DPEJddN4d85qTr5KDEcWc`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
  "old_string": "As a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions.",
  "new_string": "The permutation test makes no distributional assumptions."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "e29e1ea6-e1e2-4a6d-9717-e3ca71b22374",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 66 · 2026-05-27T20:38:20.184Z_

<details><summary>↩ Tool result · `toolu_016DPEJddN4d85qTr5KDEcWc`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "08ce4207-e2d9-4a24-9d49-827b23210f05",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
    "oldString": "As a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions.",
    "newString": "The permutation test makes no distributional assumptions.",
    "originalFile": "\\section{Displacement Distribution}\n\\label{sec:appendix_displacement}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{fig2_ee_displacement_distribution}\n\\caption{Displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap makes $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\section{Displacement Threshold Sensitivity Analysis}\n\\label{sec:appendix_threshold}\n\nTo validate the robustness of our displacement threshold $\\tau_d$, we evaluate the frozen rate across four orders of magnitude. Table~\\ref{tab:threshold_sensitivity} shows that the fake safety pattern persists across all reasonable threshold choices: A1-LoRA exhibits near-total action collapse regardless of threshold, while Pi0.5+A1 maintains 0\\% frozen rate even at the most conservative setting.\n\n\\begin{table}[h]\n\\centering\n\\caption{Frozen rate (\\% of episodes with $d_\\mathrm{max} < \\tau_d$) across threshold values.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{lccc}\n\\toprule\n$\\tau_d$ & A1-LoRA (Pi0) & Pi0.5 Baseline & Pi0.5+A1 (SDF aux) \\\\\n\\midrule\n0.001 mm (1\\,$\\mu$m) & 73.9 & 0.0 & 0.0 \\\\\n0.1 mm  & 99.6 & 0.0 & 0.0 \\\\\n1.0 mm  & 100.0 & 0.0 & 0.0 \\\\\n10 mm   & 100.0 & 0.0 & 0.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe choice of $\\tau_d = 0.1$\\,mm represents a conservative threshold: displacement below this value is physically negligible in manipulation tasks where typical action magnitudes are 1--10\\,mm per step. Even at $\\tau_d = 1$\\,$\\mu$m, 73.9\\% of A1-LoRA safe episodes are classified as frozen, while all Pi0.5 episodes remain above threshold at every level tested.\n\nTable~\\ref{tab:dfcar_threshold} extends this analysis to dfCAR across fine-tuned Pi0.5 configurations. All eight model-seed combinations yield identical dfCAR for $\\tau_d \\in [2, 200]$\\,mm. At $\\tau_d = 300$\\,mm, 0--2 episodes per seed fall below threshold (displacement 200--300\\,mm), causing $\\leq$0.5\\,pp deviation. Our conclusions hold across the entire tested range.\n\n\\begin{table}[h]\n\\centering\n\\caption{dfCAR (\\%) across displacement thresholds for fine-tuned Pi0.5 configurations ($n = 200$ episodes per seed). Values are identical across $\\tau_d \\in [2, 200]$\\,mm; at $\\tau_d = 300$\\,mm, at most 2 episodes are excluded.}\n\\label{tab:dfcar_threshold}\n\\vspace{2pt}\n\\footnotesize\n\\begin{tabular}{lcccccccc}\n\\toprule\n& \\multicolumn{8}{c}{$\\tau_d$ (mm)} \\\\\n\\cmidrule(lr){2-9}\nCondition & 2 & 5 & 10 & 20 & 50 & 100 & 200 & 300 \\\\\n\\midrule\nLoRA s0            & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nLoRA s1            & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 \\\\\nSDF $\\lambda{=}0.005$ s0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.1 \\\\\nSDF $\\lambda{=}0.005$ s1 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 \\\\\nSDF $\\lambda{=}0.005$ s2 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.3 \\\\\nSDF $\\lambda{=}0.01$ s0  & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nSDF $\\lambda{=}0.01$ s1  & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.1 \\\\\nSDF $\\lambda{=}0.01$ s2  & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Per-Task TSR Breakdown}\\label{sec:appendix_tsr_pertask}\n\nTable~\\ref{tab:per_task_tsr} decomposes TSR by task for the avoidance source attribution experiments (Section~\\ref{sec:avoidance_source}). All tasks retain meaningful success rates after fine-tuning, with Chocolate Pudding most resilient and Orange Juice most affected.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task TSR (\\%) at 30K training steps. LoRA-only reports seed~0 (rotation-fixed re-evaluation); SDF conditions report 3-seed means.}\n\\label{tab:per_task_tsr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTask & Pi0.5 Base & LoRA-only\\textsuperscript{$\\dagger$} & SDF $\\lambda{=}0.005$ & SDF $\\lambda{=}0.01$ \\\\\n & (3 seeds) & (seed 0) & (3 seeds) & (3 seeds) \\\\\n\\midrule\nOrange Juice      & 70.7 & 18.0 & 33.3 & 24.7 \\\\\nChoco.\\ Pudding   & 86.0 & 72.0 & 78.0 & 76.7 \\\\\nMilk              & 66.0 & 32.0 & 35.3 & 48.7 \\\\\nBBQ Sauce         & 76.0 & 62.0 & 69.3 & 65.3 \\\\\n\\midrule\nMean              & 74.7 & 46.0 & 54.0 & 53.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}Rotation-fixed re-evaluation; seed-1 evaluated with original rotation protocol, excluded to avoid mixing evaluation conditions.}\n\\end{table}\n\n\\section{Per-Task CAR Breakdown}\\label{sec:appendix_pertask_car}\n\nTable~\\ref{tab:per_task_car} decomposes CAR by task for all fine-tuned conditions, supporting the claim that per-task ordering is preserved across SDF loss weights (\\S\\ref{sec:avoidance_source}). Chocolate Pudding is consistently highest and BBQ Sauce consistently lowest across all conditions, including $\\lambda = 0.1$. The intermediate tasks (Orange Juice and Milk) exchange rank between seeds but remain bounded by the extremes. This invariance indicates that avoidance patterns reflect the spatial statistics of collision-free demonstrations rather than geometric supervision.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) at 30K steps. $\\lambda{=}0.005$ and $\\lambda{=}0.01$ report 3-seed means. Per-task ordering (CP highest, BBQ lowest) is preserved across all conditions.}\n\\label{tab:per_task_car}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nCondition & OJ & CP & Milk & BBQ & Agg. \\\\\n\\midrule\nLoRA s0 & 68 & 74 & 66 & 20 & 57.0 \\\\\nLoRA s1 & 54 & 68 & 72 & 16 & 52.5 \\\\\nLoRA s2 & 56 & 76 & 62 & 26 & 55.0 \\\\\nSDF $\\lambda{=}0.005$ (3-seed) & 54.0 & 72.7 & 71.3 & 20.0 & 54.5 \\\\\nSDF $\\lambda{=}0.01$ (3-seed) & 57.3 & 72.7 & 72.0 & 23.3 & 56.3 \\\\\nSDF $\\lambda{=}0.1$ s0 & 60 & 74 & 68 & 30 & 58.0 \\\\\nSDF $\\lambda{=}0.1$ s1 & 66 & 72 & 70 & 26 & 58.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor the $\\lambda = 0.1$ condition, seed~1 records avg\\_max\\_obstacle\\_displacement of 0.0553\\,m (per-task: OJ\\,=\\,0.033, CP\\,=\\,0.055, Milk\\,=\\,0.041, BBQ\\,=\\,0.093), comparable to other fine-tuned conditions and consistent with active manipulation rather than frozen behavior.\n\n\\section{Safe Success Rate Analysis}\\label{sec:appendix_ssr}\n\nTable~\\ref{tab:ssr} reports the Safe Success Rate (SSR\\,=\\,TSR\\,$\\cap$\\,CAR), the fraction of episodes achieving both task completion and collision avoidance. The SSR/TSR ratio quantifies the proportion of successful episodes that are also collision-free, controlling for task-completion rate.\n\n\\begin{table}[h]\n\\centering\n\\caption{SSR and SSR/TSR ratio across conditions. The ratio increase from 0.33 (baseline) to 0.51--0.57 (fine-tuned) indicates that CAR gains reflect learned safer execution, not reduced task exposure.}\n\\label{tab:ssr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nCondition & TSR (\\%) & CAR (\\%) & SSR (\\%) & SSR/TSR \\\\\n\\midrule\nPi0.5 baseline & 74.7 & 26.8 & 25.0\\textsuperscript{a} & 0.33 \\\\\nLoRA-only (3 seeds) & 49.7 & 54.83 & 28.3 & 0.57 \\\\\nSDF $\\lambda{=}0.005$ (3 seeds) & 54.0 & 54.5 & 27.8 & 0.51 \\\\\nSDF $\\lambda{=}0.01$ (3 seeds) & 53.8 & 56.33 & 30.2 & 0.56 \\\\\nSDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 48.0 & 58.25 & 26.5 & 0.55 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{a}Estimated; per-episode overlap unavailable for 3-seed rotation-corrected protocol. \\textsuperscript{$\\dagger$}SSR from seed~1 only; seed~0 per-episode data overwritten.}\n\\end{table}\n\n\\section{Per-Task Oracle Analysis}\n\\label{sec:appendix_pertask}\n\\label{sec:appendix_pertask_oracle}\n\nTable~\\ref{tab:oracle_pertask} shows per-task CAR for oracle refinement. On task~1 (\\texttt{chocolate\\_pudding}), where the EE is the primary collision body and the LoRA baseline achieves only 46.0\\% CAR, Oracle-adaptive improves to 55.0\\% and Oracle-feature to 47.5\\%. On the remaining tasks, all oracle variants degrade: Oracle-adaptive reduces task~0 (\\texttt{orange\\_juice}) from 96.0\\% to 82.5\\% and task~2 (\\texttt{milk}) from 98.0\\% to 77.5\\%. The SDF gradient pushes the EE away from the nearest surface, but the resulting joint-space displacement rotates intermediate arm links into obstacle volumes.\n\nThe feature-space oracle fires on nearly every timestep (241.7 refinements/episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49), and CAR (76.9\\%) shows no advantage despite 17$\\times$ more steps. The A3 learned SDF never triggers refinement (0 steps/episode), as its outputs avoid the activation threshold.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) for oracle SDF refinement variants. EE-only refinement helps only on task~1 where the EE is the primary collision body; on other tasks it trades one collision site for another.}\n\\label{tab:oracle_pertask}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & Task 0 & Task 1 & Task 2 & Task 3 & Agg. \\\\\n\\midrule\nLoRA baseline & 96.0 & 46.0 & 98.0 & 88.0 & 82.0 \\\\\n\\midrule\nOracle-adaptive & 82.5 & 55.0 & 77.5 & 85.0 & 75.0 \\\\\nOracle-fixed & 85.0 & 50.0 & 77.5 & 80.0 & 73.1 \\\\\nOracle-feature & 90.0 & 47.5 & 82.5 & 87.5 & 76.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Null Distribution for SDF Loss Weight Analysis}\n\\label{sec:appendix_null}\n\nWe construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.\n\nAs a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.\n\nA Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.\n\n\\section{Step-wise Checkpoint Analysis for \\texorpdfstring{$\\lambda = 0.1$}{lambda = 0.1}}\n\\label{sec:appendix_stepwise}\n\nTable~\\ref{tab:stepwise_lambda01} reports per-seed CAR at seven checkpoints for $\\lambda = 0.1$. Seed-1 data is available at 16K, 20K, 22K, and 30K; 24K--28K report seed-0 only. The seed-0 curve shows no monotonic trend through 28K; the 30K checkpoint marks the first consistent dual-seed departure from the null band, though whether this reflects a genuine late-training effect or sampling variance at $n = 2$ remains open.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).}\n\\label{tab:stepwise_lambda01}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nCheckpoint & Seed 0 & Seed 1 & Mean \\\\\n\\midrule\n16K steps & 55.5 & 56.0 & 55.75 \\\\\n20K steps & 55.0 & 56.0 & 55.5 \\\\\n22K steps & 60.5 & 56.5 & 58.5 \\\\\n24K steps & 52.5 & -- & -- \\\\\n26K steps & 53.5 & -- & -- \\\\\n28K steps & 54.5 & -- & -- \\\\\n30K steps & 58.0 & 58.5 & 58.25 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIndividual seeds exhibit checkpoint-to-checkpoint CAR fluctuations of up to 8\\,pp (seed~0: 52.5--60.5\\%), larger than the cross-seed standard deviation at any fixed checkpoint ($\\leq$2.8\\,pp). This is consistent with binomial sampling noise at $n = 50$ episodes per task ($\\sigma \\approx 7$\\,pp per task for $p \\approx 0.5$). The seed-averaged curve shows no monotonic trend, confirming that SDF loss weight does not produce a progressive training signal.\n\n\n\\section{Oracle SDF Refinement Details}\n\\label{sec:appendix_oracle}\n\nAll oracle variants replace the learned SDF decoder with ground-truth distance fields computed from the simulation geometry. Each is evaluated for 160 episodes (4 tasks $\\times$ 40).\n\n\\paragraph{Oracle-adaptive.} At each timestep, if the ground-truth SDF at the end-effector position falls below a safety margin, the action is adjusted by a step in the negative SDF gradient direction. The step size $\\alpha$ is scaled inversely with distance: smaller distances produce larger corrections. This mimics an adaptive potential field controller.\n\n\\paragraph{Oracle-fixed.} Identical to Oracle-adaptive except the step size is fixed at $\\alpha = 0.005$ regardless of distance. This isolates the effect of step-size adaptation from the refinement geometry.\n\n\\paragraph{Oracle-feature.} Instead of modifying the action directly in Cartesian space, this variant applies the SDF gradient in the policy's latent feature space via backpropagation. The gradient of the ground-truth SDF value with respect to the intermediate features is computed and used to perturb the features before the action head decodes them. This tests whether geometric corrections are more effective when applied in the model's learned representation space. In practice, the feature-space variant fires on nearly every timestep (241.7 refinements per episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49 in action space).\n\n\n\\section{Training Details}\n\\label{sec:appendix_training}\n\n\\paragraph{Architecture.}\nWe use LoRA~\\citep{hu2022lora} adapters injected into the PaliGemma vision encoder (rank 16, $\\alpha$=16) and the action expert (rank 32, $\\alpha$=32), following the configuration of OpenPi. The SDF decoder is a 4-layer MLP (hidden dimension 256) with skip connections, taking pooled suffix features (1024-d) and query points (3-d) as input. The end-effector extractor is a 2-layer MLP (1024 $\\to$ 256 $\\to$ 3).\n\n\\paragraph{Training schedule.}\nTraining proceeds in two phases:\n\\begin{itemize}\n    \\item \\textbf{Phase 1} (steps 0--5000): Backbone and LoRA parameters are frozen. Only the SDF decoder and EE extractor are trained, allowing them to learn meaningful representations before the policy adapts.\n    \\item \\textbf{Phase 2} (steps 5000--30000): LoRA parameters are unfrozen with a 100-step gradient warmup ramp. All auxiliary heads continue training jointly with the policy.\n\\end{itemize}\n\n\\paragraph{Hyperparameters.}\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters.}\n\\label{tab:hyperparams}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nBase model & Pi0.5 (OpenPi, $\\sim$3.5B parameters) \\\\\nOptimizer & AdamW \\\\\nLearning rate & $2.5 \\times 10^{-5}$ (cosine decay to $\\mathrm{lr}/10$) \\\\\nWarmup steps & 1000 \\\\\nBatch size & 32 \\\\\nTotal steps & 30000 \\\\\n$\\lambda_\\mathrm{sdf}$ & \\{0.005, 0.01, 0.1\\} \\\\\n$\\lambda_\\mathrm{ee}$ & 0.01 \\\\\nSDF query points per step & 64 \\\\\nSDF clamp $\\delta$ & 0.05 m \\\\\nEikonal weight & 0.1 \\\\\nLoRA rank (vision) & 16 \\\\\nLoRA rank (action) & 32 \\\\\nPhase 1 duration & 5000 steps \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Evaluation protocol.}\nEach episode runs for at most 300 timesteps. The policy generates a 50-step action trajectory via flow matching and executes the first 5 steps before replanning. An episode terminates early upon task completion. Collision detection uses MuJoCo's built-in contact detection: any contact between the robot and a non-target object registers as a collision. For Pi0.5 evaluations, camera images are rotated 180$^\\circ$ to match the pre-training viewpoint convention; this correction was verified to restore TSR from ${\\sim}$5\\% to ${\\sim}$52\\% while leaving CAR comparable. Oracle variants use 40 episodes per task (160 total) with a single seed; all other configurations use 50 episodes per task (200 total).\n\n\\paragraph{Data.}\nWe use the SafeLIBERO object\\_pudding suite with pre-computed SDF ground truth. SDF values are computed offline from the obstacle mesh using a dense $64^3$ voxel grid. During training, 64 query points are randomly sampled per step from this grid.\n\n\\paragraph{Computational resources.}\nAll training and evaluation experiments are conducted on NVIDIA RTX PRO 6000 GPUs (96\\,GB). Phase~1 (5K steps) takes approximately 6 hours on a single GPU; Phase~2 (25K steps) takes approximately 32 hours. Evaluation of 200 episodes requires approximately 4 hours. Across 100+ experiments (training runs, evaluations, oracle variants, and ablations), the total computational budget is approximately 700 GPU-hours.\n",
    "structuredPatch": [
      {
        "oldStart": 170,
        "oldLines": 7,
        "newStart": 170,
        "newLines": 7,
        "lines": [
          " ",
          " We construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.",
          " ",
          "-As a robustness check, we verify the $\\lambda = 0.1$ departure with an exact permutation test that makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
          "+The permutation test makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
          " ",
          " A Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.",
          " "
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

### Tool call

_source line 67_

<details open><summary>🔧 Tool call — Edit · `toolu_018VYkoSUhX4v7xgPnz2QrDo`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
  "old_string": "This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
  "new_string": "The consistency of the exact permutation and approximate $z$-test results confirms that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f09339c4-3ec5-42d1-80b1-5a263e88c508",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 68 · 2026-05-27T20:38:21.598Z_

<details><summary>↩ Tool result · `toolu_018VYkoSUhX4v7xgPnz2QrDo`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "dd865773-f180-41ab-a658-b7226622f483",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
    "oldString": "This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
    "newString": "The consistency of the exact permutation and approximate $z$-test results confirms that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
    "originalFile": "\\section{Displacement Distribution}\n\\label{sec:appendix_displacement}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{fig2_ee_displacement_distribution}\n\\caption{Displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap makes $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\section{Displacement Threshold Sensitivity Analysis}\n\\label{sec:appendix_threshold}\n\nTo validate the robustness of our displacement threshold $\\tau_d$, we evaluate the frozen rate across four orders of magnitude. Table~\\ref{tab:threshold_sensitivity} shows that the fake safety pattern persists across all reasonable threshold choices: A1-LoRA exhibits near-total action collapse regardless of threshold, while Pi0.5+A1 maintains 0\\% frozen rate even at the most conservative setting.\n\n\\begin{table}[h]\n\\centering\n\\caption{Frozen rate (\\% of episodes with $d_\\mathrm{max} < \\tau_d$) across threshold values.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{lccc}\n\\toprule\n$\\tau_d$ & A1-LoRA (Pi0) & Pi0.5 Baseline & Pi0.5+A1 (SDF aux) \\\\\n\\midrule\n0.001 mm (1\\,$\\mu$m) & 73.9 & 0.0 & 0.0 \\\\\n0.1 mm  & 99.6 & 0.0 & 0.0 \\\\\n1.0 mm  & 100.0 & 0.0 & 0.0 \\\\\n10 mm   & 100.0 & 0.0 & 0.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe choice of $\\tau_d = 0.1$\\,mm represents a conservative threshold: displacement below this value is physically negligible in manipulation tasks where typical action magnitudes are 1--10\\,mm per step. Even at $\\tau_d = 1$\\,$\\mu$m, 73.9\\% of A1-LoRA safe episodes are classified as frozen, while all Pi0.5 episodes remain above threshold at every level tested.\n\nTable~\\ref{tab:dfcar_threshold} extends this analysis to dfCAR across fine-tuned Pi0.5 configurations. All eight model-seed combinations yield identical dfCAR for $\\tau_d \\in [2, 200]$\\,mm. At $\\tau_d = 300$\\,mm, 0--2 episodes per seed fall below threshold (displacement 200--300\\,mm), causing $\\leq$0.5\\,pp deviation. Our conclusions hold across the entire tested range.\n\n\\begin{table}[h]\n\\centering\n\\caption{dfCAR (\\%) across displacement thresholds for fine-tuned Pi0.5 configurations ($n = 200$ episodes per seed). Values are identical across $\\tau_d \\in [2, 200]$\\,mm; at $\\tau_d = 300$\\,mm, at most 2 episodes are excluded.}\n\\label{tab:dfcar_threshold}\n\\vspace{2pt}\n\\footnotesize\n\\begin{tabular}{lcccccccc}\n\\toprule\n& \\multicolumn{8}{c}{$\\tau_d$ (mm)} \\\\\n\\cmidrule(lr){2-9}\nCondition & 2 & 5 & 10 & 20 & 50 & 100 & 200 & 300 \\\\\n\\midrule\nLoRA s0            & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nLoRA s1            & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 \\\\\nSDF $\\lambda{=}0.005$ s0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.1 \\\\\nSDF $\\lambda{=}0.005$ s1 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 \\\\\nSDF $\\lambda{=}0.005$ s2 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.3 \\\\\nSDF $\\lambda{=}0.01$ s0  & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nSDF $\\lambda{=}0.01$ s1  & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.1 \\\\\nSDF $\\lambda{=}0.01$ s2  & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Per-Task TSR Breakdown}\\label{sec:appendix_tsr_pertask}\n\nTable~\\ref{tab:per_task_tsr} decomposes TSR by task for the avoidance source attribution experiments (Section~\\ref{sec:avoidance_source}). All tasks retain meaningful success rates after fine-tuning, with Chocolate Pudding most resilient and Orange Juice most affected.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task TSR (\\%) at 30K training steps. LoRA-only reports seed~0 (rotation-fixed re-evaluation); SDF conditions report 3-seed means.}\n\\label{tab:per_task_tsr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTask & Pi0.5 Base & LoRA-only\\textsuperscript{$\\dagger$} & SDF $\\lambda{=}0.005$ & SDF $\\lambda{=}0.01$ \\\\\n & (3 seeds) & (seed 0) & (3 seeds) & (3 seeds) \\\\\n\\midrule\nOrange Juice      & 70.7 & 18.0 & 33.3 & 24.7 \\\\\nChoco.\\ Pudding   & 86.0 & 72.0 & 78.0 & 76.7 \\\\\nMilk              & 66.0 & 32.0 & 35.3 & 48.7 \\\\\nBBQ Sauce         & 76.0 & 62.0 & 69.3 & 65.3 \\\\\n\\midrule\nMean              & 74.7 & 46.0 & 54.0 & 53.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}Rotation-fixed re-evaluation; seed-1 evaluated with original rotation protocol, excluded to avoid mixing evaluation conditions.}\n\\end{table}\n\n\\section{Per-Task CAR Breakdown}\\label{sec:appendix_pertask_car}\n\nTable~\\ref{tab:per_task_car} decomposes CAR by task for all fine-tuned conditions, supporting the claim that per-task ordering is preserved across SDF loss weights (\\S\\ref{sec:avoidance_source}). Chocolate Pudding is consistently highest and BBQ Sauce consistently lowest across all conditions, including $\\lambda = 0.1$. The intermediate tasks (Orange Juice and Milk) exchange rank between seeds but remain bounded by the extremes. This invariance indicates that avoidance patterns reflect the spatial statistics of collision-free demonstrations rather than geometric supervision.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) at 30K steps. $\\lambda{=}0.005$ and $\\lambda{=}0.01$ report 3-seed means. Per-task ordering (CP highest, BBQ lowest) is preserved across all conditions.}\n\\label{tab:per_task_car}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nCondition & OJ & CP & Milk & BBQ & Agg. \\\\\n\\midrule\nLoRA s0 & 68 & 74 & 66 & 20 & 57.0 \\\\\nLoRA s1 & 54 & 68 & 72 & 16 & 52.5 \\\\\nLoRA s2 & 56 & 76 & 62 & 26 & 55.0 \\\\\nSDF $\\lambda{=}0.005$ (3-seed) & 54.0 & 72.7 & 71.3 & 20.0 & 54.5 \\\\\nSDF $\\lambda{=}0.01$ (3-seed) & 57.3 & 72.7 & 72.0 & 23.3 & 56.3 \\\\\nSDF $\\lambda{=}0.1$ s0 & 60 & 74 & 68 & 30 & 58.0 \\\\\nSDF $\\lambda{=}0.1$ s1 & 66 & 72 & 70 & 26 & 58.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor the $\\lambda = 0.1$ condition, seed~1 records avg\\_max\\_obstacle\\_displacement of 0.0553\\,m (per-task: OJ\\,=\\,0.033, CP\\,=\\,0.055, Milk\\,=\\,0.041, BBQ\\,=\\,0.093), comparable to other fine-tuned conditions and consistent with active manipulation rather than frozen behavior.\n\n\\section{Safe Success Rate Analysis}\\label{sec:appendix_ssr}\n\nTable~\\ref{tab:ssr} reports the Safe Success Rate (SSR\\,=\\,TSR\\,$\\cap$\\,CAR), the fraction of episodes achieving both task completion and collision avoidance. The SSR/TSR ratio quantifies the proportion of successful episodes that are also collision-free, controlling for task-completion rate.\n\n\\begin{table}[h]\n\\centering\n\\caption{SSR and SSR/TSR ratio across conditions. The ratio increase from 0.33 (baseline) to 0.51--0.57 (fine-tuned) indicates that CAR gains reflect learned safer execution, not reduced task exposure.}\n\\label{tab:ssr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nCondition & TSR (\\%) & CAR (\\%) & SSR (\\%) & SSR/TSR \\\\\n\\midrule\nPi0.5 baseline & 74.7 & 26.8 & 25.0\\textsuperscript{a} & 0.33 \\\\\nLoRA-only (3 seeds) & 49.7 & 54.83 & 28.3 & 0.57 \\\\\nSDF $\\lambda{=}0.005$ (3 seeds) & 54.0 & 54.5 & 27.8 & 0.51 \\\\\nSDF $\\lambda{=}0.01$ (3 seeds) & 53.8 & 56.33 & 30.2 & 0.56 \\\\\nSDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 48.0 & 58.25 & 26.5 & 0.55 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{a}Estimated; per-episode overlap unavailable for 3-seed rotation-corrected protocol. \\textsuperscript{$\\dagger$}SSR from seed~1 only; seed~0 per-episode data overwritten.}\n\\end{table}\n\n\\section{Per-Task Oracle Analysis}\n\\label{sec:appendix_pertask}\n\\label{sec:appendix_pertask_oracle}\n\nTable~\\ref{tab:oracle_pertask} shows per-task CAR for oracle refinement. On task~1 (\\texttt{chocolate\\_pudding}), where the EE is the primary collision body and the LoRA baseline achieves only 46.0\\% CAR, Oracle-adaptive improves to 55.0\\% and Oracle-feature to 47.5\\%. On the remaining tasks, all oracle variants degrade: Oracle-adaptive reduces task~0 (\\texttt{orange\\_juice}) from 96.0\\% to 82.5\\% and task~2 (\\texttt{milk}) from 98.0\\% to 77.5\\%. The SDF gradient pushes the EE away from the nearest surface, but the resulting joint-space displacement rotates intermediate arm links into obstacle volumes.\n\nThe feature-space oracle fires on nearly every timestep (241.7 refinements/episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49), and CAR (76.9\\%) shows no advantage despite 17$\\times$ more steps. The A3 learned SDF never triggers refinement (0 steps/episode), as its outputs avoid the activation threshold.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) for oracle SDF refinement variants. EE-only refinement helps only on task~1 where the EE is the primary collision body; on other tasks it trades one collision site for another.}\n\\label{tab:oracle_pertask}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & Task 0 & Task 1 & Task 2 & Task 3 & Agg. \\\\\n\\midrule\nLoRA baseline & 96.0 & 46.0 & 98.0 & 88.0 & 82.0 \\\\\n\\midrule\nOracle-adaptive & 82.5 & 55.0 & 77.5 & 85.0 & 75.0 \\\\\nOracle-fixed & 85.0 & 50.0 & 77.5 & 80.0 & 73.1 \\\\\nOracle-feature & 90.0 & 47.5 & 82.5 & 87.5 & 76.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Null Distribution for SDF Loss Weight Analysis}\n\\label{sec:appendix_null}\n\nWe construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.\n\nThe permutation test makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.\n\nA Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.\n\n\\section{Step-wise Checkpoint Analysis for \\texorpdfstring{$\\lambda = 0.1$}{lambda = 0.1}}\n\\label{sec:appendix_stepwise}\n\nTable~\\ref{tab:stepwise_lambda01} reports per-seed CAR at seven checkpoints for $\\lambda = 0.1$. Seed-1 data is available at 16K, 20K, 22K, and 30K; 24K--28K report seed-0 only. The seed-0 curve shows no monotonic trend through 28K; the 30K checkpoint marks the first consistent dual-seed departure from the null band, though whether this reflects a genuine late-training effect or sampling variance at $n = 2$ remains open.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).}\n\\label{tab:stepwise_lambda01}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nCheckpoint & Seed 0 & Seed 1 & Mean \\\\\n\\midrule\n16K steps & 55.5 & 56.0 & 55.75 \\\\\n20K steps & 55.0 & 56.0 & 55.5 \\\\\n22K steps & 60.5 & 56.5 & 58.5 \\\\\n24K steps & 52.5 & -- & -- \\\\\n26K steps & 53.5 & -- & -- \\\\\n28K steps & 54.5 & -- & -- \\\\\n30K steps & 58.0 & 58.5 & 58.25 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIndividual seeds exhibit checkpoint-to-checkpoint CAR fluctuations of up to 8\\,pp (seed~0: 52.5--60.5\\%), larger than the cross-seed standard deviation at any fixed checkpoint ($\\leq$2.8\\,pp). This is consistent with binomial sampling noise at $n = 50$ episodes per task ($\\sigma \\approx 7$\\,pp per task for $p \\approx 0.5$). The seed-averaged curve shows no monotonic trend, confirming that SDF loss weight does not produce a progressive training signal.\n\n\n\\section{Oracle SDF Refinement Details}\n\\label{sec:appendix_oracle}\n\nAll oracle variants replace the learned SDF decoder with ground-truth distance fields computed from the simulation geometry. Each is evaluated for 160 episodes (4 tasks $\\times$ 40).\n\n\\paragraph{Oracle-adaptive.} At each timestep, if the ground-truth SDF at the end-effector position falls below a safety margin, the action is adjusted by a step in the negative SDF gradient direction. The step size $\\alpha$ is scaled inversely with distance: smaller distances produce larger corrections. This mimics an adaptive potential field controller.\n\n\\paragraph{Oracle-fixed.} Identical to Oracle-adaptive except the step size is fixed at $\\alpha = 0.005$ regardless of distance. This isolates the effect of step-size adaptation from the refinement geometry.\n\n\\paragraph{Oracle-feature.} Instead of modifying the action directly in Cartesian space, this variant applies the SDF gradient in the policy's latent feature space via backpropagation. The gradient of the ground-truth SDF value with respect to the intermediate features is computed and used to perturb the features before the action head decodes them. This tests whether geometric corrections are more effective when applied in the model's learned representation space. In practice, the feature-space variant fires on nearly every timestep (241.7 refinements per episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49 in action space).\n\n\n\\section{Training Details}\n\\label{sec:appendix_training}\n\n\\paragraph{Architecture.}\nWe use LoRA~\\citep{hu2022lora} adapters injected into the PaliGemma vision encoder (rank 16, $\\alpha$=16) and the action expert (rank 32, $\\alpha$=32), following the configuration of OpenPi. The SDF decoder is a 4-layer MLP (hidden dimension 256) with skip connections, taking pooled suffix features (1024-d) and query points (3-d) as input. The end-effector extractor is a 2-layer MLP (1024 $\\to$ 256 $\\to$ 3).\n\n\\paragraph{Training schedule.}\nTraining proceeds in two phases:\n\\begin{itemize}\n    \\item \\textbf{Phase 1} (steps 0--5000): Backbone and LoRA parameters are frozen. Only the SDF decoder and EE extractor are trained, allowing them to learn meaningful representations before the policy adapts.\n    \\item \\textbf{Phase 2} (steps 5000--30000): LoRA parameters are unfrozen with a 100-step gradient warmup ramp. All auxiliary heads continue training jointly with the policy.\n\\end{itemize}\n\n\\paragraph{Hyperparameters.}\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters.}\n\\label{tab:hyperparams}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nBase model & Pi0.5 (OpenPi, $\\sim$3.5B parameters) \\\\\nOptimizer & AdamW \\\\\nLearning rate & $2.5 \\times 10^{-5}$ (cosine decay to $\\mathrm{lr}/10$) \\\\\nWarmup steps & 1000 \\\\\nBatch size & 32 \\\\\nTotal steps & 30000 \\\\\n$\\lambda_\\mathrm{sdf}$ & \\{0.005, 0.01, 0.1\\} \\\\\n$\\lambda_\\mathrm{ee}$ & 0.01 \\\\\nSDF query points per step & 64 \\\\\nSDF clamp $\\delta$ & 0.05 m \\\\\nEikonal weight & 0.1 \\\\\nLoRA rank (vision) & 16 \\\\\nLoRA rank (action) & 32 \\\\\nPhase 1 duration & 5000 steps \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Evaluation protocol.}\nEach episode runs for at most 300 timesteps. The policy generates a 50-step action trajectory via flow matching and executes the first 5 steps before replanning. An episode terminates early upon task completion. Collision detection uses MuJoCo's built-in contact detection: any contact between the robot and a non-target object registers as a collision. For Pi0.5 evaluations, camera images are rotated 180$^\\circ$ to match the pre-training viewpoint convention; this correction was verified to restore TSR from ${\\sim}$5\\% to ${\\sim}$52\\% while leaving CAR comparable. Oracle variants use 40 episodes per task (160 total) with a single seed; all other configurations use 50 episodes per task (200 total).\n\n\\paragraph{Data.}\nWe use the SafeLIBERO object\\_pudding suite with pre-computed SDF ground truth. SDF values are computed offline from the obstacle mesh using a dense $64^3$ voxel grid. During training, 64 query points are randomly sampled per step from this grid.\n\n\\paragraph{Computational resources.}\nAll training and evaluation experiments are conducted on NVIDIA RTX PRO 6000 GPUs (96\\,GB). Phase~1 (5K steps) takes approximately 6 hours on a single GPU; Phase~2 (25K steps) takes approximately 32 hours. Evaluation of 200 episodes requires approximately 4 hours. Across 100+ experiments (training runs, evaluations, oracle variants, and ablations), the total computational budget is approximately 700 GPU-hours.\n",
    "structuredPatch": [
      {
        "oldStart": 170,
        "oldLines": 7,
        "newStart": 170,
        "newLines": 7,
        "lines": [
          " ",
          " We construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.",
          " ",
          "-The permutation test makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). This is consistent with the approximate $z$-test ($p \\approx 0.039$). Both tests confirm that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
          "+The permutation test makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). The consistency of the exact permutation and approximate $z$-test results confirms that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.",
          " ",
          " A Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.",
          " "
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

### Tool call

_source line 69_

<details open><summary>🔧 Tool call — Edit · `toolu_01PX42ydZPUFDAzvvqzGG2C1`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
  "old_string": "where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).",
  "new_string": "where both seeds depart marginally (two-tailed permutation $p \\approx 0.071$)."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "12c99159-fbf3-4e53-bce7-5ede21e648e4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LWWwc8VTBEu3jYcLKmwpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8872,
      "cache_read_input_tokens": 40775,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8872
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

_source line 70 · 2026-05-27T20:38:22.703Z_

<details><summary>↩ Tool result · `toolu_01PX42ydZPUFDAzvvqzGG2C1`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "16f52583-5061-470e-a872-cc02378e863f",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
    "oldString": "where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).",
    "newString": "where both seeds depart marginally (two-tailed permutation $p \\approx 0.071$).",
    "originalFile": "\\section{Displacement Distribution}\n\\label{sec:appendix_displacement}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{fig2_ee_displacement_distribution}\n\\caption{Displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap makes $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\section{Displacement Threshold Sensitivity Analysis}\n\\label{sec:appendix_threshold}\n\nTo validate the robustness of our displacement threshold $\\tau_d$, we evaluate the frozen rate across four orders of magnitude. Table~\\ref{tab:threshold_sensitivity} shows that the fake safety pattern persists across all reasonable threshold choices: A1-LoRA exhibits near-total action collapse regardless of threshold, while Pi0.5+A1 maintains 0\\% frozen rate even at the most conservative setting.\n\n\\begin{table}[h]\n\\centering\n\\caption{Frozen rate (\\% of episodes with $d_\\mathrm{max} < \\tau_d$) across threshold values.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{lccc}\n\\toprule\n$\\tau_d$ & A1-LoRA (Pi0) & Pi0.5 Baseline & Pi0.5+A1 (SDF aux) \\\\\n\\midrule\n0.001 mm (1\\,$\\mu$m) & 73.9 & 0.0 & 0.0 \\\\\n0.1 mm  & 99.6 & 0.0 & 0.0 \\\\\n1.0 mm  & 100.0 & 0.0 & 0.0 \\\\\n10 mm   & 100.0 & 0.0 & 0.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe choice of $\\tau_d = 0.1$\\,mm represents a conservative threshold: displacement below this value is physically negligible in manipulation tasks where typical action magnitudes are 1--10\\,mm per step. Even at $\\tau_d = 1$\\,$\\mu$m, 73.9\\% of A1-LoRA safe episodes are classified as frozen, while all Pi0.5 episodes remain above threshold at every level tested.\n\nTable~\\ref{tab:dfcar_threshold} extends this analysis to dfCAR across fine-tuned Pi0.5 configurations. All eight model-seed combinations yield identical dfCAR for $\\tau_d \\in [2, 200]$\\,mm. At $\\tau_d = 300$\\,mm, 0--2 episodes per seed fall below threshold (displacement 200--300\\,mm), causing $\\leq$0.5\\,pp deviation. Our conclusions hold across the entire tested range.\n\n\\begin{table}[h]\n\\centering\n\\caption{dfCAR (\\%) across displacement thresholds for fine-tuned Pi0.5 configurations ($n = 200$ episodes per seed). Values are identical across $\\tau_d \\in [2, 200]$\\,mm; at $\\tau_d = 300$\\,mm, at most 2 episodes are excluded.}\n\\label{tab:dfcar_threshold}\n\\vspace{2pt}\n\\footnotesize\n\\begin{tabular}{lcccccccc}\n\\toprule\n& \\multicolumn{8}{c}{$\\tau_d$ (mm)} \\\\\n\\cmidrule(lr){2-9}\nCondition & 2 & 5 & 10 & 20 & 50 & 100 & 200 & 300 \\\\\n\\midrule\nLoRA s0            & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nLoRA s1            & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 \\\\\nSDF $\\lambda{=}0.005$ s0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.1 \\\\\nSDF $\\lambda{=}0.005$ s1 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 & 54.0 \\\\\nSDF $\\lambda{=}0.005$ s2 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.5 & 52.3 \\\\\nSDF $\\lambda{=}0.01$ s0  & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 & 57.0 \\\\\nSDF $\\lambda{=}0.01$ s1  & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.5 & 57.1 \\\\\nSDF $\\lambda{=}0.01$ s2  & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.5 & 54.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Per-Task TSR Breakdown}\\label{sec:appendix_tsr_pertask}\n\nTable~\\ref{tab:per_task_tsr} decomposes TSR by task for the avoidance source attribution experiments (Section~\\ref{sec:avoidance_source}). All tasks retain meaningful success rates after fine-tuning, with Chocolate Pudding most resilient and Orange Juice most affected.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task TSR (\\%) at 30K training steps. LoRA-only reports seed~0 (rotation-fixed re-evaluation); SDF conditions report 3-seed means.}\n\\label{tab:per_task_tsr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTask & Pi0.5 Base & LoRA-only\\textsuperscript{$\\dagger$} & SDF $\\lambda{=}0.005$ & SDF $\\lambda{=}0.01$ \\\\\n & (3 seeds) & (seed 0) & (3 seeds) & (3 seeds) \\\\\n\\midrule\nOrange Juice      & 70.7 & 18.0 & 33.3 & 24.7 \\\\\nChoco.\\ Pudding   & 86.0 & 72.0 & 78.0 & 76.7 \\\\\nMilk              & 66.0 & 32.0 & 35.3 & 48.7 \\\\\nBBQ Sauce         & 76.0 & 62.0 & 69.3 & 65.3 \\\\\n\\midrule\nMean              & 74.7 & 46.0 & 54.0 & 53.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}Rotation-fixed re-evaluation; seed-1 evaluated with original rotation protocol, excluded to avoid mixing evaluation conditions.}\n\\end{table}\n\n\\section{Per-Task CAR Breakdown}\\label{sec:appendix_pertask_car}\n\nTable~\\ref{tab:per_task_car} decomposes CAR by task for all fine-tuned conditions, supporting the claim that per-task ordering is preserved across SDF loss weights (\\S\\ref{sec:avoidance_source}). Chocolate Pudding is consistently highest and BBQ Sauce consistently lowest across all conditions, including $\\lambda = 0.1$. The intermediate tasks (Orange Juice and Milk) exchange rank between seeds but remain bounded by the extremes. This invariance indicates that avoidance patterns reflect the spatial statistics of collision-free demonstrations rather than geometric supervision.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) at 30K steps. $\\lambda{=}0.005$ and $\\lambda{=}0.01$ report 3-seed means. Per-task ordering (CP highest, BBQ lowest) is preserved across all conditions.}\n\\label{tab:per_task_car}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nCondition & OJ & CP & Milk & BBQ & Agg. \\\\\n\\midrule\nLoRA s0 & 68 & 74 & 66 & 20 & 57.0 \\\\\nLoRA s1 & 54 & 68 & 72 & 16 & 52.5 \\\\\nLoRA s2 & 56 & 76 & 62 & 26 & 55.0 \\\\\nSDF $\\lambda{=}0.005$ (3-seed) & 54.0 & 72.7 & 71.3 & 20.0 & 54.5 \\\\\nSDF $\\lambda{=}0.01$ (3-seed) & 57.3 & 72.7 & 72.0 & 23.3 & 56.3 \\\\\nSDF $\\lambda{=}0.1$ s0 & 60 & 74 & 68 & 30 & 58.0 \\\\\nSDF $\\lambda{=}0.1$ s1 & 66 & 72 & 70 & 26 & 58.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor the $\\lambda = 0.1$ condition, seed~1 records avg\\_max\\_obstacle\\_displacement of 0.0553\\,m (per-task: OJ\\,=\\,0.033, CP\\,=\\,0.055, Milk\\,=\\,0.041, BBQ\\,=\\,0.093), comparable to other fine-tuned conditions and consistent with active manipulation rather than frozen behavior.\n\n\\section{Safe Success Rate Analysis}\\label{sec:appendix_ssr}\n\nTable~\\ref{tab:ssr} reports the Safe Success Rate (SSR\\,=\\,TSR\\,$\\cap$\\,CAR), the fraction of episodes achieving both task completion and collision avoidance. The SSR/TSR ratio quantifies the proportion of successful episodes that are also collision-free, controlling for task-completion rate.\n\n\\begin{table}[h]\n\\centering\n\\caption{SSR and SSR/TSR ratio across conditions. The ratio increase from 0.33 (baseline) to 0.51--0.57 (fine-tuned) indicates that CAR gains reflect learned safer execution, not reduced task exposure.}\n\\label{tab:ssr}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nCondition & TSR (\\%) & CAR (\\%) & SSR (\\%) & SSR/TSR \\\\\n\\midrule\nPi0.5 baseline & 74.7 & 26.8 & 25.0\\textsuperscript{a} & 0.33 \\\\\nLoRA-only (3 seeds) & 49.7 & 54.83 & 28.3 & 0.57 \\\\\nSDF $\\lambda{=}0.005$ (3 seeds) & 54.0 & 54.5 & 27.8 & 0.51 \\\\\nSDF $\\lambda{=}0.01$ (3 seeds) & 53.8 & 56.33 & 30.2 & 0.56 \\\\\nSDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 48.0 & 58.25 & 26.5 & 0.55 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{a}Estimated; per-episode overlap unavailable for 3-seed rotation-corrected protocol. \\textsuperscript{$\\dagger$}SSR from seed~1 only; seed~0 per-episode data overwritten.}\n\\end{table}\n\n\\section{Per-Task Oracle Analysis}\n\\label{sec:appendix_pertask}\n\\label{sec:appendix_pertask_oracle}\n\nTable~\\ref{tab:oracle_pertask} shows per-task CAR for oracle refinement. On task~1 (\\texttt{chocolate\\_pudding}), where the EE is the primary collision body and the LoRA baseline achieves only 46.0\\% CAR, Oracle-adaptive improves to 55.0\\% and Oracle-feature to 47.5\\%. On the remaining tasks, all oracle variants degrade: Oracle-adaptive reduces task~0 (\\texttt{orange\\_juice}) from 96.0\\% to 82.5\\% and task~2 (\\texttt{milk}) from 98.0\\% to 77.5\\%. The SDF gradient pushes the EE away from the nearest surface, but the resulting joint-space displacement rotates intermediate arm links into obstacle volumes.\n\nThe feature-space oracle fires on nearly every timestep (241.7 refinements/episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49), and CAR (76.9\\%) shows no advantage despite 17$\\times$ more steps. The A3 learned SDF never triggers refinement (0 steps/episode), as its outputs avoid the activation threshold.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task CAR (\\%) for oracle SDF refinement variants. EE-only refinement helps only on task~1 where the EE is the primary collision body; on other tasks it trades one collision site for another.}\n\\label{tab:oracle_pertask}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & Task 0 & Task 1 & Task 2 & Task 3 & Agg. \\\\\n\\midrule\nLoRA baseline & 96.0 & 46.0 & 98.0 & 88.0 & 82.0 \\\\\n\\midrule\nOracle-adaptive & 82.5 & 55.0 & 77.5 & 85.0 & 75.0 \\\\\nOracle-fixed & 85.0 & 50.0 & 77.5 & 80.0 & 73.1 \\\\\nOracle-feature & 90.0 & 47.5 & 82.5 & 87.5 & 76.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Null Distribution for SDF Loss Weight Analysis}\n\\label{sec:appendix_null}\n\nWe construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.\n\nThe permutation test makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). The consistency of the exact permutation and approximate $z$-test results confirms that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.\n\nA Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.\n\n\\section{Step-wise Checkpoint Analysis for \\texorpdfstring{$\\lambda = 0.1$}{lambda = 0.1}}\n\\label{sec:appendix_stepwise}\n\nTable~\\ref{tab:stepwise_lambda01} reports per-seed CAR at seven checkpoints for $\\lambda = 0.1$. Seed-1 data is available at 16K, 20K, 22K, and 30K; 24K--28K report seed-0 only. The seed-0 curve shows no monotonic trend through 28K; the 30K checkpoint marks the first consistent dual-seed departure from the null band, though whether this reflects a genuine late-training effect or sampling variance at $n = 2$ remains open.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).}\n\\label{tab:stepwise_lambda01}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nCheckpoint & Seed 0 & Seed 1 & Mean \\\\\n\\midrule\n16K steps & 55.5 & 56.0 & 55.75 \\\\\n20K steps & 55.0 & 56.0 & 55.5 \\\\\n22K steps & 60.5 & 56.5 & 58.5 \\\\\n24K steps & 52.5 & -- & -- \\\\\n26K steps & 53.5 & -- & -- \\\\\n28K steps & 54.5 & -- & -- \\\\\n30K steps & 58.0 & 58.5 & 58.25 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIndividual seeds exhibit checkpoint-to-checkpoint CAR fluctuations of up to 8\\,pp (seed~0: 52.5--60.5\\%), larger than the cross-seed standard deviation at any fixed checkpoint ($\\leq$2.8\\,pp). This is consistent with binomial sampling noise at $n = 50$ episodes per task ($\\sigma \\approx 7$\\,pp per task for $p \\approx 0.5$). The seed-averaged curve shows no monotonic trend, confirming that SDF loss weight does not produce a progressive training signal.\n\n\n\\section{Oracle SDF Refinement Details}\n\\label{sec:appendix_oracle}\n\nAll oracle variants replace the learned SDF decoder with ground-truth distance fields computed from the simulation geometry. Each is evaluated for 160 episodes (4 tasks $\\times$ 40).\n\n\\paragraph{Oracle-adaptive.} At each timestep, if the ground-truth SDF at the end-effector position falls below a safety margin, the action is adjusted by a step in the negative SDF gradient direction. The step size $\\alpha$ is scaled inversely with distance: smaller distances produce larger corrections. This mimics an adaptive potential field controller.\n\n\\paragraph{Oracle-fixed.} Identical to Oracle-adaptive except the step size is fixed at $\\alpha = 0.005$ regardless of distance. This isolates the effect of step-size adaptation from the refinement geometry.\n\n\\paragraph{Oracle-feature.} Instead of modifying the action directly in Cartesian space, this variant applies the SDF gradient in the policy's latent feature space via backpropagation. The gradient of the ground-truth SDF value with respect to the intermediate features is computed and used to perturb the features before the action head decodes them. This tests whether geometric corrections are more effective when applied in the model's learned representation space. In practice, the feature-space variant fires on nearly every timestep (241.7 refinements per episode vs.\\ 14.2 for Cartesian variants) but with gradient magnitudes two orders of magnitude smaller (0.004--0.006 vs.\\ 0.18--0.49 in action space).\n\n\n\\section{Training Details}\n\\label{sec:appendix_training}\n\n\\paragraph{Architecture.}\nWe use LoRA~\\citep{hu2022lora} adapters injected into the PaliGemma vision encoder (rank 16, $\\alpha$=16) and the action expert (rank 32, $\\alpha$=32), following the configuration of OpenPi. The SDF decoder is a 4-layer MLP (hidden dimension 256) with skip connections, taking pooled suffix features (1024-d) and query points (3-d) as input. The end-effector extractor is a 2-layer MLP (1024 $\\to$ 256 $\\to$ 3).\n\n\\paragraph{Training schedule.}\nTraining proceeds in two phases:\n\\begin{itemize}\n    \\item \\textbf{Phase 1} (steps 0--5000): Backbone and LoRA parameters are frozen. Only the SDF decoder and EE extractor are trained, allowing them to learn meaningful representations before the policy adapts.\n    \\item \\textbf{Phase 2} (steps 5000--30000): LoRA parameters are unfrozen with a 100-step gradient warmup ramp. All auxiliary heads continue training jointly with the policy.\n\\end{itemize}\n\n\\paragraph{Hyperparameters.}\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters.}\n\\label{tab:hyperparams}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nBase model & Pi0.5 (OpenPi, $\\sim$3.5B parameters) \\\\\nOptimizer & AdamW \\\\\nLearning rate & $2.5 \\times 10^{-5}$ (cosine decay to $\\mathrm{lr}/10$) \\\\\nWarmup steps & 1000 \\\\\nBatch size & 32 \\\\\nTotal steps & 30000 \\\\\n$\\lambda_\\mathrm{sdf}$ & \\{0.005, 0.01, 0.1\\} \\\\\n$\\lambda_\\mathrm{ee}$ & 0.01 \\\\\nSDF query points per step & 64 \\\\\nSDF clamp $\\delta$ & 0.05 m \\\\\nEikonal weight & 0.1 \\\\\nLoRA rank (vision) & 16 \\\\\nLoRA rank (action) & 32 \\\\\nPhase 1 duration & 5000 steps \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Evaluation protocol.}\nEach episode runs for at most 300 timesteps. The policy generates a 50-step action trajectory via flow matching and executes the first 5 steps before replanning. An episode terminates early upon task completion. Collision detection uses MuJoCo's built-in contact detection: any contact between the robot and a non-target object registers as a collision. For Pi0.5 evaluations, camera images are rotated 180$^\\circ$ to match the pre-training viewpoint convention; this correction was verified to restore TSR from ${\\sim}$5\\% to ${\\sim}$52\\% while leaving CAR comparable. Oracle variants use 40 episodes per task (160 total) with a single seed; all other configurations use 50 episodes per task (200 total).\n\n\\paragraph{Data.}\nWe use the SafeLIBERO object\\_pudding suite with pre-computed SDF ground truth. SDF values are computed offline from the obstacle mesh using a dense $64^3$ voxel grid. During training, 64 query points are randomly sampled per step from this grid.\n\n\\paragraph{Computational resources.}\nAll training and evaluation experiments are conducted on NVIDIA RTX PRO 6000 GPUs (96\\,GB). Phase~1 (5K steps) takes approximately 6 hours on a single GPU; Phase~2 (25K steps) takes approximately 32 hours. Evaluation of 200 episodes requires approximately 4 hours. Across 100+ experiments (training runs, evaluations, oracle variants, and ablations), the total computational budget is approximately 700 GPU-hours.\n",
    "structuredPatch": [
      {
        "oldStart": 181,
        "oldLines": 7,
        "newStart": 181,
        "newLines": 7,
        "lines": [
          " ",
          " \\begin{table}[h]",
          " \\centering",
          "-\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally ($z = 1.76$, $p \\approx 0.039$).}",
          "+\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally (two-tailed permutation $p \\approx 0.071$).}",
          " \\label{tab:stepwise_lambda01}",
          " \\vspace{2pt}",
          " \\small"
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

_source line 71_

All 6 edits applied. Let me verify the final state and check for any remaining z-test references.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "c2419ac9-440c-4823-83f9-b880816a34cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RGu1oB171caPr54nRtVmC1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7670,
      "cache_read_input_tokens": 49647,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7670
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

_source line 72_

<details open><summary>🔧 Tool call — Grep · `toolu_01CR8HPrfvQtNnncKFMwxiD3`</summary>

```json
{
  "pattern": "z.test|z-test|z = 1\\.76|z=1\\.76",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "25e476cf-9803-4597-8787-482c4ee88720",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RGu1oB171caPr54nRtVmC1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7670,
      "cache_read_input_tokens": 49647,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7670
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

_source line 73 · 2026-05-27T20:38:31.244Z_

<details><summary>↩ Tool result · `toolu_01CR8HPrfvQtNnncKFMwxiD3`</summary>

```text
docs/paper/appendix.tex:171:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "7da42509-cc15-41ca-9af3-9f399182730f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/appendix.tex:171:[Omitted long matching line]",
    "numLines": 1
  }
}
```

</details>

---

### Tool call

_source line 74_

<details open><summary>🔧 Tool call — Grep · `toolu_01WkrJjZqWYeg2iAfPXjGF6C`</summary>

```json
{
  "pattern": "p \\\\approx 0\\\\.039|p\\\\approx0\\\\.039|p{\\\\approx}0\\\\.039",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "00f6a2f5-0dcf-4ebc-8321-debdf5424584",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RGu1oB171caPr54nRtVmC1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7670,
      "cache_read_input_tokens": 49647,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7670
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

_source line 75 · 2026-05-27T20:38:32.410Z_

<details><summary>↩ Tool result · `toolu_01WkrJjZqWYeg2iAfPXjGF6C`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "c6e41387-f38a-413c-9c2b-89c938c305f0",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Assistant

_source line 76_

<details><summary>Logged reasoning block</summary>

```text
Let me check the remaining z-test reference in appendix.tex L171.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "1f147ecf-cbf3-4b99-b688-d4e629f5b1b2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015YFZajCfc5gNryZhbo136v",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 412,
      "cache_read_input_tokens": 57317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 412
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

_source line 77_

<details open><summary>🔧 Tool call — Read · `toolu_01TuCmsW29Xa4saQKnyoV4iR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
  "offset": 169,
  "limit": 8
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "56aacd54-e480-4ec8-ac29-275d986416df",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015YFZajCfc5gNryZhbo136v",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 412,
      "cache_read_input_tokens": 57317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 412
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

_source line 78 · 2026-05-27T20:38:35.593Z_

<details><summary>↩ Tool result · `toolu_01TuCmsW29Xa4saQKnyoV4iR`</summary>

```text
169	\label{sec:appendix_null}
170	
171	We construct a null distribution by pooling the three LoRA-only seeds and three $\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\% (LoRA s0, re-evaluated), 52.5\% (LoRA s1), 55.0\% (LoRA s2), 57.0\% ($\lambda{=}0.005$ s0), 54.0\% ($\lambda{=}0.005$ s1), 52.5\% ($\lambda{=}0.005$ s2), yielding mean 54.67\% and standard deviation 2.04\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\lambda = 0.005$ produces no separation from LoRA-only. The $\lambda = 0.01$ mean of 56.33\% falls within $0.8\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\lambda = 0.1$ 30K mean of 58.25\% (2 seeds) yields a two-tailed permutation $p \approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.
172	
173	The permutation test makes no distributional assumptions. Pooling the six null values $\{57, 52.5, 55, 57, 54, 52.5\}$ and two $\lambda = 0.1$ values $\{58, 58.5\}$ into eight measurements, we enumerate all $\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\geq 58.25$. Only one combination ($\{58, 58.5\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \approx 0.036$ (two-tailed $p = 2/28 \approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). The consistency of the exact permutation and approximate $z$-test results confirms that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.
174	
175	A Phase~2 ablation reinforces this conclusion. Setting $\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.
176	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "2b9f9e90-5435-4843-bb01-60e611fd7346",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
      "content": "\\label{sec:appendix_null}\n\nWe construct a null distribution by pooling the three LoRA-only seeds and three $\\lambda = 0.005$ seeds into six per-seed CAR measurements: 57.0\\% (LoRA s0, re-evaluated), 52.5\\% (LoRA s1), 55.0\\% (LoRA s2), 57.0\\% ($\\lambda{=}0.005$ s0), 54.0\\% ($\\lambda{=}0.005$ s1), 52.5\\% ($\\lambda{=}0.005$ s2), yielding mean 54.67\\% and standard deviation 2.04\\% (Bessel-corrected, $n{-}1 = 5$). We treat these as exchangeable because SDF at $\\lambda = 0.005$ produces no separation from LoRA-only. The $\\lambda = 0.01$ mean of 56.33\\% falls within $0.8\\sigma$ of this null ($p > 0.1$), consistent with seed-to-seed variation rather than a treatment effect. The $\\lambda = 0.1$ 30K mean of 58.25\\% (2 seeds) yields a two-tailed permutation $p \\approx 0.071$ (one-tailed $p = 0.036$); a $z$-test gives an approximate $p \\approx 0.039$ ($z = 1.76$). This marginal departure is inconclusive at $n = 2$.\n\nThe permutation test makes no distributional assumptions. Pooling the six null values $\\{57, 52.5, 55, 57, 54, 52.5\\}$ and two $\\lambda = 0.1$ values $\\{58, 58.5\\}$ into eight measurements, we enumerate all $\\binom{8}{2} = 28$ two-element combinations and compute the fraction whose mean $\\geq 58.25$. Only one combination ($\\{58, 58.5\\}$, mean $= 58.25$) meets this threshold, yielding an exact one-tailed permutation $p = 1/28 \\approx 0.036$ (two-tailed $p = 2/28 \\approx 0.071$, as one combination on the lower tail also reaches equal distance from the pooled mean). The consistency of the exact permutation and approximate $z$-test results confirms that the marginal signal is robust to distributional assumptions but remains inconclusive at $n = 2$.\n\nA Phase~2 ablation reinforces this conclusion. Setting $\\lambda = 0$ during Phase~2 (steps 5K--30K), so that SDF supervision is active only during auxiliary head warmup (Phase~1, steps 0--5K), yields CAR of 57.5\\% (single seed, s2). This value lies within the null range, indicating that SDF training produces no lasting behavioral effect on collision avoidance.\n",
      "numLines": 8,
      "startLine": 169,
      "totalLines": 266
    }
  }
}
```

</details>

---

### Assistant

_source line 79_

<details><summary>Logged reasoning block</summary>

```text
The remaining z-test reference in appendix.tex L171 is now properly positioned as a secondary/approximate comparison ("a $z$-test gives an approximate..."), while permutation is the primary test. And on L173, it's referenced as "$z$-test results" in the context of confirming robustness. This is the correct framing per the task.

Let me also verify claim3.tex L33 and the stepwise caption.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "06e78a8c-fa6b-4614-94fa-4a161baff8e9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XTP52YuBCm3neuscxNidSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 898,
      "cache_read_input_tokens": 57729,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 898
      },
      "output_tokens": 27,
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

_source line 80_

Good — the remaining z-test mention in appendix is now properly framed as "approximate" secondary to the permutation test. Let me verify claim3.tex and the stepwise caption.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "2ea761df-6438-42f6-8e6a-6bbfb87b334b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XTP52YuBCm3neuscxNidSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 898,
      "cache_read_input_tokens": 57729,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 898
      },
      "output_tokens": 27,
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

_source line 81_

<details open><summary>🔧 Tool call — Read · `toolu_01PgCuiFF8cCqrQyEQ471DPF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
  "offset": 5,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a4ab7551-199a-4595-ad90-951c015260d0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XTP52YuBCm3neuscxNidSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 898,
      "cache_read_input_tokens": 57729,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 898
      },
      "output_tokens": 27,
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

_source line 82 · 2026-05-27T20:38:42.301Z_

<details><summary>↩ Tool result · `toolu_01PgCuiFF8cCqrQyEQ471DPF`</summary>

```text
5	\begin{table}[t]
6	\centering
7	\caption{Avoidance source attribution on SafeLIBERO. SDF at $\lambda \leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\lambda = 0.1$ shows a marginal signal ($p \approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\% frozen rate and displacement $>$\,0.37\,m.}
8	\label{tab:avoidance_source}
9	\vspace{2pt}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "ad822ed7-beb1-4bf9-8d15-7d382eca40a4",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
      "content": "\\begin{table}[t]\n\\centering\n\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($p \\approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\n\\label{tab:avoidance_source}\n\\vspace{2pt}",
      "numLines": 5,
      "startLine": 5,
      "totalLines": 40
    }
  }
}
```

</details>

---

### Tool call

_source line 83_

<details open><summary>🔧 Tool call — Read · `toolu_0135bRR6ibCHGQGh2SYK2GKD`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
  "offset": 31,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "d53134a7-6132-4254-9b6e-58ba4c28eb54",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XTP52YuBCm3neuscxNidSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 898,
      "cache_read_input_tokens": 57729,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 898
      },
      "output_tokens": 27,
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

_source line 84 · 2026-05-27T20:38:43.250Z_

<details><summary>↩ Tool result · `toolu_0135bRR6ibCHGQGh2SYK2GKD`</summary>

```text
31	
32	\paragraph{Dose-response at higher loss weights.}\label{sec:lambda_high}
33	Increasing $\lambda$ by 20$\times$ to 0.1 yields CAR\,=\,58.25\%\,$\pm$\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\%, $\sigma = 2.04$; two-tailed permutation $p \approx 0.071$)\footnote{One-tailed permutation $p = 0.036$; we report the conservative two-tailed value in the main text. A directional prior is justified because the SDF loss is designed to \emph{reduce} collisions.}. This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\%, within 0.3$\sigma$ of the null; Appendix~\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\lambda \leq 0.01$ ($p > 0.1$), with a marginal signal at $\lambda = 0.1$ whose modest effect size (${\sim}$3.6\,pp) and limited sample preclude strong conclusions. Even at elevated $\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.
34	
35	\begin{figure}[t]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a7897fde-f70a-4232-acc2-d59b29290f4e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
      "content": "\n\\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}\nIncreasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$; two-tailed permutation $p \\approx 0.071$)\\footnote{One-tailed permutation $p = 0.036$; we report the conservative two-tailed value in the main text. A directional prior is justified because the SDF loss is designed to \\emph{reduce} collisions.}. This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.\n\n\\begin{figure}[t]",
      "numLines": 5,
      "startLine": 31,
      "totalLines": 40
    }
  }
}
```

</details>

---

### Tool call

_source line 85_

<details open><summary>🔧 Tool call — Read · `toolu_01VZsC82zwMdcFRwNGBUQqps`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
  "offset": 182,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "bf6ad4c9-1cd6-44a2-adf9-65fb35d9efca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XTP52YuBCm3neuscxNidSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 898,
      "cache_read_input_tokens": 57729,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 898
      },
      "output_tokens": 27,
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

_source line 86 · 2026-05-27T20:38:43.719Z_

<details><summary>↩ Tool result · `toolu_01VZsC82zwMdcFRwNGBUQqps`</summary>

```text
182	\begin{table}[h]
183	\centering
184	\caption{Per-seed CAR (\%) at training checkpoints for $\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\%\,$\pm$\,2.04\%) at all checkpoints except 30K, where both seeds depart marginally (two-tailed permutation $p \approx 0.071$).}
185	\label{tab:stepwise_lambda01}
186	\vspace{2pt}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "74b703ac-2fa5-424d-b06c-fe4374199382",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/appendix.tex",
      "content": "\\begin{table}[h]\n\\centering\n\\caption{Per-seed CAR (\\%) at training checkpoints for $\\lambda = 0.1$ (200 episodes each). 24K--28K: seed-0 only. Dual-seed means remain within the null band (54.67\\%\\,$\\pm$\\,2.04\\%) at all checkpoints except 30K, where both seeds depart marginally (two-tailed permutation $p \\approx 0.071$).}\n\\label{tab:stepwise_lambda01}\n\\vspace{2pt}",
      "numLines": 5,
      "startLine": 182,
      "totalLines": 266
    }
  }
}
```

</details>

---

### Assistant

_source line 87_

All edits verified. Now let me check if there's also a z-test reference in the figure caption of claim3.tex (L38) — already checked it uses `$p \approx 0.039$` which I checked above and got no matches, so it was already fine. Let me also check the abstract and discussion for `p≈0.039` or `z` references.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "eeddade3-962e-4d54-a001-179c21dd573d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013cfbc6f7fwxkU1DpEPmYk9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1283,
      "cache_read_input_tokens": 58627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1283
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

_source line 88_

<details open><summary>🔧 Tool call — Grep · `toolu_01FM7cfmB8dZ6ALM9sALiHkD`</summary>

```json
{
  "pattern": "0\\.039",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "fbf7377d-f356-46b2-a742-71d2b11df759",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013cfbc6f7fwxkU1DpEPmYk9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1283,
      "cache_read_input_tokens": 58627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1283
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

_source line 89 · 2026-05-27T20:38:50.021Z_

<details><summary>↩ Tool result · `toolu_01FM7cfmB8dZ6ALM9sALiHkD`</summary>

```text
docs/paper/claim3.tex:38:\caption{Effect of SDF loss weight $\lambda$ on CAR and TSR. $\lambda = 0$: LoRA-only. Low $\lambda$ ($\leq 0.01$) remains within the null band; $\lambda = 0.1$ (58.25\%, 2 seeds) shows a marginal departure ($p \approx 0.039$) whose per-task pattern still matches the demonstration distribution.}
docs/paper/discussion.tex:12:[Omitted long matching line]
docs/paper/abstract.tex:7:Its contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\% to 54.83\%$\,\pm\,$2.25, matching SDF-augmented training at $\lambda{=}0.005$ (54.5\%$\,\pm\,$2.29) and $\lambda{=}0.01$ (56.33\%$\,\pm\,$1.61); at $\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\%$\,\pm\,$0.35, $p{\approx}0.039$) whose per-task avoidance pattern still mirrors the demonstration distribution.
docs/paper/appendix.tex:171:[Omitted long matching line]
docs/paper/introduction.tex:20:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f9dbff85-c457-4b2b-ba06-ac268c7f1d3c",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/claim3.tex:38:\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}\ndocs/paper/discussion.tex:12:[Omitted long matching line]\ndocs/paper/abstract.tex:7:Its contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\\%$\\,\\pm\\,$0.35, $p{\\approx}0.039$) whose per-task avoidance pattern still mirrors the demonstration distribution.\ndocs/paper/appendix.tex:171:[Omitted long matching line]\ndocs/paper/introduction.tex:20:[Omitted long matching line]",
    "numLines": 5
  }
}
```

</details>

---

### Assistant

_source line 90_

<details><summary>Logged reasoning block</summary>

```text
There are more `0.039` references I need to fix:
1. **claim3.tex L38** (figure caption): `$p \approx 0.039$` — needs to change to permutation p
2. **discussion.tex L12**: has `$p \approx 0.039$`
3. **abstract.tex L7**: has `$p{\approx}0.039$`
4. **introduction.tex L20**: has reference to 0.039
5. **appendix.tex L171**: this is now the z-test reference properly framed as approximate — OK to keep


6. **claim3.tex L38, abstract.tex L7, discussion.tex L12, introduction.tex L20**: all need unification per D041 to distinguish between permutation test p-values and z-test approximations

, but the task explicitly lists only the four items under M3, so I should focus there first and note these as secondary issues.

Looking at the remaining p-value references, they all stem from the z-test result (p ≈ 0.039), but the decision requires using the two-tailed permutation p-value (p ≈ 0.071) in the main text instead. I need to systematically update these references across the files and verify what the discussion and introduction sections actually contain before making changes.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "04cf7b71-d61c-4034-8ce1-3577d54d6d95",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Zm5BUSduvB3GuknSVvNqQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 59910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
      },
      "output_tokens": 25,
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

_source line 91_

Found additional `p ≈ 0.039` references in claim3.tex L38, abstract.tex L7, discussion.tex L12, and introduction.tex L20. These also use the z-test p-value and should be unified. Let me read and fix them.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "a8b6f100-16b0-409c-b78e-9213b3a57ffe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Zm5BUSduvB3GuknSVvNqQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 59910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
      },
      "output_tokens": 25,
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

_source line 92_

<details open><summary>🔧 Tool call — Read · `toolu_01UGCGgsRb7gTGWYHoVPLAja`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
  "offset": 36,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "fab5389b-6eeb-4f64-bf3c-108cb9149467",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Zm5BUSduvB3GuknSVvNqQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 59910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
      },
      "output_tokens": 25,
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

_source line 93 · 2026-05-27T20:39:10.926Z_

<details><summary>↩ Tool result · `toolu_01UGCGgsRb7gTGWYHoVPLAja`</summary>

```text
36	\centering
37	\includegraphics[width=0.85\linewidth]{fig5_lambda_curve}
38	\caption{Effect of SDF loss weight $\lambda$ on CAR and TSR. $\lambda = 0$: LoRA-only. Low $\lambda$ ($\leq 0.01$) remains within the null band; $\lambda = 0.1$ (58.25\%, 2 seeds) shows a marginal departure ($p \approx 0.039$) whose per-task pattern still matches the demonstration distribution.}
39	\label{fig:lambda_car}
40	\end{figure}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "26b965f4-05fc-4ff0-bd95-99baa6a7f0b8",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
      "content": "\\centering\n\\includegraphics[width=0.85\\linewidth]{fig5_lambda_curve}\n\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}\n\\label{fig:lambda_car}\n\\end{figure}",
      "numLines": 5,
      "startLine": 36,
      "totalLines": 40
    }
  }
}
```

</details>

---

### Tool call

_source line 94_

<details open><summary>🔧 Tool call — Read · `toolu_01633jyAS59WTEFtEycU3Bse`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "0807a077-08be-4d8f-80f6-228d791b6373",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Zm5BUSduvB3GuknSVvNqQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 59910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
      },
      "output_tokens": 25,
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

_source line 95 · 2026-05-27T20:39:11.398Z_

<details><summary>↩ Tool result · `toolu_01633jyAS59WTEFtEycU3Bse`</summary>

```text
1	\begin{abstract}
2	Vision-Language-Action (VLA) models report high Collision Avoidance Rates (CAR) on safety benchmarks, yet we show these metrics are contaminated by action collapse.
3	On SafeLIBERO, an SDF-augmented Pi0 achieves 91.5\% CAR while 99.6\% of its safe episodes exhibit end-effector (EE) displacement below 0.1\,mm; the robot is frozen, not safe.
4	We present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\,mm threshold range.
5	We show that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.
6	It is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as the SDF gradient repels the end-effector but drives arm links into obstacles.
7	Its contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\% to 54.83\%$\,\pm\,$2.25, matching SDF-augmented training at $\lambda{=}0.005$ (54.5\%$\,\pm\,$2.29) and $\lambda{=}0.01$ (56.33\%$\,\pm\,$1.61); at $\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\%$\,\pm\,$0.35, $p{\approx}0.039$) whose per-task avoidance pattern still mirrors the demonstration distribution.
8	Per-task avoidance patterns remain identical across all conditions: collision avoidance arises from collision-free demonstration data rather than EE-only geometric supervision.
9	Displacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.
10	\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "17c508a7-6ddf-44e4-a445-be4a73af5897",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nVision-Language-Action (VLA) models report high Collision Avoidance Rates (CAR) on safety benchmarks, yet we show these metrics are contaminated by action collapse.\nOn SafeLIBERO, an SDF-augmented Pi0 achieves 91.5\\% CAR while 99.6\\% of its safe episodes exhibit end-effector (EE) displacement below 0.1\\,mm; the robot is frozen, not safe.\nWe present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\\,mm threshold range.\nWe show that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.\nIt is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as the SDF gradient repels the end-effector but drives arm links into obstacles.\nIts contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\\%$\\,\\pm\\,$0.35, $p{\\approx}0.039$) whose per-task avoidance pattern still mirrors the demonstration distribution.\nPer-task avoidance patterns remain identical across all conditions: collision avoidance arises from collision-free demonstration data rather than EE-only geometric supervision.\nDisplacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.\n\\end{abstract}",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  }
}
```

</details>

---

### Tool call

_source line 96_

<details open><summary>🔧 Tool call — Read · `toolu_01SEURRhWLCFPPqaPZzyCKsX`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "92c7aec4-1928-4918-801e-582cb19604f9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Zm5BUSduvB3GuknSVvNqQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 59910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
      },
      "output_tokens": 25,
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

_source line 97 · 2026-05-27T20:39:11.833Z_

<details><summary>↩ Tool result · `toolu_01SEURRhWLCFPPqaPZzyCKsX`</summary>

```text
1	\section{Discussion and Conclusion}\label{sec:conclusion}
2	
3	Across 100+ experiments and 6000+ evaluation episodes on two VLA model families, three findings converge: current VLA safety evaluation is structurally unreliable. Action collapse renders reported CAR illusory (\S\ref{sec:dfcar}); EE-only oracle refinement is counterproductive (\S\ref{sec:ee_only}); and collision-free demonstrations, not geometric supervision, account for all measured avoidance gains (\S\ref{sec:avoidance_source}).
4	
5	\paragraph{Why EE-only SDF fails.}
6	Two independent causes explain the null result. \textit{(i)~Demonstration data subsumes the SDF signal.} Collision-free demonstrations implicitly encode spatial avoidance; the ${\sim}$28\,pp CAR gain arises entirely from this distributional shift, with per-task ordering invariant across all SDF conditions (\S\ref{sec:avoidance_source}). At low $\lambda$, SDF is redundant; at $\lambda = 0.1$, the marginal signal preserves the same demonstration-driven pattern. \textit{(ii)~EE monitoring cannot prevent full-body collisions.} The SDF gradient acts on a single point while collisions occur along intermediate links. Oracle experiments confirm this: ground-truth SDF refinement \emph{reduces} CAR by 6--10\,pp below unrefined baselines (\S\ref{sec:ee_only}), because pushing the EE away rotates unmonitored links through obstacles. These two causes are independent; effective geometric safety requires both full-body supervision and training signals beyond demonstrations.
7	
8	\paragraph{Implications for evaluation.}
9	dfCAR corrects action-collapse contamination using only EE position logging, already available in most evaluation pipelines. The bimodal displacement distribution makes $\tau_d$ robust across five orders of magnitude. We recommend reporting both CAR and dfCAR; the gap quantifies contamination. This contamination spans a 4000$\times$ parameter range (Pi0 Full-FT ${\sim}$2.5B to Pi0+A1 ${\sim}$658K trainable), a structural consequence of evaluating avoidance without verifying motion. More broadly, safety may need to operate at the planning or joint-space constraint layer, since any EE-centric loss inherits the same blind spot.
10	
11	\paragraph{Limitations.}
12	Our evaluation covers one benchmark suite (SafeLIBERO, four tasks) and two model families (Pi0, Pi0.5). The tabletop setting with fixed-base manipulator and known obstacles may not generalize to mobile platforms and cluttered scenes. Oracle experiments used a largely frozen model (Pi0+A1, TSR${\approx}$0\%); testing on an actively moving policy would better isolate the structural limitation. The $\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \approx 0.039$) is inconclusive. Full-body SDF remains untested. Fine-tuning degrades TSR by ${\sim}$21--25\,pp, yet SSR/TSR increases from 0.33 to 0.51--0.57 (Appendix~\ref{sec:appendix_ssr}); reduced exposure alone does not explain the pattern.
13	
14	\paragraph{Future work.}
15	Three directions follow: (1) full-body SDF supervision along the kinematic chain; (2) cross-architecture evaluation on OpenVLA, RT-2, and other VLA families; (3) planning-layer safety constraints in joint space rather than EE space.
16	
17	\paragraph{Broader impact.}
18	Contaminated CAR scores allow models with no genuine avoidance to pass safety benchmarks. dfCAR exposes this gap with minimal changes to existing protocols.
19	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "5b1b5a79-8715-4aba-855a-ca74c159983f",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
      "content": "\\section{Discussion and Conclusion}\\label{sec:conclusion}\n\nAcross 100+ experiments and 6000+ evaluation episodes on two VLA model families, three findings converge: current VLA safety evaluation is structurally unreliable. Action collapse renders reported CAR illusory (\\S\\ref{sec:dfcar}); EE-only oracle refinement is counterproductive (\\S\\ref{sec:ee_only}); and collision-free demonstrations, not geometric supervision, account for all measured avoidance gains (\\S\\ref{sec:avoidance_source}).\n\n\\paragraph{Why EE-only SDF fails.}\nTwo independent causes explain the null result. \\textit{(i)~Demonstration data subsumes the SDF signal.} Collision-free demonstrations implicitly encode spatial avoidance; the ${\\sim}$28\\,pp CAR gain arises entirely from this distributional shift, with per-task ordering invariant across all SDF conditions (\\S\\ref{sec:avoidance_source}). At low $\\lambda$, SDF is redundant; at $\\lambda = 0.1$, the marginal signal preserves the same demonstration-driven pattern. \\textit{(ii)~EE monitoring cannot prevent full-body collisions.} The SDF gradient acts on a single point while collisions occur along intermediate links. Oracle experiments confirm this: ground-truth SDF refinement \\emph{reduces} CAR by 6--10\\,pp below unrefined baselines (\\S\\ref{sec:ee_only}), because pushing the EE away rotates unmonitored links through obstacles. These two causes are independent; effective geometric safety requires both full-body supervision and training signals beyond demonstrations.\n\n\\paragraph{Implications for evaluation.}\ndfCAR corrects action-collapse contamination using only EE position logging, already available in most evaluation pipelines. The bimodal displacement distribution makes $\\tau_d$ robust across five orders of magnitude. We recommend reporting both CAR and dfCAR; the gap quantifies contamination. This contamination spans a 4000$\\times$ parameter range (Pi0 Full-FT ${\\sim}$2.5B to Pi0+A1 ${\\sim}$658K trainable), a structural consequence of evaluating avoidance without verifying motion. More broadly, safety may need to operate at the planning or joint-space constraint layer, since any EE-centric loss inherits the same blind spot.\n\n\\paragraph{Limitations.}\nOur evaluation covers one benchmark suite (SafeLIBERO, four tasks) and two model families (Pi0, Pi0.5). The tabletop setting with fixed-base manipulator and known obstacles may not generalize to mobile platforms and cluttered scenes. Oracle experiments used a largely frozen model (Pi0+A1, TSR${\\approx}$0\\%); testing on an actively moving policy would better isolate the structural limitation. The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.039$) is inconclusive. Full-body SDF remains untested. Fine-tuning degrades TSR by ${\\sim}$21--25\\,pp, yet SSR/TSR increases from 0.33 to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}); reduced exposure alone does not explain the pattern.\n\n\\paragraph{Future work.}\nThree directions follow: (1) full-body SDF supervision along the kinematic chain; (2) cross-architecture evaluation on OpenVLA, RT-2, and other VLA families; (3) planning-layer safety constraints in joint space rather than EE space.\n\n\\paragraph{Broader impact.}\nContaminated CAR scores allow models with no genuine avoidance to pass safety benchmarks. dfCAR exposes this gap with minimal changes to existing protocols.\n",
      "numLines": 19,
      "startLine": 1,
      "totalLines": 19
    }
  }
}
```

</details>

---

### Tool call

_source line 98_

<details open><summary>🔧 Tool call — Read · `toolu_01CNKmPWNnRk8X4KNRKQFtRh`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "17baea3a-07ed-4126-8070-998c3e5a6a1f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Zm5BUSduvB3GuknSVvNqQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 693,
      "cache_read_input_tokens": 59910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 693
      },
      "output_tokens": 25,
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

_source line 99 · 2026-05-27T20:39:12.385Z_

<details><summary>↩ Tool result · `toolu_01CNKmPWNnRk8X4KNRKQFtRh`</summary>

```text
1	\section{Introduction}\label{sec:intro}
2	
3	Vision-Language-Action (VLA) models must avoid collisions to operate safely in physical environments~\cite{li2026vlasafety}. The SafeLIBERO benchmark~\cite{hu2025vlsa} provides the first systematic protocol for measuring collision avoidance in VLA manipulation, and recent methods, including SDF-augmented training~\cite{zhang2025safevla}, constraint-based planning~\cite{yang2025cape}, and collision-free demonstrations~\cite{cofreeevla2026}, report high Collision Avoidance Rate (CAR). Our SDF-augmented Pi0~\cite{black2024pi0} reaches 91.5\% CAR across 800 episodes. The problem appears close to solved.
4	
5	\begin{figure}[t]
6	\centering
7	\includegraphics[width=\linewidth]{fig1_teaser}
8	\caption{The fake safety problem in VLA collision avoidance evaluation. Standard CAR classifies a frozen robot as safe because it produces zero collisions (left). dfCAR filters out action-collapsed episodes where displacement falls below $\tau_d$; Pi0+A1's 91.5\% safety score drops to ${\approx}$\,0\% (center). Pi0.5 exhibits genuine avoidance with active motion above 288\,mm in all safe episodes, and dfCAR equals raw CAR (right).}
9	\label{fig:teaser}
10	\end{figure}
11	
12	It is not (Figure~\ref{fig:teaser}). Of the 732 collision-free episodes, 99.6\% exhibit displacement below 0.1\,mm; TSR is 0\% across all 800 episodes. The robot is frozen, not safe. The same pattern holds across all Pi0 configurations (Section~\ref{sec:fake_safety}). We term this \emph{fake safety}: \emph{action collapse} (near-zero actions producing zero collisions) renders reported CAR illusory, and standard evaluation cannot distinguish inaction from deliberate avoidance~\cite{karwowski2024goodhart}.
13	
14	We present a systematic investigation of this problem across the Pi0 and Pi0.5~\cite{black2024pi0} model families on SafeLIBERO, spanning 100+ experiments and 6000+ evaluation episodes. Three findings emerge.
15	
16	\textbf{Fake safety is pervasive.} We introduce displacement-filtered CAR (dfCAR), which excludes episodes below a displacement threshold $\tau_d$. dfCAR collapses Pi0+A1 from 91.5\% to ${\approx}$\,0\% (3/732 safe episodes survive). The bimodal displacement distribution makes $\tau_d$ robust across five orders of magnitude. Pi0.5 validates the metric: TSR\,=\,74.7\%, CAR\,=\,26.8\%, with every safe episode above 288\,mm displacement and dfCAR equal to raw CAR (Section~\ref{sec:fake_safety}).
17	
18	\textbf{EE-only SDF refinement is structurally counterproductive.} Three ground-truth oracle variants all achieve \emph{lower} CAR than unrefined baselines (73.1--76.9\% vs.\ 82--83\%). The SDF gradient repels the EE but rotates arm links into obstacle volumes (Section~\ref{sec:ee_only}).
19	
20	\textbf{Collision-free demonstrations are sufficient for collision avoidance.} LoRA fine-tuning on Pi0.5 raises CAR by ${\sim}$28 points (26.8\% $\to$ 54.83\%) with zero frozen episodes; adding SDF supervision at low loss weights ($\lambda \in \{0.005, 0.01\}$) produces no measurable benefit and at high $\lambda = 0.1$ yields only a marginal, inconclusive signal ($p \approx 0.039$, $n = 2$); the per-task avoidance pattern is identical with and without geometric supervision. The collision-free demonstration distribution, not EE-only SDF supervision, accounts for all observed avoidance learning on this benchmark (Section~\ref{sec:avoidance_source}).
21	
22	Our contributions are:
23	\begin{itemize}
24	    \item \textbf{dfCAR metric:} displacement-filtered CAR that separates genuine avoidance from action collapse, robust across $\tau_d \in [2, 200]$\,mm.
25	    \item \textbf{Fake safety diagnosis:} 100+ experiments across Pi0/Pi0.5 showing $>$99\% of Pi0 safe episodes are action-collapse artifacts.
26	    \item \textbf{EE-only SDF is counterproductive:} ground-truth oracle refinement \emph{reduces} CAR below unrefined baselines by redistributing collisions to unmonitored arm links.
27	    \item \textbf{Demonstration sufficiency:} on SafeLIBERO, collision-free demonstrations account for all measured CAR gains (${\sim}$28\,pp); EE-only SDF at low $\lambda$ ($\leq 0.01$) adds nothing, and at high $\lambda = 0.1$ shows only a marginal, inconclusive signal ($n = 2$) whose per-task pattern still matches the demonstration distribution.
28	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "fa5a5ea2-d68e-48d0-908e-f411f0647c14",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\\label{sec:intro}\n\nVision-Language-Action (VLA) models must avoid collisions to operate safely in physical environments~\\cite{li2026vlasafety}. The SafeLIBERO benchmark~\\cite{hu2025vlsa} provides the first systematic protocol for measuring collision avoidance in VLA manipulation, and recent methods, including SDF-augmented training~\\cite{zhang2025safevla}, constraint-based planning~\\cite{yang2025cape}, and collision-free demonstrations~\\cite{cofreeevla2026}, report high Collision Avoidance Rate (CAR). Our SDF-augmented Pi0~\\cite{black2024pi0} reaches 91.5\\% CAR across 800 episodes. The problem appears close to solved.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{fig1_teaser}\n\\caption{The fake safety problem in VLA collision avoidance evaluation. Standard CAR classifies a frozen robot as safe because it produces zero collisions (left). dfCAR filters out action-collapsed episodes where displacement falls below $\\tau_d$; Pi0+A1's 91.5\\% safety score drops to ${\\approx}$\\,0\\% (center). Pi0.5 exhibits genuine avoidance with active motion above 288\\,mm in all safe episodes, and dfCAR equals raw CAR (right).}\n\\label{fig:teaser}\n\\end{figure}\n\nIt is not (Figure~\\ref{fig:teaser}). Of the 732 collision-free episodes, 99.6\\% exhibit displacement below 0.1\\,mm; TSR is 0\\% across all 800 episodes. The robot is frozen, not safe. The same pattern holds across all Pi0 configurations (Section~\\ref{sec:fake_safety}). We term this \\emph{fake safety}: \\emph{action collapse} (near-zero actions producing zero collisions) renders reported CAR illusory, and standard evaluation cannot distinguish inaction from deliberate avoidance~\\cite{karwowski2024goodhart}.\n\nWe present a systematic investigation of this problem across the Pi0 and Pi0.5~\\cite{black2024pi0} model families on SafeLIBERO, spanning 100+ experiments and 6000+ evaluation episodes. Three findings emerge.\n\n\\textbf{Fake safety is pervasive.} We introduce displacement-filtered CAR (dfCAR), which excludes episodes below a displacement threshold $\\tau_d$. dfCAR collapses Pi0+A1 from 91.5\\% to ${\\approx}$\\,0\\% (3/732 safe episodes survive). The bimodal displacement distribution makes $\\tau_d$ robust across five orders of magnitude. Pi0.5 validates the metric: TSR\\,=\\,74.7\\%, CAR\\,=\\,26.8\\%, with every safe episode above 288\\,mm displacement and dfCAR equal to raw CAR (Section~\\ref{sec:fake_safety}).\n\n\\textbf{EE-only SDF refinement is structurally counterproductive.} Three ground-truth oracle variants all achieve \\emph{lower} CAR than unrefined baselines (73.1--76.9\\% vs.\\ 82--83\\%). The SDF gradient repels the EE but rotates arm links into obstacle volumes (Section~\\ref{sec:ee_only}).\n\n\\textbf{Collision-free demonstrations are sufficient for collision avoidance.} LoRA fine-tuning on Pi0.5 raises CAR by ${\\sim}$28 points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes; adding SDF supervision at low loss weights ($\\lambda \\in \\{0.005, 0.01\\}$) produces no measurable benefit and at high $\\lambda = 0.1$ yields only a marginal, inconclusive signal ($p \\approx 0.039$, $n = 2$); the per-task avoidance pattern is identical with and without geometric supervision. The collision-free demonstration distribution, not EE-only SDF supervision, accounts for all observed avoidance learning on this benchmark (Section~\\ref{sec:avoidance_source}).\n\nOur contributions are:\n\\begin{itemize}\n    \\item \\textbf{dfCAR metric:} displacement-filtered CAR that separates genuine avoidance from action collapse, robust across $\\tau_d \\in [2, 200]$\\,mm.\n    \\item \\textbf{Fake safety diagnosis:} 100+ experiments across Pi0/Pi0.5 showing $>$99\\% of Pi0 safe episodes are action-collapse artifacts.\n    \\item \\textbf{EE-only SDF is counterproductive:} ground-truth oracle refinement \\emph{reduces} CAR below unrefined baselines by redistributing collisions to unmonitored arm links.\n    \\item \\textbf{Demonstration sufficiency:} on SafeLIBERO, collision-free demonstrations account for all measured CAR gains (${\\sim}$28\\,pp); EE-only SDF at low $\\lambda$ ($\\leq 0.01$) adds nothing, and at high $\\lambda = 0.1$ shows only a marginal, inconclusive signal ($n = 2$) whose per-task pattern still matches the demonstration distribution.\n\\end{itemize}",
      "numLines": 28,
      "startLine": 1,
      "totalLines": 28
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
Now I see several more references to p ≈ 0.039:

1. **claim3.tex L38** (figure caption): `$p \approx 0.039$` — needs to change to `$p \approx 0.071$, two-tailed permutation test`
2. **abstract.tex L7**: `$p{\approx}0.039$` — needs to change
3. **discussion.tex L12**: `$p \approx 0.039$` — needs to change
4. **introduction.tex L20**: `$p \approx 0.039$, $n = 2$` — needs to change


5. **discussion.tex L6** looks fine — it discusses the SDF pattern at different lambda values without referencing the p-value

I need to update all four instances with the corrected p-value and add the two-tailed permutation test specification where appropriate.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "88a1f805-13fa-4135-89fb-c58ba2c2b919",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SaKme2RtapYtAcuufLat6n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4216,
      "cache_read_input_tokens": 60603,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4216
      },
      "output_tokens": 24,
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

_source line 101_

Four more `p ≈ 0.039` references remain. Fixing them all.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "1f180b81-5ab6-493d-8654-8e20cc25a993",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SaKme2RtapYtAcuufLat6n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4216,
      "cache_read_input_tokens": 60603,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4216
      },
      "output_tokens": 24,
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

_source line 102_

<details open><summary>🔧 Tool call — Edit · `toolu_0195V9PyxvXJ9k7t8xVmfXFL`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
  "old_string": "$\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.",
  "new_string": "$\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.071$, two-tailed permutation test) whose per-task pattern still matches the demonstration distribution."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "39404a9a-cda9-4195-a505-2b65a120042c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SaKme2RtapYtAcuufLat6n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4216,
      "cache_read_input_tokens": 60603,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4216
      },
      "output_tokens": 24,
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

_source line 103 · 2026-05-27T20:39:27.042Z_

<details><summary>↩ Tool result · `toolu_0195V9PyxvXJ9k7t8xVmfXFL`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "6326c9ed-5036-40bc-aa17-cc3202c8c417",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim3.tex",
    "oldString": "$\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.",
    "newString": "$\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.071$, two-tailed permutation test) whose per-task pattern still matches the demonstration distribution.",
    "originalFile": "\\section{Avoidance Source Diagnosis}\\label{sec:avoidance_source}\n\nFine-tuning on collision-free demonstrations produces genuine collision avoidance: LoRA-adapted Pi0.5 raises CAR by ${\\sim}$28 percentage points with zero frozen episodes. Does SDF geometric supervision contribute additional avoidance beyond what demonstrations provide? We compare LoRA-only, LoRA+SDF ($\\lambda = 0.005$), and LoRA+SDF ($\\lambda = 0.01$) on Pi0.5, all evaluated at the 30K-step checkpoint.\n\n\\begin{table}[t]\n\\centering\n\\caption{Avoidance source attribution on SafeLIBERO. SDF at $\\lambda \\leq 0.01$ adds no measurable CAR beyond LoRA-only ($p > 0.1$); $\\lambda = 0.1$ shows a marginal signal ($p \\approx 0.071$, two-tailed permutation test, $n{=}2$) that requires additional seeds. All fine-tuned models exhibit 0\\% frozen rate and displacement $>$\\,0.37\\,m.}\n\\label{tab:avoidance_source}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nMethod & Seeds & TSR (\\%) & CAR (\\%) & EE Disp (m) \\\\\n\\midrule\nPi0.5 baseline & 3 & 74.7\\,$\\pm$\\,1.5 & 26.8\\,$\\pm$\\,1.6 & 0.367 \\\\\n\\midrule\nLoRA-only (no SDF) & 3 & 49.7\\,$\\pm$\\,3.2 & 54.83\\,$\\pm$\\,2.25 & 0.391 \\\\\nLoRA+SDF $\\lambda{=}0.005$ & 3 & 54.0\\,$\\pm$\\,3.0 & 54.5\\,$\\pm$\\,2.29 & 0.387 \\\\\nLoRA+SDF $\\lambda{=}0.01$ & 3 & 53.8\\,$\\pm$\\,1.5 & 56.33\\,$\\pm$\\,1.61 & 0.389 \\\\\nLoRA+SDF $\\lambda{=}0.1$\\textsuperscript{$\\dagger$} & 2 & 48.0\\,$\\pm$\\,1.4 & 58.25\\,$\\pm$\\,0.35 & 0.394 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}30K checkpoint, two of three seeds; third seed in progress.}\n\\end{table}\n\nTable~\\ref{tab:avoidance_source} shows that collision-free demonstrations alone raise CAR by ${\\sim}$28 percentage points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes and displacement above 0.37\\,m, which confirms genuine avoidance. Adding SDF supervision produces no measurable benefit: LoRA-only CAR (54.83\\%) is within 0.33\\,pp of $\\lambda = 0.005$ and statistically indistinguishable from $\\lambda = 0.01$ (56.33\\%, $p > 0.1$; Appendix~\\ref{sec:appendix_null}). A Phase~2 ablation ($\\lambda = 0$ after step 5K) yields CAR\\,=\\,57.5\\%\\footnote{Single seed (s2); computational constraints precluded additional seeds for this ablation.}; SDF gradients produce no lasting behavioral effect. The per-task CAR ordering is preserved across all conditions (chocolate\\_pudding highest, bbq\\_sauce lowest) and invariant to $\\lambda$ across a 20$\\times$ range; avoidance patterns reflect the demonstration distribution rather than geometric supervision.\n\n\\paragraph{CAR--TSR trade-off.}\\label{sec:tsr_collapse}\nFine-tuning degrades TSR by ${\\sim}$21--25\\,pp (74.7\\% $\\to$ 49.7--54.0\\%), a consequence of distributional shift from the pre-trained prior rather than learned paralysis (all models retain $>$\\,0.37\\,m displacement and 0\\% frozen episodes). The SSR/TSR ratio increases from 0.33 (baseline) to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}): among task-completing episodes, a larger fraction avoids collisions after fine-tuning.\n\n\\paragraph{Dose-response at higher loss weights.}\\label{sec:lambda_high}\nIncreasing $\\lambda$ by 20$\\times$ to 0.1 yields CAR\\,=\\,58.25\\%\\,$\\pm$\\,0.35 at the 30K checkpoint (two of three seeds), above the null distribution (mean 54.67\\%, $\\sigma = 2.04$; two-tailed permutation $p \\approx 0.071$)\\footnote{One-tailed permutation $p = 0.036$; we report the conservative two-tailed value in the main text. A directional prior is justified because the SDF loss is designed to \\emph{reduce} collisions.}. This departure is suggestive but inconclusive at $n = 2$. A stepwise ablation across six checkpoints (16K--28K) shows no sustained trend (mean 55.3\\%, within 0.3$\\sigma$ of the null; Appendix~\\ref{sec:appendix_stepwise}), and per-task CAR ordering at 30K remains identical to all other conditions (Figure~\\ref{fig:lambda_car}). The response is thus dose-dependent: SDF is fully redundant at $\\lambda \\leq 0.01$ ($p > 0.1$), with a marginal signal at $\\lambda = 0.1$ whose modest effect size (${\\sim}$3.6\\,pp) and limited sample preclude strong conclusions. Even at elevated $\\lambda$, avoidance patterns remain driven by demonstration distribution rather than geometric supervision.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\linewidth]{fig5_lambda_curve}\n\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}\n\\label{fig:lambda_car}\n\\end{figure}",
    "structuredPatch": [
      {
        "oldStart": 35,
        "oldLines": 6,
        "newStart": 35,
        "newLines": 6,
        "lines": [
          " \\begin{figure}[t]",
          " \\centering",
          " \\includegraphics[width=0.85\\linewidth]{fig5_lambda_curve}",
          "-\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.039$) whose per-task pattern still matches the demonstration distribution.}",
          "+\\caption{Effect of SDF loss weight $\\lambda$ on CAR and TSR. $\\lambda = 0$: LoRA-only. Low $\\lambda$ ($\\leq 0.01$) remains within the null band; $\\lambda = 0.1$ (58.25\\%, 2 seeds) shows a marginal departure ($p \\approx 0.071$, two-tailed permutation test) whose per-task pattern still matches the demonstration distribution.}",
          " \\label{fig:lambda_car}",
          " \\end{figure}",
          "\\ No newline at end of file"
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

### Tool call

_source line 104_

<details open><summary>🔧 Tool call — Edit · `toolu_01QgLJ3beVYdTPQ3YDaG9E9E`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex",
  "old_string": "$p{\\approx}0.039$",
  "new_string": "$p{\\approx}0.071$, two-tailed permutation test"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "96725dfd-d57d-4ada-8e06-a4bbb8dd04c9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SaKme2RtapYtAcuufLat6n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4216,
      "cache_read_input_tokens": 60603,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4216
      },
      "output_tokens": 24,
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

_source line 105 · 2026-05-27T20:39:28.385Z_

<details><summary>↩ Tool result · `toolu_01QgLJ3beVYdTPQ3YDaG9E9E`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b884e783-9292-450a-8e8b-16353ca868da",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex",
    "oldString": "$p{\\approx}0.039$",
    "newString": "$p{\\approx}0.071$, two-tailed permutation test",
    "originalFile": "\\begin{abstract}\nVision-Language-Action (VLA) models report high Collision Avoidance Rates (CAR) on safety benchmarks, yet we show these metrics are contaminated by action collapse.\nOn SafeLIBERO, an SDF-augmented Pi0 achieves 91.5\\% CAR while 99.6\\% of its safe episodes exhibit end-effector (EE) displacement below 0.1\\,mm; the robot is frozen, not safe.\nWe present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\\,mm threshold range.\nWe show that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.\nIt is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as the SDF gradient repels the end-effector but drives arm links into obstacles.\nIts contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\\%$\\,\\pm\\,$0.35, $p{\\approx}0.039$) whose per-task avoidance pattern still mirrors the demonstration distribution.\nPer-task avoidance patterns remain identical across all conditions: collision avoidance arises from collision-free demonstration data rather than EE-only geometric supervision.\nDisplacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.\n\\end{abstract}",
    "structuredPatch": [
      {
        "oldStart": 4,
        "oldLines": 7,
        "newStart": 4,
        "newLines": 7,
        "lines": [
          " We present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\\,mm threshold range.",
          " We show that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.",
          " It is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as the SDF gradient repels the end-effector but drives arm links into obstacles.",
          "-Its contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\\%$\\,\\pm\\,$0.35, $p{\\approx}0.039$) whose per-task avoidance pattern still mirrors the demonstration distribution.",
          "+Its contribution during training is dose-dependent: LoRA-only fine-tuning raises dfCAR from 26.8\\% to 54.83\\%$\\,\\pm\\,$2.25, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61); at $\\lambda{=}0.1$, two of three seeds show a marginal signal (58.25\\%$\\,\\pm\\,$0.35, $p{\\approx}0.071$, two-tailed permutation test) whose per-task avoidance pattern still mirrors the demonstration distribution.",
          " Per-task avoidance patterns remain identical across all conditions: collision avoidance arises from collision-free demonstration data rather than EE-only geometric supervision.",
          " Displacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.",
          " \\end{abstract}",
          "\\ No newline at end of file"
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

### Tool call

_source line 106_

<details open><summary>🔧 Tool call — Edit · `toolu_01CGoGJZoUZrJVuHWqi5woLr`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
  "old_string": "The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.039$) is inconclusive.",
  "new_string": "The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.071$, two-tailed permutation test) is inconclusive."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "70661d88-a35b-4f05-a444-395fd6fe94db",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SaKme2RtapYtAcuufLat6n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4216,
      "cache_read_input_tokens": 60603,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4216
      },
      "output_tokens": 24,
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

_source line 107 · 2026-05-27T20:39:29.999Z_

<details><summary>↩ Tool result · `toolu_01CGoGJZoUZrJVuHWqi5woLr`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "6dc56a53-33a1-4c4d-a66a-37b74e317943",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
    "oldString": "The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.039$) is inconclusive.",
    "newString": "The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.071$, two-tailed permutation test) is inconclusive.",
    "originalFile": "\\section{Discussion and Conclusion}\\label{sec:conclusion}\n\nAcross 100+ experiments and 6000+ evaluation episodes on two VLA model families, three findings converge: current VLA safety evaluation is structurally unreliable. Action collapse renders reported CAR illusory (\\S\\ref{sec:dfcar}); EE-only oracle refinement is counterproductive (\\S\\ref{sec:ee_only}); and collision-free demonstrations, not geometric supervision, account for all measured avoidance gains (\\S\\ref{sec:avoidance_source}).\n\n\\paragraph{Why EE-only SDF fails.}\nTwo independent causes explain the null result. \\textit{(i)~Demonstration data subsumes the SDF signal.} Collision-free demonstrations implicitly encode spatial avoidance; the ${\\sim}$28\\,pp CAR gain arises entirely from this distributional shift, with per-task ordering invariant across all SDF conditions (\\S\\ref{sec:avoidance_source}). At low $\\lambda$, SDF is redundant; at $\\lambda = 0.1$, the marginal signal preserves the same demonstration-driven pattern. \\textit{(ii)~EE monitoring cannot prevent full-body collisions.} The SDF gradient acts on a single point while collisions occur along intermediate links. Oracle experiments confirm this: ground-truth SDF refinement \\emph{reduces} CAR by 6--10\\,pp below unrefined baselines (\\S\\ref{sec:ee_only}), because pushing the EE away rotates unmonitored links through obstacles. These two causes are independent; effective geometric safety requires both full-body supervision and training signals beyond demonstrations.\n\n\\paragraph{Implications for evaluation.}\ndfCAR corrects action-collapse contamination using only EE position logging, already available in most evaluation pipelines. The bimodal displacement distribution makes $\\tau_d$ robust across five orders of magnitude. We recommend reporting both CAR and dfCAR; the gap quantifies contamination. This contamination spans a 4000$\\times$ parameter range (Pi0 Full-FT ${\\sim}$2.5B to Pi0+A1 ${\\sim}$658K trainable), a structural consequence of evaluating avoidance without verifying motion. More broadly, safety may need to operate at the planning or joint-space constraint layer, since any EE-centric loss inherits the same blind spot.\n\n\\paragraph{Limitations.}\nOur evaluation covers one benchmark suite (SafeLIBERO, four tasks) and two model families (Pi0, Pi0.5). The tabletop setting with fixed-base manipulator and known obstacles may not generalize to mobile platforms and cluttered scenes. Oracle experiments used a largely frozen model (Pi0+A1, TSR${\\approx}$0\\%); testing on an actively moving policy would better isolate the structural limitation. The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.039$) is inconclusive. Full-body SDF remains untested. Fine-tuning degrades TSR by ${\\sim}$21--25\\,pp, yet SSR/TSR increases from 0.33 to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}); reduced exposure alone does not explain the pattern.\n\n\\paragraph{Future work.}\nThree directions follow: (1) full-body SDF supervision along the kinematic chain; (2) cross-architecture evaluation on OpenVLA, RT-2, and other VLA families; (3) planning-layer safety constraints in joint space rather than EE space.\n\n\\paragraph{Broader impact.}\nContaminated CAR scores allow models with no genuine avoidance to pass safety benchmarks. dfCAR exposes this gap with minimal changes to existing protocols.\n",
    "structuredPatch": [
      {
        "oldStart": 9,
        "oldLines": 7,
        "newStart": 9,
        "newLines": 7,
        "lines": [
          " dfCAR corrects action-collapse contamination using only EE position logging, already available in most evaluation pipelines. The bimodal displacement distribution makes $\\tau_d$ robust across five orders of magnitude. We recommend reporting both CAR and dfCAR; the gap quantifies contamination. This contamination spans a 4000$\\times$ parameter range (Pi0 Full-FT ${\\sim}$2.5B to Pi0+A1 ${\\sim}$658K trainable), a structural consequence of evaluating avoidance without verifying motion. More broadly, safety may need to operate at the planning or joint-space constraint layer, since any EE-centric loss inherits the same blind spot.",
          " ",
          " \\paragraph{Limitations.}",
          "-Our evaluation covers one benchmark suite (SafeLIBERO, four tasks) and two model families (Pi0, Pi0.5). The tabletop setting with fixed-base manipulator and known obstacles may not generalize to mobile platforms and cluttered scenes. Oracle experiments used a largely frozen model (Pi0+A1, TSR${\\approx}$0\\%); testing on an actively moving policy would better isolate the structural limitation. The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.039$) is inconclusive. Full-body SDF remains untested. Fine-tuning degrades TSR by ${\\sim}$21--25\\,pp, yet SSR/TSR increases from 0.33 to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}); reduced exposure alone does not explain the pattern.",
          "+Our evaluation covers one benchmark suite (SafeLIBERO, four tasks) and two model families (Pi0, Pi0.5). The tabletop setting with fixed-base manipulator and known obstacles may not generalize to mobile platforms and cluttered scenes. Oracle experiments used a largely frozen model (Pi0+A1, TSR${\\approx}$0\\%); testing on an actively moving policy would better isolate the structural limitation. The $\\lambda = 0.1$ condition has $n = 2$ seeds; the marginal departure ($p \\approx 0.071$, two-tailed permutation test) is inconclusive. Full-body SDF remains untested. Fine-tuning degrades TSR by ${\\sim}$21--25\\,pp, yet SSR/TSR increases from 0.33 to 0.51--0.57 (Appendix~\\ref{sec:appendix_ssr}); reduced exposure alone does not explain the pattern.",
          " ",
          " \\paragraph{Future work.}",
          " Three directions follow: (1) full-body SDF supervision along the kinematic chain; (2) cross-architecture evaluation on OpenVLA, RT-2, and other VLA families; (3) planning-layer safety constraints in joint space rather than EE space."
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

### Tool call

_source line 108_

<details open><summary>🔧 Tool call — Edit · `toolu_01RU88VNPsyKhDx2D7dUBD25`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/introduction.tex",
  "old_string": "($p \\approx 0.039$, $n = 2$)",
  "new_string": "($p \\approx 0.071$, two-tailed permutation test, $n = 2$)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "c3669faa-a351-4418-b3c6-6f2f6a56b097",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SaKme2RtapYtAcuufLat6n",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4216,
      "cache_read_input_tokens": 60603,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4216
      },
      "output_tokens": 24,
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

_source line 109 · 2026-05-27T20:39:30.941Z_

<details><summary>↩ Tool result · `toolu_01RU88VNPsyKhDx2D7dUBD25`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/introduction.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b6d9c464-40db-4430-94f2-e5e7ab9606c6",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/introduction.tex",
    "oldString": "($p \\approx 0.039$, $n = 2$)",
    "newString": "($p \\approx 0.071$, two-tailed permutation test, $n = 2$)",
    "originalFile": "\\section{Introduction}\\label{sec:intro}\n\nVision-Language-Action (VLA) models must avoid collisions to operate safely in physical environments~\\cite{li2026vlasafety}. The SafeLIBERO benchmark~\\cite{hu2025vlsa} provides the first systematic protocol for measuring collision avoidance in VLA manipulation, and recent methods, including SDF-augmented training~\\cite{zhang2025safevla}, constraint-based planning~\\cite{yang2025cape}, and collision-free demonstrations~\\cite{cofreeevla2026}, report high Collision Avoidance Rate (CAR). Our SDF-augmented Pi0~\\cite{black2024pi0} reaches 91.5\\% CAR across 800 episodes. The problem appears close to solved.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{fig1_teaser}\n\\caption{The fake safety problem in VLA collision avoidance evaluation. Standard CAR classifies a frozen robot as safe because it produces zero collisions (left). dfCAR filters out action-collapsed episodes where displacement falls below $\\tau_d$; Pi0+A1's 91.5\\% safety score drops to ${\\approx}$\\,0\\% (center). Pi0.5 exhibits genuine avoidance with active motion above 288\\,mm in all safe episodes, and dfCAR equals raw CAR (right).}\n\\label{fig:teaser}\n\\end{figure}\n\nIt is not (Figure~\\ref{fig:teaser}). Of the 732 collision-free episodes, 99.6\\% exhibit displacement below 0.1\\,mm; TSR is 0\\% across all 800 episodes. The robot is frozen, not safe. The same pattern holds across all Pi0 configurations (Section~\\ref{sec:fake_safety}). We term this \\emph{fake safety}: \\emph{action collapse} (near-zero actions producing zero collisions) renders reported CAR illusory, and standard evaluation cannot distinguish inaction from deliberate avoidance~\\cite{karwowski2024goodhart}.\n\nWe present a systematic investigation of this problem across the Pi0 and Pi0.5~\\cite{black2024pi0} model families on SafeLIBERO, spanning 100+ experiments and 6000+ evaluation episodes. Three findings emerge.\n\n\\textbf{Fake safety is pervasive.} We introduce displacement-filtered CAR (dfCAR), which excludes episodes below a displacement threshold $\\tau_d$. dfCAR collapses Pi0+A1 from 91.5\\% to ${\\approx}$\\,0\\% (3/732 safe episodes survive). The bimodal displacement distribution makes $\\tau_d$ robust across five orders of magnitude. Pi0.5 validates the metric: TSR\\,=\\,74.7\\%, CAR\\,=\\,26.8\\%, with every safe episode above 288\\,mm displacement and dfCAR equal to raw CAR (Section~\\ref{sec:fake_safety}).\n\n\\textbf{EE-only SDF refinement is structurally counterproductive.} Three ground-truth oracle variants all achieve \\emph{lower} CAR than unrefined baselines (73.1--76.9\\% vs.\\ 82--83\\%). The SDF gradient repels the EE but rotates arm links into obstacle volumes (Section~\\ref{sec:ee_only}).\n\n\\textbf{Collision-free demonstrations are sufficient for collision avoidance.} LoRA fine-tuning on Pi0.5 raises CAR by ${\\sim}$28 points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes; adding SDF supervision at low loss weights ($\\lambda \\in \\{0.005, 0.01\\}$) produces no measurable benefit and at high $\\lambda = 0.1$ yields only a marginal, inconclusive signal ($p \\approx 0.039$, $n = 2$); the per-task avoidance pattern is identical with and without geometric supervision. The collision-free demonstration distribution, not EE-only SDF supervision, accounts for all observed avoidance learning on this benchmark (Section~\\ref{sec:avoidance_source}).\n\nOur contributions are:\n\\begin{itemize}\n    \\item \\textbf{dfCAR metric:} displacement-filtered CAR that separates genuine avoidance from action collapse, robust across $\\tau_d \\in [2, 200]$\\,mm.\n    \\item \\textbf{Fake safety diagnosis:} 100+ experiments across Pi0/Pi0.5 showing $>$99\\% of Pi0 safe episodes are action-collapse artifacts.\n    \\item \\textbf{EE-only SDF is counterproductive:} ground-truth oracle refinement \\emph{reduces} CAR below unrefined baselines by redistributing collisions to unmonitored arm links.\n    \\item \\textbf{Demonstration sufficiency:} on SafeLIBERO, collision-free demonstrations account for all measured CAR gains (${\\sim}$28\\,pp); EE-only SDF at low $\\lambda$ ($\\leq 0.01$) adds nothing, and at high $\\lambda = 0.1$ shows only a marginal, inconclusive signal ($n = 2$) whose per-task pattern still matches the demonstration distribution.\n\\end{itemize}",
    "structuredPatch": [
      {
        "oldStart": 17,
        "oldLines": 7,
        "newStart": 17,
        "newLines": 7,
        "lines": [
          " ",
          " \\textbf{EE-only SDF refinement is structurally counterproductive.} Three ground-truth oracle variants all achieve \\emph{lower} CAR than unrefined baselines (73.1--76.9\\% vs.\\ 82--83\\%). The SDF gradient repels the EE but rotates arm links into obstacle volumes (Section~\\ref{sec:ee_only}).",
          " ",
          "-\\textbf{Collision-free demonstrations are sufficient for collision avoidance.} LoRA fine-tuning on Pi0.5 raises CAR by ${\\sim}$28 points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes; adding SDF supervision at low loss weights ($\\lambda \\in \\{0.005, 0.01\\}$) produces no measurable benefit and at high $\\lambda = 0.1$ yields only a marginal, inconclusive signal ($p \\approx 0.039$, $n = 2$); the per-task avoidance pattern is identical with and without geometric supervision. The collision-free demonstration distribution, not EE-only SDF supervision, accounts for all observed avoidance learning on this benchmark (Section~\\ref{sec:avoidance_source}).",
          "+\\textbf{Collision-free demonstrations are sufficient for collision avoidance.} LoRA fine-tuning on Pi0.5 raises CAR by ${\\sim}$28 points (26.8\\% $\\to$ 54.83\\%) with zero frozen episodes; adding SDF supervision at low loss weights ($\\lambda \\in \\{0.005, 0.01\\}$) produces no measurable benefit and at high $\\lambda = 0.1$ yields only a marginal, inconclusive signal ($p \\approx 0.071$, two-tailed permutation test, $n = 2$); the per-task avoidance pattern is identical with and without geometric supervision. The collision-free demonstration distribution, not EE-only SDF supervision, accounts for all observed avoidance learning on this benchmark (Section~\\ref{sec:avoidance_source}).",
          " ",
          " Our contributions are:",
          " \\begin{itemize}"
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

_source line 110_

Final verification — confirm no stray `0.039` remains in main text (only appendix where it's properly framed as approximate).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "d5f15a84-3241-4cbf-b5e9-7db07d1f7844",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JDyqzjKwpXrgWStvscdXeA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1431,
      "cache_read_input_tokens": 64819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1431
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

_source line 111_

<details open><summary>🔧 Tool call — Grep · `toolu_01AdWvW3fo7vjP3MjZxR5Rzz`</summary>

```json
{
  "pattern": "0\\.039",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "6a814777-493a-42c8-a257-ea5393c12fda",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JDyqzjKwpXrgWStvscdXeA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1431,
      "cache_read_input_tokens": 64819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1431
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

_source line 112 · 2026-05-27T20:39:36.570Z_

<details><summary>↩ Tool result · `toolu_01AdWvW3fo7vjP3MjZxR5Rzz`</summary>

```text
docs/paper/appendix.tex:171:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f08e242f-0fd0-4c5b-8e61-f5d7c0a8199f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/appendix.tex:171:[Omitted long matching line]",
    "numLines": 1
  }
}
```

</details>

---

### Assistant

_source line 113_

Only one `0.039` remains — in appendix.tex L171, properly framed as "a $z$-test gives an approximate $p \approx 0.039$". This is exactly what the task requires.

Now syncing files to the server and compiling. The paper files are local, so I need to copy them to the server first. Let me check if there's a git-based sync or if I should copy directly.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "ee369bc1-9fda-473e-8c34-81be85639ff9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fa37qbvkM1RfXjPyFLhtSc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 217,
      "cache_read_input_tokens": 66250,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 217
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

_source line 114_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_016pU8wLGRqGw5EP8zGMbu7R`</summary>

```json
{
  "server": "westd-45947",
  "command": "find /root -name \"main.tex\" -maxdepth 6",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "8ebcedbf-56a5-4e02-9423-4744baacd860",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fa37qbvkM1RfXjPyFLhtSc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 217,
      "cache_read_input_tokens": 66250,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 217
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

_source line 115 · 2026-05-27T20:39:47.183Z_

<details><summary>↩ Tool result · `toolu_016pU8wLGRqGw5EP8zGMbu7R`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "24ec0c8b-5f3b-4e07-9e64-2b1f5d82b073",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.5}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 116_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Lamjx4iJLZhyywnpk1TSet`</summary>

```json
{
  "server": "westd-35807",
  "command": "find /root -name \"main.tex\" -maxdepth 6",
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
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "6c40437f-5690-4d58-ae21-e876ff571989",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fa37qbvkM1RfXjPyFLhtSc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 217,
      "cache_read_input_tokens": 66250,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 217
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

_source line 117 · 2026-05-27T20:39:47.804Z_

<details><summary>↩ Tool result · `toolu_01Lamjx4iJLZhyywnpk1TSet`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "45bfd139-e0df-4ee7-8994-40f69ea134ce",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.46}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 118_

<details><summary>Logged reasoning block</summary>

```text
No main.tex on either server. The paper is entirely local. The task asks to compile with `latexmk -pdf main.tex` but since the paper doesn't exist on the servers, I should try compiling locally.

Let me check if latexmk is available locally.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "4b473190-4150-4bd6-a96f-08c6ceb1ebef",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GTxYvDfasoUGcZYyzCpiZe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 524,
      "cache_read_input_tokens": 66467,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 524
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

_source line 119_

Paper files exist only locally. Let me try compiling locally.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "508821ba-4619-4f77-920d-e80467785d05",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GTxYvDfasoUGcZYyzCpiZe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 524,
      "cache_read_input_tokens": 66467,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 524
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

_source line 120_

<details open><summary>🔧 Tool call — Bash · `toolu_01RKRzphB9d45dznADG1MDEc`</summary>

```json
{
  "command": "which latexmk 2>/dev/null && which pdflatex 2>/dev/null",
  "description": "Check if LaTeX tools are available locally"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "95f25b2a-77a8-4bf4-b0ee-e7628271247e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GTxYvDfasoUGcZYyzCpiZe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 524,
      "cache_read_input_tokens": 66467,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 524
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

_source line 121 · 2026-05-27T20:39:53.417Z_

<details><summary>↩ Tool result · `toolu_01RKRzphB9d45dznADG1MDEc`</summary>

```text
/usr/bin/latexmk
/usr/bin/pdflatex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "663eb7dc-40ce-4b30-8046-64c0724221e8",
  "tool_use_result": {
    "stdout": "/usr/bin/latexmk\n/usr/bin/pdflatex",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 122_

<details open><summary>🔧 Tool call — Bash · `toolu_01WbrseAdMPjNrWjNAXabsiK`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper && latexmk -pdf -interaction=nonstopmode main.tex 2>&1 | tail -30",
  "description": "Compile paper PDF with latexmk",
  "timeout": 120000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "b093469a-caba-484e-b547-d2c184f767ec",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MQAE6Z3VgTPbb9QxBTamSw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 219,
      "cache_read_input_tokens": 66991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 219
      },
      "output_tokens": 64,
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

_source line 123 · 2026-05-27T20:39:58.225Z_

<details><summary>↩ Tool result · `toolu_01WbrseAdMPjNrWjNAXabsiK`</summary>

```text
ist/fonts/type1/public/amsfonts/cm/cmex10.pfb>&lt;/usr/share/texlive/texmf-dist/fo
nts/type1/public/amsfonts/cm/cmmi10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/ty
pe1/public/amsfonts/cm/cmmi12.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/pu
blic/amsfonts/cm/cmmi6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/am
sfonts/cm/cmmi7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/
cm/cmmi9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr1
0.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr12.pfb><
/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr7.pfb>&lt;/usr/sha
re/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr9.pfb>&lt;/usr/share/texli
ve/texmf-dist/fonts/type1/public/amsfonts/cm/cmsy10.pfb>&lt;/usr/share/texlive/tex
mf-dist/fonts/type1/public/amsfonts/cm/cmsy6.pfb>&lt;/usr/share/texlive/texmf-dist
/fonts/type1/public/amsfonts/cm/cmsy7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/
type1/public/amsfonts/cm/cmsy9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/p
ublic/amsfonts/cm/cmtt10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/hel
vetic/uhvr8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmb8a.pf
b>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmr8a.pfb>&lt;/usr/share/t
exlive/texmf-dist/fonts/type1/urw/times/utmri8a.pfb>
Output written on main.pdf (15 pages, 456912 bytes).
Transcript written on main.log.
Latexmk: Getting log file 'main.log'
Latexmk: Examining 'main.fls'
Latexmk: Examining 'main.log'
Latexmk: Found input bbl file 'main.bbl'
Latexmk: Log file says output to 'main.pdf'
Latexmk: Using bibtex to make bibliography file(s).
  ===Source file 'main.bbl' for 'pdflatex'
Latexmk: Found bibliography file(s):
  ./references.bib
Latexmk: All targets (main.pdf) are up-to-date
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "f25eb1c8-2e75-491e-a030-fd7918e58029",
  "tool_use_result": {
    "stdout": "ist/fonts/type1/public/amsfonts/cm/cmex10.pfb>&lt;/usr/share/texlive/texmf-dist/fo\nnts/type1/public/amsfonts/cm/cmmi10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/ty\npe1/public/amsfonts/cm/cmmi12.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/pu\nblic/amsfonts/cm/cmmi6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/am\nsfonts/cm/cmmi7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/\ncm/cmmi9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr1\n0.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr12.pfb><\n/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr7.pfb>&lt;/usr/sha\nre/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr9.pfb>&lt;/usr/share/texli\nve/texmf-dist/fonts/type1/public/amsfonts/cm/cmsy10.pfb>&lt;/usr/share/texlive/tex\nmf-dist/fonts/type1/public/amsfonts/cm/cmsy6.pfb>&lt;/usr/share/texlive/texmf-dist\n/fonts/type1/public/amsfonts/cm/cmsy7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/\ntype1/public/amsfonts/cm/cmsy9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/p\nublic/amsfonts/cm/cmtt10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/hel\nvetic/uhvr8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmb8a.pf\nb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmr8a.pfb>&lt;/usr/share/t\nexlive/texmf-dist/fonts/type1/urw/times/utmri8a.pfb>\nOutput written on main.pdf (15 pages, 456912 bytes).\nTranscript written on main.log.\nLatexmk: Getting log file 'main.log'\nLatexmk: Examining 'main.fls'\nLatexmk: Examining 'main.log'\nLatexmk: Found input bbl file 'main.bbl'\nLatexmk: Log file says output to 'main.pdf'\nLatexmk: Using bibtex to make bibliography file(s).\n  ===Source file 'main.bbl' for 'pdflatex'\nLatexmk: Found bibliography file(s):\n  ./references.bib\nLatexmk: All targets (main.pdf) are up-to-date",
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

_source line 124_

PDF compiled successfully (15 pages, no errors).

---

**汇报：**

**M1** — `within 0.33\,pp`：已验证正确，无需修改。

**M2** — λ 范围 `\{0.005, 0.01, 0.1\}`：method.tex L23 和 L44 已包含 0.1，无需修改。

**M3** — 统计检验统一，共 10 处修改：

| 文件 | 位置 | 修改 |
|------|------|------|
| claim3.tex | L7 表格 caption | `z=1.76, p≈0.039` → `p≈0.071, two-tailed permutation test` |
| claim3.tex | L33 dose-response | `z=1.76, p≈0.039` → two-tailed permutation `p≈0.071` + 脚注（one-tailed p=0.036 + directional prior） |
| claim3.tex | L38 图 caption | `p≈0.039` → `p≈0.071, two-tailed permutation test` |
| abstract.tex | L7 | `p≈0.039` → `p≈0.071, two-tailed permutation test` |
| introduction.tex | L20 | `p≈0.039, n=2` → `p≈0.071, two-tailed permutation test, n=2` |
| discussion.tex | L12 | `p≈0.039` → `p≈0.071, two-tailed permutation test` |
| appendix.tex | L171 | z-test 从主要测试降为 "approximate"，permutation 为主 |
| appendix.tex | L173 | "As a robustness check" → 直接描述 permutation 程序 |
| appendix.tex | L173 末尾 | 重述统一表述 |
| appendix.tex | L184 stepwise caption | `z=1.76, p≈0.039` → `two-tailed permutation p≈0.071` |

**M3b** — paper_switch.py 问题记录：脚本将 one-tailed p 输出到所有位置（`v["p_value"] = p_one`），未区分正文（应用 two-tailed）和脚注（应用 one-tailed）。未修改脚本。

编译通过，15 页 PDF 无错误。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "uuid": "1a55cd33-0d92-4618-9ce4-ea1bedc57a16",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GsX5gHi8sVV7LXcx3qVjtX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1032,
      "cache_read_input_tokens": 67210,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1032
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

_source line 125_

PDF compiled successfully (15 pages, no errors).

---

**汇报：**

**M1** — `within 0.33\,pp`：已验证正确，无需修改。

**M2** — λ 范围 `\{0.005, 0.01, 0.1\}`：method.tex L23 和 L44 已包含 0.1，无需修改。

**M3** — 统计检验统一，共 10 处修改：

| 文件 | 位置 | 修改 |
|------|------|------|
| claim3.tex | L7 表格 caption | `z=1.76, p≈0.039` → `p≈0.071, two-tailed permutation test` |
| claim3.tex | L33 dose-response | `z=1.76, p≈0.039` → two-tailed permutation `p≈0.071` + 脚注（one-tailed p=0.036 + directional prior） |
| claim3.tex | L38 图 caption | `p≈0.039` → `p≈0.071, two-tailed permutation test` |
| abstract.tex | L7 | `p≈0.039` → `p≈0.071, two-tailed permutation test` |
| introduction.tex | L20 | `p≈0.039, n=2` → `p≈0.071, two-tailed permutation test, n=2` |
| discussion.tex | L12 | `p≈0.039` → `p≈0.071, two-tailed permutation test` |
| appendix.tex | L171 | z-test 从主要测试降为 "approximate"，permutation 为主 |
| appendix.tex | L173 | "As a robustness check" → 直接描述 permutation 程序 |
| appendix.tex | L173 末尾 | 重述统一表述 |
| appendix.tex | L184 stepwise caption | `z=1.76, p≈0.039` → `two-tailed permutation p≈0.071` |

**M3b** — paper_switch.py 问题记录：脚本将 one-tailed p 输出到所有位置（`v["p_value"] = p_one`），未区分正文（应用 two-tailed）和脚注（应用 one-tailed）。未修改脚本。

编译通过，15 页 PDF 无错误。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 307338,
  "duration_api_ms": 304446,
  "num_turns": 47,
  "stop_reason": "end_turn",
  "session_id": "ac4b7721-0d5e-47a4-bc33-dfc958e35369",
  "total_cost_usd": 1.2064867500000003,
  "usage": {
    "input_tokens": 25,
    "cache_creation_input_tokens": 56791,
    "cache_read_input_tokens": 951560,
    "output_tokens": 14940,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 56791,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 657,
        "cache_read_input_tokens": 67210,
        "cache_creation_input_tokens": 1032,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 1032
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2053,
      "outputTokens": 17,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002138,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 25,
      "outputTokens": 14940,
      "cacheReadInputTokens": 951560,
      "cacheCreationInputTokens": 56791,
      "webSearchRequests": 0,
      "costUSD": 1.2043487500000003,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "1d1c4330-f0a7-4b2c-9339-d7f056b46b88"
}
```

</details>

---

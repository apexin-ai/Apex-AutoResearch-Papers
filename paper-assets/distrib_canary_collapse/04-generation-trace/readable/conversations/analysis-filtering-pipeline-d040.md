# analysis filtering pipeline d040

**Characterizing the Detectability Landscape of Iterative Model Collapse** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 37
- **Recorded user turns:** 0
- **Tool calls:** 18
- **Original source:** `logs/chats/worker_analysis_filtering-pipeline-d040_20260515T153235.jsonl`
- **Structured JSON:** [`1278cae26153cf5d2a83.json`](../../sessions/12/1278cae26153cf5d2a83.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

37 recorded events

### Tool call

_source line 1 · 2026-05-15T15:42:03.791385+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__read_project_file",
  "max_results": "5"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__read_project_file",
    "max_results": "5"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-15T15:42:03.791664+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-15T15:42:03.791816+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "ls -la /root/autodl-tmp/distrib_canary_collapse/results/analysis/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "ls -la /root/autodl-tmp/distrib_canary_collapse/results/analysis/",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-15T15:42:03.791942+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "find /root/autodl-tmp/distrib_canary_collapse/results/analysis/ -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "find /root/autodl-tmp/distrib_canary_collapse/results/analysis/ -name \"*.json\" -type f",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-15T15:42:03.792078+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"total 328\\ndrwxr-xr-x 2 root root  4096 May 15 21:17 .\\ndrwxr-xr-x 9 root root  4096 May 15 19:57 ..\\n-rw-r--r-- 1 root root 12551 May 15 13:31 cross_alpha_analysis.json\\n-rw-r--r-- 1 root root  3769 May 15 13:33 cross_alpha_analysis.md\\n-rw-r--r-- 1 root root  9508 May 15 13:48 cross_alpha_v3_full.json\\n-rw-r--r-- 1 root root 71968 May 15 18:56 cross_alpha_v4.json\\n-rw-r--r-- 1 root root  6859 May 15 18:56 cross_alpha_v4_report.md\\n-rw-r--r-- 1 root root 71968 May 15 20:13 cross_alpha_v5.json\\n-rw-r--r-- 1 root root  6859 May 15 20:13 cross_alpha_v5_report.md\\n-rw-r--r-- 1 root root 88994 May 15 21:18 cross_alpha_v6.json\\n-rw-r--r-- 1 root root  8251 May 15 21:18 cross_alpha_v6_report.md\\n-rw-r--r-- 1 root root 18313 May 15 17:56 d028_fpr_null_control.json\\n-rw-r--r-- 1 root root  5688 May 15 17:57 d028_fpr_null_control_full.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.98}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T15:42:03.792213+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_analysis.json\\n/root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v3_full.json\\n/root/autodl-tmp/distrib_canary_collapse/results/analysis/d028_fpr_null_control.json\\n/root/autodl-tmp/distrib_canary_collapse/results/analysis/d028_fpr_null_control_full.json\\n/root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v4.json\\n/root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v5.json\\n/root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-15T15:42:03.792385+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "head -500 /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "head -500 /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-15T15:42:03.792772+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"version\\\": \\\"v6\\\",\\n  \\\"date\\\": \\\"2026-05-15\\\",\\n  \\\"n_alphas\\\": 5,\\n  \\\"alpha_points\\\": [\\n    0.0,\\n    0.25,\\n    0.5,\\n    0.75,\\n    1.0\\n  ],\\n  \\\"n_generations\\\": 11,\\n  \\\"gen_range\\\": \\\"gen_0 to gen_10\\\",\\n  \\\"statistical_config\\\": {\\n    \\\"granger_max_lag\\\": 1,\\n    \\\"granger_n_perm\\\": 5000,\\n    \\\"granger_differenced\\\": true,\\n    \\\"fdr_method\\\": \\\"benjamini-hochberg\\\",\\n    \\\"fdr_scope\\\": \\\"all 40 tests corrected together\\\",\\n    \\\"n_independent_tests\\\": 40\\n  },\\n  \\\"dose_response\\\": {\\n    \\\"a000\\\": {\\n      \\\"alpha\\\": 0.0,\\n      \\\"distinct_1\\\": {\\n        \\\"gen0\\\": 0.098216,\\n        \\\"gen10\\\": 0.08468,\\n        \\\"drift_pct\\\": -13.78\\n      },\\n      \\\"distinct_2\\\": {\\n        \\\"gen0\\\": 0.517803,\\n        \\\"gen10\\\": 0.467199,\\n        \\\"drift_pct\\\": -9.77\\n      },\\n      \\\"distinct_3\\\": {\\n        \\\"gen0\\\": 0.812728,\\n        \\\"gen10\\\": 0.77602,\\n        \\\"drift_pct\\\": -4.52\\n      },\\n      \\\"token_entropy\\\": {\\n        \\\"gen0\\\": 3.234195,\\n        \\\"gen10\\\": 3.069313,\\n        \\\"drift_pct\\\": -5.1\\n      },\\n      \\\"ece\\\": {\\n        \\\"gen0\\\": 0.010805,\\n        \\\"gen10\\\": 0.016391,\\n        \\\"drift_pct\\\": 51.7\\n      },\\n      \\\"perplexity\\\": {\\n        \\\"gen0\\\": 26.948959,\\n        \\\"gen10\\\": 21.107704,\\n        \\\"drift_pct\\\": -21.68\\n      }\\n    },\\n    \\\"a025\\\": {\\n      \\\"alpha\\\": 0.25,\\n      \\\"distinct_1\\\": {\\n        \\\"gen0\\\": 0.098216,\\n        \\\"gen10\\\": 0.058594,\\n        \\\"drift_pct\\\": -40.34\\n      },\\n      \\\"distinct_2\\\": {\\n        \\\"gen0\\\": 0.517803,\\n        \\\"gen10\\\": 0.221939,\\n        \\\"drift_pct\\\": -57.14\\n      },\\n      \\\"distinct_3\\\": {\\n        \\\"gen0\\\": 0.812728,\\n    
…[truncated 9044 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-15T15:42:03.792945+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/d028_fpr_null_control.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/d028_fpr_null_control.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-15T15:42:03.793231+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"null_control_fpr\\\": {\\n    \\\"description\\\": \\\"FPR computed from alpha=0.0 null control (single seed=42, 8 pairs)\\\",\\n    \\\"per_method_fdr\\\": {\\n      \\\"naive\\\": {\\n        \\\"sig_raw\\\": 8,\\n        \\\"total\\\": 8,\\n        \\\"fpr_raw\\\": 1.0,\\n        \\\"sig_fdr\\\": 8,\\n        \\\"fpr_fdr\\\": 1.0\\n      },\\n      \\\"differenced\\\": {\\n        \\\"sig_raw\\\": 4,\\n        \\\"total\\\": 8,\\n        \\\"fpr_raw\\\": 0.5,\\n        \\\"sig_fdr\\\": 3,\\n        \\\"fpr_fdr\\\": 0.375\\n      },\\n      \\\"threshold\\\": {\\n        \\\"sig_raw\\\": 5,\\n        \\\"total\\\": 8,\\n        \\\"fpr_raw\\\": 0.625,\\n        \\\"sig_fdr\\\": 5,\\n        \\\"fpr_fdr\\\": 0.625,\\n        \\\"note\\\": \\\"non-statistical (no p-values, FDR not applicable)\\\"\\n      },\\n      \\\"permutation_granger\\\": {\\n        \\\"sig_raw\\\": 0,\\n        \\\"total\\\": 8,\\n        \\\"fpr_raw\\\": 0.0,\\n        \\\"sig_fdr\\\": 0,\\n        \\\"fpr_fdr\\\": 0.0\\n      },\\n      \\\"TY\\\": {\\n        \\\"sig_raw\\\": 0,\\n        \\\"total\\\": 8,\\n        \\\"fpr_raw\\\": 0.0,\\n        \\\"sig_fdr\\\": 0,\\n        \\\"fpr_fdr\\\": 0.0\\n      }\\n    },\\n    \\\"per_method_full\\\": {\\n      \\\"naive\\\": {\\n        \\\"sig_raw\\\": 8,\\n        \\\"total\\\": 8,\\n        \\\"fpr_raw\\\": 1.0,\\n        \\\"sig_fdr\\\": 8,\\n        \\\"fpr_fdr\\\": 1.0,\\n        \\\"p_values_raw\\\": [\\n          0.002496,\\n          0.006055,\\n          0.007303,\\n          0.0,\\n          0.005344,\\n          0.009665,\\n          0.022381,\\n          0.018795\\n        ],\\n        \\\"p_values_fdr\\\": [\\n          0.009984,\\n          0.011684799999999999,\\n          0.011684799999999999,\\n          0.0,\\n          0.011684799999999999,\\n          0.012886666666666666,\\n          0.022381,\\n          0.02148\\n        ]\\n      },\\n      \\\"differenc
…[truncated 7724 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-15T15:42:03.793421+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/d028_fpr_null_control_full.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/d028_fpr_null_control_full.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-15T15:42:03.793664+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"null_control_fpr\\\": {\\n    \\\"description\\\": \\\"FPR from alpha=0.0 null control (no canary injection)\\\",\\n    \\\"ground_truth\\\": \\\"alpha=0.0 (any significance is false positive by definition)\\\",\\n    \\\"n_pairs\\\": 8,\\n    \\\"seed\\\": 42,\\n    \\\"note\\\": \\\"single seed \\\\u2014 interpret with caution\\\",\\n    \\\"table\\\": [\\n      {\\n        \\\"method\\\": \\\"naive\\\",\\n        \\\"fpr_p_raw\\\": 1.0,\\n        \\\"sig_raw\\\": 8,\\n        \\\"fpr_p_fdr\\\": 1.0,\\n        \\\"sig_fdr\\\": 8,\\n        \\\"total\\\": 8,\\n        \\\"p_values_raw\\\": [\\n          0.002496,\\n          0.006055,\\n          0.007303,\\n          0.0,\\n          0.005344,\\n          0.009665,\\n          0.022381,\\n          0.018795\\n        ]\\n      },\\n      {\\n        \\\"method\\\": \\\"differenced\\\",\\n        \\\"fpr_p_raw\\\": 0.5,\\n        \\\"sig_raw\\\": 4,\\n        \\\"fpr_p_fdr\\\": 0.375,\\n        \\\"sig_fdr\\\": 3,\\n        \\\"total\\\": 8,\\n        \\\"p_values_raw\\\": [\\n          0.000157,\\n          0.00325,\\n          0.044726,\\n          2e-06,\\n          0.051439,\\n          0.192837,\\n          0.202654,\\n          0.096018\\n        ]\\n      },\\n      {\\n        \\\"method\\\": \\\"threshold\\\",\\n        \\\"fpr_p_raw\\\": 0.625,\\n        \\\"sig_raw\\\": 5,\\n        \\\"fpr_p_fdr\\\": 0.625,\\n        \\\"sig_fdr\\\": 5,\\n        \\\"total\\\": 8\\n      },\\n      {\\n        \\\"method\\\": \\\"permutation_granger\\\",\\n        \\\"fpr_p_raw\\\": 0.0,\\n        \\\"sig_raw\\\": 0,\\n        \\\"fpr_p_fdr\\\": 0.0,\\n        \\\"sig_fdr\\\": 0,\\n        \\\"total\\\": 8,\\n        \\\"p_values_raw\\\": [\\n          0.058941,\\n          0.093906,\\n          0.080919,\\n          0.67033,\\n          0.955045,\\n          0.549451,\\n          0.350649,\\n          0.365634\\n        ]\\n      },\\n      {\\n        \
…[truncated 5501 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-15T15:42:03.793851+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "tail -600 /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "tail -600 /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-15T15:42:03.794153+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"            \\\"is_robust\\\": false,\\n            \\\"n_sig_methods\\\": 2,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a050\\\": {\\n            \\\"alpha\\\": 0.5,\\n            \\\"is_robust\\\": false,\\n            \\\"n_sig_methods\\\": 3,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a075\\\": {\\n            \\\"alpha\\\": 0.75,\\n            \\\"is_robust\\\": true,\\n            \\\"n_sig_methods\\\": 4,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a100\\\": {\\n            \\\"alpha\\\": 1.0,\\n            \\\"is_robust\\\": false,\\n            \\\"n_sig_methods\\\": 3,\\n            \\\"mode\\\": \\\"full_consensus\\\"\\n          }\\n        },\\n        \\\"stable\\\": false,\\n        \\\"all_robust\\\": false,\\n        \\\"all_non_robust\\\": false\\n      },\\n      \\\"token_entropy→distinct_1\\\": {\\n        \\\"pair\\\": \\\"token_entropy→distinct_1\\\",\\n        \\\"per_alpha\\\": {\\n          \\\"a000\\\": {\\n            \\\"alpha\\\": 0.0,\\n            \\\"is_robust\\\": false,\\n            \\\"n_sig_methods\\\": 3,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a025\\\": {\\n            \\\"alpha\\\": 0.25,\\n            \\\"is_robust\\\": true,\\n            \\\"n_sig_methods\\\": 4,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a050\\\": {\\n            \\\"alpha\\\": 0.5,\\n            \\\"is_robust\\\": false,\\n            \\\"n_sig_methods\\\": 3,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a075\\\": {\\n            \\\"alpha\\\": 0.75,\\n            \\\"is_robust\\\": true,\\n            \\\"n_sig_methods\\\": 4,\\n            \\\"mode\\\": \\\"method_agreement_only\\\"\\n          },\\n          \\\"a100\\\": {\\
…[truncated 8499 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-15T15:42:03.794333+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "find /root/autodl-tmp/distrib_canary_collapse/results/ -name \"*multi*\" -o -name \"*seed*\" -o -name \"*d017*\" -o -name \"*consensus*\" -o -name \"*method_ablation*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "find /root/autodl-tmp/distrib_canary_collapse/results/ -name \"*multi*\" -o -name \"*seed*\" -o -name \"*d017*\" -o -name \"*consensus*\" -o -name \"*method_ablation*\"",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-15T15:42:03.794472+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/method_ablation.json\\n/root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/method_ablation_dmax_sensitivity.json\\n/root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/consensus\\n/root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/consensus/consensus_classification.json\\n/root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/consensus/consensus_classification.json.bak_raw\\n/root/autodl-tmp/distrib_canary_collapse/results/method_ablation_phase2_panel.json\\n/root/autodl-tmp/distrib_canary_collapse/results/method_ablation_phase2_report.md\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-15T15:42:03.794594+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6_report.md",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6_report.md",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-15T15:42:03.794794+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"# Cross-Alpha Analysis Report (v6)\\n\\n**Date:** 2026-05-15\\n**Alpha points:** [0.0, 0.25, 0.5, 0.75, 1.0]\\n**Generations:** gen_0 to gen_10\\n\\n## 1. Dose-Response (gen0 to genN drift %)\\n\\n| Metric | α=0.00 | α=0.25 | α=0.50 | α=0.75 | α=1.00 |\\n|--------|--------:|--------:|--------:|--------:|--------:|\\n| distinct_1 | -13.8% | -40.3% | -37.3% | -32.7% | -28.3% |\\n| distinct_2 | -9.8% | -57.1% | -51.5% | -41.3% | -35.2% |\\n| distinct_3 | -4.5% | -59.9% | -52.4% | -38.4% | -31.6% |\\n| token_entropy | -5.1% | -4.1% | -18.6% | -27.7% | -60.5% |\\n| ece | +51.7% | +79.7% | +842.8% | +1809.5% | +3762.6% |\\n| perplexity | -21.7% | -17.2% | +21.1% | +182.1% | +3624.6% |\\n\\n## 2. Granger Causality (bidirectional, permutation, FDR-corrected)\\n\\n| Direction | α=0.00 p_raw | p_fdr | α=0.25 p_raw | p_fdr | α=0.50 p_raw | p_fdr | α=0.75 p_raw | p_fdr | α=1.00 p_raw | p_fdr |\\n|-----------|--------:|--------:|--------:|--------:|--------:|--------:|--------:|--------:|--------:|--------:|\\n| entropy->d1 | 0.0514 | 0.1285 | 0.0150 | 0.0667 | 0.0950 | 0.1855 | 0.0106 | 0.0540 | 0.0060 | 0.0480 * |\\n| ECE->d1 | 0.9498 | 0.9742 | 0.2352 | 0.4090 | 0.0190 | 0.0760 | 0.0038 | 0.0460 * | 0.0006 | 0.0240 * |\\n| entropy->d2 | 0.0804 | 0.1786 | 0.0730 | 0.1717 | 0.0974 | 0.1855 | 0.0072 | 0.0480 * | 0.0108 | 0.0540 |\\n| ECE->d2 | 0.5443 | 0.6220 | 0.0882 | 0.1855 | 0.0394 | 0.1285 | 0.0032 | 0.0460 * | 0.0046 | 0.0460 * |\\n| d1->entropy | 0.7956 | 0.8375 | 0.0236 | 0.0858 | 0.2170 | 0.3945 | 0.7762 | 0.8375 | 0.3313 | 0.4719 |\\n| d1->ECE | 0.3431 | 0.4719 | 0.4661 | 0.5484 | 0.2771 | 0.4619 | 0.3915 | 0.4962 | 0.0502 | 0.1285 |\\n| d2->entropy | 0.9782 | 0.9782 | 0.0498 | 0.1285 | 0.3143 | 0.4719 | 0.7674 | 0.8375 | 0.3447 | 0.4719 |\\n| d2->ECE | 0.3539 | 0.4719 | 0.3969 | 0.4962 | 0.3529 | 0.4719 | 0.4615 | 0.5484 | 0.0430 | 0.1285 |\\n\\nFDR: 40 tests, BH correction. \\\\* = p_fdr < 0.05\\n\\n## 3. Consen
…[truncated 6576 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-15T15:42:03.794983+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "grep -c \"p_raw\" /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "grep -c \"p_raw\" /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v6.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-15T15:42:03.795113+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"40\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-15T15:42:03.795229+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v4.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v4.json",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-15T15:42:03.795378+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/method_ablation.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/method_ablation.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 23 · 2026-05-15T15:42:03.795762+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"version\\\": \\\"v4\\\",\\n  \\\"date\\\": \\\"2026-05-15\\\",\\n  \\\"n_alphas\\\": 4,\\n  \\\"alpha_points\\\": [\\n    0.0,\\n    0.25,\\n    0.5,\\n    1.0\\n  ],\\n  \\\"n_generations\\\": 11,\\n  \\\"gen_range\\\": \\\"gen_0 to gen_10\\\",\\n  \\\"statistical_config\\\": {\\n    \\\"granger_max_lag\\\": 1,\\n    \\\"granger_n_perm\\\": 5000,\\n    \\\"granger_differenced\\\": true,\\n    \\\"fdr_method\\\": \\\"benjamini-hochberg\\\",\\n    \\\"fdr_scope\\\": \\\"all 32 tests corrected together\\\",\\n    \\\"n_independent_tests\\\": 32\\n  },\\n  \\\"dose_response\\\": {\\n    \\\"a000\\\": {\\n      \\\"alpha\\\": 0.0,\\n      \\\"distinct_1\\\": {\\n        \\\"gen0\\\": 0.098216,\\n        \\\"gen10\\\": 0.08468,\\n        \\\"drift_pct\\\": -13.78\\n      },\\n      \\\"distinct_2\\\": {\\n        \\\"gen0\\\": 0.517803,\\n        \\\"gen10\\\": 0.467199,\\n        \\\"drift_pct\\\": -9.77\\n      },\\n      \\\"distinct_3\\\": {\\n        \\\"gen0\\\": 0.812728,\\n        \\\"gen10\\\": 0.77602,\\n        \\\"drift_pct\\\": -4.52\\n      },\\n      \\\"token_entropy\\\": {\\n        \\\"gen0\\\": 3.234195,\\n        \\\"gen10\\\": 3.069313,\\n        \\\"drift_pct\\\": -5.1\\n      },\\n      \\\"ece\\\": {\\n        \\\"gen0\\\": 0.010805,\\n        \\\"gen10\\\": 0.016391,\\n        \\\"drift_pct\\\": 51.7\\n      },\\n      \\\"perplexity\\\": {\\n        \\\"gen0\\\": 26.948959,\\n        \\\"gen10\\\": 21.107704,\\n        \\\"drift_pct\\\": -21.68\\n      }\\n    },\\n    \\\"a025\\\": {\\n      \\\"alpha\\\": 0.25,\\n      \\\"distinct_1\\\": {\\n        \\\"gen0\\\": 0.098216,\\n        \\\"gen10\\\": 0.058594,\\n        \\\"drift_pct\\\": -40.34\\n      },\\n      \\\"distinct_2\\\": {\\n        \\\"gen0\\\": 0.517803,\\n        \\\"gen10\\\": 0.221939,\\n        \\\"drift_pct\\\": -57.14\\n      },\\n      \\\"distinct_3\\\": {\\n        \\\"gen0\\\": 0.812728,\\n        \\\"gen1
…[truncated 8672 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-15T15:42:03.796167+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"meta\\\": {\\n    \\\"seeds\\\": [\\n      42,\\n      43,\\n      44,\\n      45\\n    ],\\n    \\\"alpha\\\": 0.05,\\n    \\\"canary_metrics\\\": [\\n      \\\"token_entropy\\\",\\n      \\\"self_bleu\\\",\\n      \\\"ece\\\",\\n      \\\"effective_rank\\\"\\n    ],\\n    \\\"downstream_metrics\\\": [\\n      \\\"perplexity\\\",\\n      \\\"distinct_1\\\",\\n      \\\"distinct_2\\\",\\n      \\\"distinct_3\\\"\\n    ],\\n    \\\"methods\\\": [\\n      \\\"naive_pearson: raw-level Pearson lag-correlation\\\",\\n      \\\"differenced_xcorr: first-differenced cross-correlation\\\",\\n      \\\"threshold_onset: 2-sigma signal-onset lead time\\\",\\n      \\\"toda_yamamoto: augmented-lag Granger causality (Wald F-test)\\\",\\n      \\\"permutation_granger: differenced + shuffle permutation Granger (F-test)\\\"\\n    ]\\n  },\\n  \\\"summary\\\": {\\n    \\\"total_pairs\\\": 16,\\n    \\\"naive_significant\\\": 16,\\n    \\\"differenced_significant\\\": 14,\\n    \\\"threshold_significant\\\": 9,\\n    \\\"ty_significant\\\": 4,\\n    \\\"perm_granger_significant\\\": 6,\\n    \\\"spurious_count\\\": 12,\\n    \\\"spurious_rate\\\": 0.75,\\n    \\\"spurious_pairs\\\": [\\n      {\\n        \\\"canary\\\": \\\"token_entropy\\\",\\n        \\\"downstream\\\": \\\"perplexity\\\"\\n      },\\n      {\\n        \\\"canary\\\": \\\"self_bleu\\\",\\n        \\\"downstream\\\": \\\"perplexity\\\"\\n      },\\n      {\\n        \\\"canary\\\": \\\"self_bleu\\\",\\n        \\\"downstream\\\": \\\"distinct_1\\\"\\n      },\\n      {\\n        \\\"canary\\\": \\\"self_bleu\\\",\\n        \\\"downstream\\\": \\\"distinct_2\\\"\\n      },\\n      {\\n        \\\"canary\\\": \\\"self_bleu\\\",\\n        \\\"downstream\\\": \\\"distinct_3\\\"\\n      },\\n      {\\n        \\\"canary\\\": \\\"ece\\\",\\n        \\\"downstream\\\": \\\"perplexity\\\"\\n      },\\n      {\\n        \\\"canary\\\": \\\"ece\\\",\\n        \\
…[truncated 8595 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-15T15:42:03.796460+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v4_report.md",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/analysis/cross_alpha_v4_report.md",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-15T15:42:03.796666+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"# Cross-Alpha Analysis Report (v4)\\n\\n**Date:** 2026-05-15\\n**Alpha points:** [0.0, 0.25, 0.5, 1.0]\\n**Generations:** gen_0 to gen_10\\n\\n## 1. Dose-Response (gen0 to genN drift %)\\n\\n| Metric | α=0.00 | α=0.25 | α=0.50 | α=1.00 |\\n|--------|--------:|--------:|--------:|--------:|\\n| distinct_1 | -13.8% | -40.3% | -37.3% | -28.3% |\\n| distinct_2 | -9.8% | -57.1% | -51.5% | -35.2% |\\n| distinct_3 | -4.5% | -59.9% | -52.4% | -31.6% |\\n| token_entropy | -5.1% | -4.1% | -18.6% | -60.5% |\\n| ece | +51.7% | +79.7% | +842.8% | +3762.6% |\\n| perplexity | -21.7% | -17.2% | +21.1% | +3624.6% |\\n\\n## 2. Granger Causality (bidirectional, permutation, FDR-corrected)\\n\\n| Direction | α=0.00 p_raw | p_fdr | α=0.25 p_raw | p_fdr | α=0.50 p_raw | p_fdr | α=1.00 p_raw | p_fdr |\\n|-----------|--------:|--------:|--------:|--------:|--------:|--------:|--------:|--------:|\\n| entropy->d1 | 0.0514 | 0.1370 | 0.0150 | 0.0960 | 0.0950 | 0.1833 | 0.0060 | 0.0640 |\\n| ECE->d1 | 0.9498 | 0.9782 | 0.2352 | 0.3960 | 0.0190 | 0.1013 | 0.0006 | 0.0192 * |\\n| entropy->d2 | 0.0804 | 0.1833 | 0.0730 | 0.1797 | 0.0974 | 0.1833 | 0.0108 | 0.0864 |\\n| ECE->d2 | 0.5443 | 0.6006 | 0.0882 | 0.1833 | 0.0394 | 0.1370 | 0.0046 | 0.0640 |\\n| d1->entropy | 0.7956 | 0.8487 | 0.0236 | 0.1079 | 0.2170 | 0.3857 | 0.3313 | 0.4356 |\\n| d1->ECE | 0.3431 | 0.4356 | 0.4661 | 0.5327 | 0.2771 | 0.4356 | 0.0502 | 0.1370 |\\n| d2->entropy | 0.9782 | 0.9782 | 0.0498 | 0.1370 | 0.3143 | 0.4356 | 0.3447 | 0.4356 |\\n| d2->ECE | 0.3539 | 0.4356 | 0.3969 | 0.4704 | 0.3529 | 0.4356 | 0.0430 | 0.1370 |\\n\\nFDR: 32 tests, BH correction. \\\\* = p_fdr < 0.05\\n\\n## 3. Consensus Classification (regime-dependent validity)\\n\\n### α=0.00 (single-seed, method agreement only (≥4/5 methods, ≥1/1 seeds))\\n\\n- Robust pairs: 0/16\\n- Non-robust: 16/16\\n\\n| Pair | Robust | Methods |\\n|------|--------|---------|\\n| token_entropy→perplexity | non-robust
…[truncated 5153 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-15T15:42:03.796827+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "find /root/autodl-tmp/distrib_canary_collapse/results/ -name \"*d017*\" -o -name \"*differenc*\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "find /root/autodl-tmp/distrib_canary_collapse/results/ -name \"*d017*\" -o -name \"*differenc*\" -type f",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-15T15:42:03.796955+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-15T15:42:03.797069+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-19828",
  "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/consensus/consensus_classification.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-19828",
    "command": "cat /root/autodl-tmp/distrib_canary_collapse/results/mvp/analysis/consensus/consensus_classification.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-15T15:42:03.797326+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"classifications\\\": [\\n    {\\n      \\\"pair_index\\\": 0,\\n      \\\"n_sig_methods\\\": 3,\\n      \\\"is_robust\\\": false,\\n      \\\"method_verdicts\\\": [\\n        true,\\n        true,\\n        true,\\n        false,\\n        false\\n      ],\\n      \\\"seed_counts\\\": [\\n        4,\\n        4,\\n        4,\\n        0,\\n        0\\n      ],\\n      \\\"canary\\\": \\\"token_entropy\\\",\\n      \\\"downstream\\\": \\\"perplexity\\\",\\n      \\\"pair_label\\\": \\\"token_entropy\\\\u2192perplexity\\\"\\n    },\\n    {\\n      \\\"pair_index\\\": 1,\\n      \\\"n_sig_methods\\\": 5,\\n      \\\"is_robust\\\": true,\\n      \\\"method_verdicts\\\": [\\n        true,\\n        true,\\n        true,\\n        true,\\n        true\\n      ],\\n      \\\"seed_counts\\\": [\\n        4,\\n        4,\\n        4,\\n        4,\\n        4\\n      ],\\n      \\\"canary\\\": \\\"token_entropy\\\",\\n      \\\"downstream\\\": \\\"distinct_1\\\",\\n      \\\"pair_label\\\": \\\"token_entropy\\\\u2192distinct_1\\\"\\n    },\\n    {\\n      \\\"pair_index\\\": 2,\\n      \\\"n_sig_methods\\\": 5,\\n      \\\"is_robust\\\": true,\\n      \\\"method_verdicts\\\": [\\n        true,\\n        true,\\n        true,\\n        true,\\n        true\\n      ],\\n      \\\"seed_counts\\\": [\\n        4,\\n        4,\\n        4,\\n        4,\\n        4\\n      ],\\n      \\\"canary\\\": \\\"token_entropy\\\",\\n      \\\"downstream\\\": \\\"distinct_2\\\",\\n      \\\"pair_label\\\": \\\"token_entropy\\\\u2192distinct_2\\\"\\n    },\\n    {\\n      \\\"pair_index\\\": 3,\\n      \\\"n_sig_methods\\\": 5,\\n      \\\"is_robust\\\": true,\\n      \\\"method_verdicts\\\": [\\n        true,\\n        true,\\n        true,\\n        true,\\n        true\\n      ],\\n      \\\"seed_counts\\\": [\\n        4,\\n        4,\\n        4,\\n        4,\\n        3\\n      ],\\n      \\\"canary\\\": \\\"token_entropy
…[truncated 6512 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-15T15:42:03.797632+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "mkdir -p /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis",
  "description": "Create pipeline_analysis artifacts directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "Bash",
  "tool_args": {
    "command": "mkdir -p /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis",
    "description": "Create pipeline_analysis artifacts directory"
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-15T15:42:03.797775+00:00_

(Bash completed with no output)

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-15T15:42:03.797987+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis/filtering_pipeline_data.json",
  "content": "{\n  \"pipeline_version\": \"v1\",\n  \"date\": \"2026-05-15\",\n  \"data_sources\": [\n    \"d028_fpr_null_control.json\",\n    \"d028_fpr_null_control_full.json\",\n    \"cross_alpha_v6.json\",\n    \"cross_alpha_v4.json\",\n    \"mvp/analysis/method_ablation.json\",\n    \"mvp/analysis/consensus/consensus_classification.json\"\n  ],\n  \"stages\": [\n    {\n      \"stage\": 1,\n      \"name\": \"Naive Correlation Scan\",\n      \"description\": \"Undifferenced Pearson correlation, no multiple-testing correction\",\n      \"role_in_pipeline\": \"Baseline showing that raw correlation flags all pairs as significant regardless of true causal structure\",\n      \"data_framework\": \"d028 per-method FPR analysis (8 unidirectional canary->downstream pairs, seed 42)\",\n      \"summary\": {\n        \"total_pairs_per_alpha\": 8,\n        \"sig_rate_all_alphas\": 1.0,\n        \"eliminated\": 0,\n        \"interpretation\": \"Naive Pearson is uninformative: 100% sig rate even at null control\"\n      },\n      \"per_alpha\": {\n        \"0.00\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0,\n          \"note\": \"Null control (zero canary injection) - all 8 significant = 100% FPR\"\n        },\n        \"0.25\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0\n        },\n        \"0.50\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0\n        },\n        \"1.00\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0,\n          \"note\": \"4-seed data: 32/32 per-seed tests also all significant\"\n        }\n      },\n      \"case_studies\": [\n        {\n          \"case\": \"alpha=0.0 null control: 100% false positive rate\",\n          \"details\": \"At alpha=0.0 (zero canary injection), naive Pearson reports 8/8 pairs significant (p < 0.05). Textbook spurious regression: shared non-stationarity in iterative training drives co-movement absent any causal link.\",\n          \"data\": {\n            \"pairs\": [\n              \"token_entropy->distinct_1\",\n              \"token_entropy->distinct_2\",\n              \"token_entropy->distinct_3\",\n              \"token_entropy->perplexity\",\n              \"ece->distinct_1\",\n              \"ece->distinct_2\",\n              \"ece->distinct_3\",\n              \"ece->perplexity\"\n            ],\n            \"p_values_raw\": [0.002496, 0.006055, 0.007303, 0.0, 0.005344, 0.009665, 0.022381, 0.018795],\n            \"p_values_fdr\": [0.009984, 0.011685, 0.011685, 0.0, 0.011685, 0.012887, 0.022381, 0.02148],\n            \"all_significant\": true,\n            \"all_significant_after_fdr\": true\n          }\n        }\n      ]\n    },\n    {\n      \"stage\": 2,\n      \"name\": \"First-Differencing\",\n      \"description\": \"First-differenced cross-correlation removes shared non-stationary trends\",\n      \"role_in_pipeline\": \"Eliminates spurious associations driven by common training trends, but retains residual FP from correlated innovations\",\n      \"data_framework\": \"d028 per-method FPR analysis (8 unidirectional pairs, seed 42)\",\n      \"summary\": {\n        \"null_control_fpr_raw\": 0.5,\n        \"null_control_fpr_fdr\": 0.375,\n        \"reduction_from_naive\": \"Eliminates 0-75% of naive-significant pairs depending on alpha\"\n      },\n      \"per_alpha\": {\n        \"0.00\": {\n          \"input\": 8,\n          \"sig_raw\": 4,\n          \"sig_fdr\": 3,\n          \"eliminated_from_naive\": 4,\n          \"fpr_raw\": 0.5,\n          \"fpr_fdr\": 0.375,\n          \"note\": \"Still 50% FPR raw - differencing alone is insufficient\"\n        },\n        \"0.25\": {\n          \"input\": 8,\n          \"sig_raw\": 2,\n          \"sig_fdr\": 2,\n          \"eliminated_from_naive\": 6\n        },\n        \"0.50\": {\n          \"input\": 8,\n          \"sig_raw\": 8,\n          \"sig_fdr\": 8,\n          \"eliminated_from_naive\": 0,\n          \"note\": \"Signal strong enough to survive differencing\"\n        },\n        \"1.00\": {\n          \"input\": 8,\n          \"sig_raw\": 8,\n          \"sig_fdr\": 8,\n          \"eliminated_from_naive\": 0,\n          \"note\": \"4-seed: 32/32 per-seed sig raw, 32/32 sig FDR\"\n        }\n      },\n      \"null_control_pair_detail\": {\n        \"pairs\": [\n          \"token_entropy->distinct_1\",\n          \"token_entropy->distinct_2\",\n          \"token_entropy->distinct_3\",\n          \"token_entropy->perplexity\",\n          \"ece->distinct_1\",\n          \"ece->distinct_2\",\n          \"ece->distinct_3\",\n          \"ece->perplexity\"\n        ],\n        \"p_values_raw\": [0.000157, 0.00325, 0.044726, 2e-06, 0.051439, 0.192837, 0.202654, 0.096018],\n        \"p_values_fdr\": [0.000628, 0.008667, 0.082302, 1.6e-05, 0.082302, 0.202654, 0.202654, 0.128024],\n        \"sig_raw_mask\": [true, true, true, true, false, false, false, false],\n        \"eliminated_pairs\": [\"ece->distinct_1\", \"ece->distinct_2\", \"ece->distinct_3\", \"ece->perplexity\"],\n        \"surviving_fp_pairs\": [\"token_entropy->distinct_1\", \"token_entropy->distinct_2\", \"token_entropy->distinct_3\", \"token_entropy->perplexity\"],\n        \"note\": \"Differencing removes all ECE->downstream spurious correlations at null but leaves all 4 token_entropy->downstream as residual FP\"\n      },\n      \"case_studies\": [\n        {\n          \"case\": \"alpha=0.0: differenced FPR ~50% (D028 finding)\",\n          \"details\": \"At null control, differencing reduces naive 8/8 sig to 4/8 sig (FPR=50% raw, 37.5% FDR). Surviving FP are all token_entropy->downstream. ECE->downstream spurious links are successfully eliminated.\",\n          \"data\": {\n            \"naive_sig\": 8,\n            \"differenced_sig\": 4,\n            \"reduction_pct\": 50.0,\n            \"eliminated_category\": \"ECE->downstream (4 pairs)\",\n            \"surviving_fp_category\": \"token_entropy->downstream (4 pairs)\"\n          }\n        },\n        {\n          \"case\": \"alpha=0.25: differencing eliminates 6/8 pairs\",\n          \"details\": \"At low canary fraction (25%), differencing removes most naive associations, leaving only 2/8 significant. Shows differencing is more effective at low signal-to-noise.\"\n        },\n        {\n          \"case\": \"Method ablation at alpha=1.0: differenced 14/16 sig vs naive 16/16\",\n          \"details\": \"At full canary injection with 4 seeds, differencing eliminates 2/16 pairs that naive finds significant. Source: method_ablation.json summary.\",\n          \"data\": {\n            \"naive_significant\": 16,\n            \"differenced_significant\": 14,\n            \"eliminated_count\": 2,\n            \"source\": \"method_ablation.json\"\n          }\n        }\n      ]\n    },\n    {\n      \"stage\": 3,\n      \"name\": \"Permutation Granger + BH FDR\",\n      \"description\": \"Non-parametric Granger causality (differenced series, 5000 permutations) with Benjamini-Hochberg FDR correction across all tests\",\n      \"role_in_pipeline\": \"Tests directional predictability beyond autocorrelation; FDR controls family-wise false discovery rate\",\n      \"data_framework\": \"v6 cross-alpha (5 alphas x 8 bidirectional directions = 40 tests, BH-corrected together)\",\n      \"summary_v6\": {\n        \"total_tests\": 40,\n        \"raw_sig\": 14,\n        \"fdr_sig\": 6,\n        \"eliminated_by_fdr\": 8,\n        \"raw_sig_rate\": 0.35,\n        \"fdr_sig_rate\": 0.15\n      },\n      \"summary_v4\": {\n        \"total_tests\": 32,\n        \"raw_sig\": 10,\n        \"fdr_sig\": 1,\n        \"eliminated_by_fdr\": 9,\n        \"fdr_sig_rate\": 0.03125,\n        \"only_surviving\": \"ECE->d1 @ alpha=1.0 (p_fdr=0.0192)\",\n        \"note\": \"4-alpha version (no alpha=0.75) for robustness comparison\"\n      },\n      \"null_control_validation\": {\n        \"alpha\": 0.0,\n        \"raw_sig\": 0,\n        \"fdr_sig\": 0,\n        \"fpr\": 0.0,\n        \"note\": \"Permutation Granger achieves 0% FPR at null control (cf. naive 100%, differenced 50%)\",\n        \"p_values_raw\": [0.058941, 0.093906, 0.080919, 0.67033, 0.955045, 0.549451, 0.350649, 0.365634]\n      },\n      \"per_alpha_v6\": {\n        \"0.00\": {\n          \"raw_sig\": 0,\n          \"fdr_sig\": 0,\n          \"note\": \"All 8 directions correctly non-significant at null control\"\n        },\n        \"0.25\": {\n          \"raw_sig\": 3,\n          \"fdr_sig\": 0,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"entropy->d1\", \"p_raw\": 0.0150, \"p_fdr\": 0.0667},\n            {\"direction\": \"d1->entropy\", \"p_raw\": 0.0236, \"p_fdr\": 0.0858},\n            {\"direction\": \"d2->entropy\", \"p_raw\": 0.0498, \"p_fdr\": 0.1285}\n          ],\n          \"note\": \"All 3 raw-sig eliminated by FDR; includes 2 reverse directions\"\n        },\n        \"0.50\": {\n          \"raw_sig\": 2,\n          \"fdr_sig\": 0,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"ECE->d1\", \"p_raw\": 0.0190, \"p_fdr\": 0.0760},\n            {\"direction\": \"ECE->d2\", \"p_raw\": 0.0394, \"p_fdr\": 0.1285}\n          ],\n          \"note\": \"Both raw-sig eliminated by FDR\"\n        },\n        \"0.75\": {\n          \"raw_sig\": 4,\n          \"fdr_sig\": 3,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"entropy->d1\", \"p_raw\": 0.0106, \"p_fdr\": 0.0540, \"fdr_sig\": false},\n            {\"direction\": \"ECE->d1\", \"p_raw\": 0.0038, \"p_fdr\": 0.0460, \"fdr_sig\": true, \"f_stat\": 443.38, \"effect_size_f2\": 73.90},\n            {\"direction\": \"entropy->d2\", \"p_raw\": 0.0072, \"p_fdr\": 0.0480, \"fdr_sig\": true},\n            {\"direction\": \"ECE->d2\", \"p_raw\": 0.0032, \"p_fdr\": 0.0460, \"fdr_sig\": true}\n          ]\n        },\n        \"1.00\": {\n          \"raw_sig\": 5,\n          \"fdr_sig\": 3,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"entropy->d1\", \"p_raw\": 0.0060, \"p_fdr\": 0.0480, \"fdr_sig\": true},\n            {\"direction\": \"ECE->d1\", \"p_raw\": 0.0006, \"p_fdr\": 0.0240, \"fdr_sig\": true},\n            {\"direction\": \"entropy->d2\", \"p_raw\": 0.0108, \"p_fdr\": 0.0540, \"fdr_sig\": false},\n            {\"direction\": \"ECE->d2\", \"p_raw\": 0.0046, \"p_fdr\": 0.0460, \"fdr_sig\": true},\n            {\"direction\": \"d2->ECE\", \"p_raw\": 0.0430, \"p_fdr\": 0.1285, \"fdr_sig\": false}\n          ]\n        }\n      },\n      \"fdr_surviving_pairs\": [\n        {\"alpha\": 0.75, \"direction\": \"ECE->d1\", \"p_raw\": 0.0038, \"p_fdr\": 0.0460, \"f_stat\": 443.38, \"effect_size_f2\": 73.90},\n        {\"alpha\": 0.75, \"direction\": \"entropy->d2\", \"p_raw\": 0.0072, \"p_fdr\": 0.0480},\n        {\"alpha\": 0.75, \"direction\": \"ECE->d2\", \"p_raw\": 0.0032, \"p_fdr\": 0.0460},\n        {\"alpha\": 1.00, \"direction\": \"entropy->d1\", \"p_raw\": 0.0060, \"p_fdr\": 0.0480},\n        {\"alpha\": 1.00, \"direction\": \"ECE->d1\", \"p_raw\": 0.0006, \"p_fdr\": 0.0240},\n        {\"alpha\": 1.00, \"direction\": \"ECE->d2\", \"p_raw\": 0.0046, \"p_fdr\": 0.0460}\n      ],\n      \"fdr_eliminated_pairs\": [\n        {\"alpha\": 0.25, \"direction\": \"entropy->d1\", \"p_raw\": 0.0150, \"p_fdr\": 0.0667},\n        {\"alpha\": 0.25, \"direction\": \"d1->entropy\", \"p_raw\": 0.0236, \"p_fdr\": 0.0858},\n        {\"alpha\": 0.25, \"direction\": \"d2->entropy\", \"p_raw\": 0.0498, \"p_fdr\": 0.1285},\n        {\"alpha\": 0.50, \"direction\": \"ECE->d1\", \"p_raw\": 0.0190, \"p_fdr\": 0.0760},\n        {\"alpha\": 0.50, \"direction\": \"ECE->d2\", \"p_raw\": 0.0394, \"p_fdr\": 0.1285},\n        {\"alpha\": 0.75, \"direction\": \"entropy->d1\", \"p_raw\": 0.0106, \"p_fdr\": 0.0540},\n        {\"alpha\": 1.00, \"direction\": \"entropy->d2\", \"p_raw\": 0.0108, \"p_fdr\": 0.0540},\n        {\"alpha\": 1.00, \"direction\": \"d2->ECE\", \"p_raw\": 0.0430, \"p_fdr\": 0.1285}\n      ],\n      \"case_studies\": [\n        {\n          \"case\": \"v6: FDR reduces raw 14/40 to 6/40 significant tests\",\n          \"details\": \"Of 40 tests (5 alphas x 8 directions), 14 show raw p<0.05 but only 6 survive BH correction. All 6 survivors are at high-canary regimes (alpha>=0.75) and involve entropy/ECE -> diversity directions only. No reverse (downstream->canary) directions survive.\",\n          \"data\": {\n            \"raw_sig_by_alpha\": [0, 3, 2, 4, 5],\n            \"fdr_sig_by_alpha\": [0, 0, 0, 3, 3],\n            \"alpha_labels\": [0.0, 0.25, 0.5, 0.75, 1.0]\n          }\n        },\n        {\n          \"case\": \"v4 vs v6: adding alpha=0.75 changes FDR landscape\",\n          \"details\": \"v4 (32 tests): raw 10/32 -> FDR 1/32 (only ECE->d1 @ alpha=1.0 survives). v6 (40 tests): raw 14/40 -> FDR 6/40. Adding alpha=0.75 contributes 4 raw-sig tests (3 survive FDR), and redistributed BH thresholds allow 2 more alpha=1.0 tests to pass.\",\n          \"data\": {\n            \"v4\": {\"tests\": 32, \"raw_sig\": 10, \"fdr_sig\": 1},\n            \"v6\": {\"tests\": 40, \"raw_sig\": 14, \"fdr_sig\": 6}\n          }\n        },\n        {\n          \"case\": \"0% FPR at null control\",\n          \"details\": \"At alpha=0.0, permutation Granger correctly rejects all 8 directions (0/8 sig), while naive gives 100% FP and differenced gives 50% FP. This validates the method's specificity.\"\n        }\n      ]\n    },\n    {\n      \"stage\": 4,\n      \"name\": \"Multi-seed Replication\",\n      \"description\": \"Cross-seed consistency check: requires >=4/5 methods significant across >=3/4 independent seeds\",\n      \"role_in_pipeline\": \"Guards against seed-specific artifacts; quantifies single-seed overestimation\",\n      \"data_framework\": \"consensus_classification (alpha=1.0, 4 seeds: 42/43/44/45, 16 canary->downstream pairs, 5 methods)\",\n      \"data_availability\": {\n        \"alpha_1.0\": \"Complete (4 seeds)\",\n        \"alpha_0.25_0.50\": \"Pending D026 multi-seed experiments\",\n        \"alpha_0.75\": \"Single-seed only (method agreement, no seed replication)\"\n      },\n      \"summary\": {\n        \"total_pairs_tested\": 16,\n        \"single_seed_robust_alpha075\": 11,\n        \"multi_seed_robust_alpha100\": 6,\n        \"eliminated_by_multi_seed\": 5,\n        \"overestimation_rate\": 0.45,\n        \"note\": \"Single-seed overestimates robustness by ~45% (11 vs 6)\"\n      },\n      \"consensus_params\": {\n        \"method_threshold\": \">=4/5 methods\",\n        \"seed_threshold\": \">=3/4 seeds\",\n        \"methods\": [\"naive_pearson\", \"differenced_xcorr\", \"threshold_onset\", \"toda_yamamoto\", \"permutation_granger\"]\n      },\n      \"robust_pairs_alpha100\": [\n        {\n          \"pair\": \"token_entropy->distinct_1\",\n          \"n_sig_methods\": 5,\n          \"method_verdicts\": [true, true, true, true, true],\n          \"seed_counts\": [4, 4, 4, 4, 4],\n          \"note\": \"Perfect agreement: 5/5 methods, 4/4 seeds each\"\n        },\n        {\n          \"pair\": \"token_entropy->distinct_2\",\n          \"n_sig_methods\": 5,\n          \"method_verdicts\": [true, true, true, true, true],\n          \"seed_counts\": [4, 4, 4, 4, 4]\n        },\n        {\n          \"pair\": \"token_entropy->distinct_3\",\n          \"n_sig_methods\": 5,\n          \"method_verdicts\": [true, true, true, true, true],\n          \"seed_counts\": [4, 4, 4, 4, 3],\n          \"note\": \"perm_granger 3/4 seeds (still passes threshold)\"\n        },\n        {\n          \"pair\": \"ece->distinct_1\",\n          \"n_sig_methods\": 4,\n          \"method_verdicts\": [true, true, true, false, true],\n          \"seed_counts\": [4, 4, 4, 2, 4],\n          \"note\": \"TY fails (2/4 seeds) but other 4 methods pass\"\n        },\n        {\n          \"pair\": \"ece->distinct_2\",\n          \"n_sig_methods\": 4,\n          \"method_verdicts\": [true, true, true, false, true],\n          \"seed_counts\": [4, 4, 4, 2, 4],\n          \"note\": \"TY fails (2/4 seeds)\"\n        },\n        {\n          \"pair\": \"ece->distinct_3\",\n          \"n_sig_methods\": 4,\n          \"method_verdicts\": [true, true, true, false, true],\n          \"seed_counts\": [4, 4, 4, 2, 4],\n          \"note\": \"TY fails (2/4 seeds)\"\n        }\n      ],\n      \"eliminated_pairs_alpha100\": [\n        {\n          \"pair\": \"token_entropy->perplexity\",\n          \"n_sig_methods\": 3,\n          \"method_verdicts\": [true, true, true, false, false],\n          \"seed_counts\": [4, 4, 4, 0, 0],\n          \"elimination_reason\": \"threshold_onset 0/4 seeds, perm_granger 0/4 seeds\"\n        },\n        {\n          \"pair\": \"ece->perplexity\",\n          \"n_sig_methods\": 3,\n          \"method_verdicts\": [true, true, true, false, false],\n          \"seed_counts\": [4, 4, 4, 0, 0],\n          \"elimination_reason\": \"TY 0/4 seeds, perm_granger 0/4 seeds\"\n        },\n        {\n          \"pair\": \"self_bleu->perplexity\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, false, true, false, false],\n          \"seed_counts\": [4, 2, 3, 0, 0],\n          \"elimination_reason\": \"Only naive + threshold pass; differenced, TY, perm all fail\"\n        },\n        {\n          \"pair\": \"self_bleu->distinct_1\",\n          \"n_sig_methods\": 1,\n          \"method_verdicts\": [true, false, false, false, false],\n          \"seed_counts\": [4, 2, 0, 1, 1],\n          \"elimination_reason\": \"Only naive passes\"\n        },\n        {\n          \"pair\": \"self_bleu->distinct_2\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [4, 3, 0, 1, 1],\n          \"elimination_reason\": \"Only naive + differenced pass\"\n        },\n        {\n          \"pair\": \"self_bleu->distinct_3\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [4, 3, 0, 1, 1],\n          \"elimination_reason\": \"Only naive + differenced pass\"\n        },\n        {\n          \"pair\": \"effective_rank->perplexity\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [3, 4, 0, 0, 0],\n          \"elimination_reason\": \"Only naive + differenced; no causal methods pass\"\n        },\n        {\n          \"pair\": \"effective_rank->distinct_1\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [4, 3, 0, 1, 1],\n          \"elimination_reason\": \"Only naive + differenced pass\"\n        },\n        {\n          \"pair\": \"effective_rank->distinct_2\",\n          \"n_sig_methods\": 1,\n          \"method_verdicts\": [true, false, false, false, false],\n          \"seed_counts\": [4, 2, 0, 1, 0],\n          \"elimination_reason\": \"Only naive passes\"\n        },\n        {\n          \"pair\": \"effective_rank->distinct_3\",\n          \"n_sig_methods\": 1,\n          \"method_verdicts\": [true, false, false, false, false],\n          \"seed_counts\": [4, 2, 0, 1, 0],\n          \"elimination_reason\": \"Only naive passes\"\n        }\n      ],\n      \"single_seed_overestimation\": {\n        \"alpha_075_single_seed\": {\n          \"mode\": \"method_agreement_only (>=4/5 methods, 1 seed)\",\n          \"robust_count\": 11,\n          \"robust_pairs\": [\n            \"token_entropy->perplexity\",\n            \"token_entropy->distinct_1\",\n            \"token_entropy->distinct_2\",\n            \"token_entropy->distinct_3\",\n            \"ece->perplexity\",\n            \"ece->distinct_1\",\n            \"ece->distinct_2\",\n            \"ece->distinct_3\",\n            \"effective_rank->distinct_1\",\n            \"effective_rank->distinct_2\",\n            \"effective_rank->distinct_3\"\n          ]\n        },\n        \"alpha_100_multi_seed\": {\n          \"mode\": \"full_consensus (>=4/5 methods, >=3/4 seeds)\",\n          \"robust_count\": 6,\n          \"robust_pairs\": [\n            \"token_entropy->distinct_1\",\n            \"token_entropy->distinct_2\",\n            \"token_entropy->distinct_3\",\n            \"ece->distinct_1\",\n            \"ece->distinct_2\",\n            \"ece->distinct_3\"\n          ]\n        },\n        \"eliminated_by_multi_seed\": {\n          \"count\": 5,\n          \"pairs\": [\n            \"token_entropy->perplexity\",\n            \"ece->perplexity\",\n            \"effective_rank->distinct_1\",\n            \"effective_rank->distinct_2\",\n            \"effective_rank->distinct_3\"\n          ],\n          \"note\": \"These 5 pairs appeared ROBUST with single-seed method agreement at alpha=0.75 but fail the stricter multi-seed criterion at alpha=1.0\"\n        }\n      },\n      \"cross_alpha_regime_summary\": {\n        \"source\": \"v6 consensus comparison\",\n        \"per_alpha_robust_count\": {\n          \"0.00\": 0,\n          \"0.25\": 1,\n          \"0.50\": 0,\n          \"0.75\": 11,\n          \"1.00\": 6\n        },\n        \"regime_dependent_pairs\": 11,\n        \"stable_pairs\": 5,\n        \"note\": \"Regime comparison uses single-seed method agreement for alpha<1.0 and 4-seed full consensus for alpha=1.0\"\n      },\n      \"constraint_c001\": \"DO NOT cite TY cross-alpha trends from Phase 2 single-seed data. D026 multi-seed needed to confirm TY non-monotonic pattern (0%->62.5%->0%->59.4%) is reproducible vs noise.\",\n      \"pending\": \"D026 multi-seed experiments for alpha=0.25/0.50 still in progress\",\n      \"case_studies\": [\n        {\n          \"case\": \"Single-seed overestimation: alpha=0.75 (11 robust) vs alpha=1.0 multi-seed (6 robust)\",\n          \"details\": \"At alpha=0.75 with one seed, method agreement alone marks 11/16 pairs ROBUST. At alpha=1.0 with 4-seed consensus, only 6/16 survive. The 5 eliminated pairs appeared robust in seed 42 but fail cross-seed replication: token_entropy->ppl (threshold_onset/perm_granger 0/4 seeds), ece->ppl (TY/perm_granger 0/4), effective_rank->d1/d2/d3 (only 1-2 seeds for causal methods).\"\n        },\n        {\n          \"case\": \"token_entropy->perplexity: single-seed ROBUST, multi-seed spurious\",\n          \"details\": \"At alpha=0.75 (seed 42), token_entropy->ppl achieves 4/5 method agreement -> ROBUST. At alpha=1.0 across 4 seeds, only 3/5 methods pass: threshold_onset sig in 0/4 seeds (onset detection unreliable), perm_granger sig in 0/4 seeds. Classification: NOT ROBUST.\",\n          \"data\": {\n            \"alpha_075_methods\": 4,\n            \"alpha_100_methods\": 3,\n            \"alpha_100_seed_counts\": [4, 4, 4, 0, 0],\n            \"failing_methods\": [\"threshold_onset (0/4 seeds)\", \"permutation_granger (0/4 seeds)\"]\n          }\n        }\n      ]\n    }\n  ],\n  \"pipeline_funnels\": {\n    \"funnel_A_null_control\": {\n      \"description\": \"Pipeline filtering at alpha=0.0 (null control) - all significance is FP\",\n      \"framework\": \"d028, 8 canary->downstream pairs\",\n      \"stages\": [\n        {\"stage\": 1, \"name\": \"Naive\", \"sig\": 8, \"eliminated\": 0, \"fpr\": 1.0},\n        {\"stage\": 2, \"name\": \"Differenced\", \"sig\": 4, \"eliminated\": 4, \"fpr\": 0.5},\n        {\"stage\": 3, \"name\": \"Perm Granger\", \"sig\": 0, \"eliminated\": 4, \"fpr\": 0.0}\n      ],\n      \"note\": \"Pipeline correctly rejects all FP at null control by Stage 3\"\n    },\n    \"funnel_B_cross_alpha_granger\": {\n      \"description\": \"Granger + FDR filtering across all alphas\",\n      \"framework_v6\": {\n        \"total_tests\": 40,\n        \"raw_sig\": 14,\n        \"fdr_sig\": 6,\n        \"note\": \"5 alphas x 8 bidirectional directions\"\n      },\n      \"framework_v4\": {\n        \"total_tests\": 32,\n        \"raw_sig\": 10,\n        \"fdr_sig\": 1,\n        \"note\": \"4 alphas x 8 bidirectional directions\"\n      }\n    },\n    \"funnel_C_method_consensus\": {\n      \"description\": \"Full pipeline at alpha=1.0 with 4-seed consensus\",\n      \"framework\": \"method_ablation, 16 canary->downstream pairs, 4 seeds\",\n      \"stages\": [\n        {\"stage\": 1, \"name\": \"Naive\", \"sig\": 16, \"eliminated\": 0},\n        {\"stage\": 2, \"name\": \"Differenced\", \"sig\": 14, \"eliminated\": 2},\n        {\"stage\": 3, \"name\": \"Perm Granger (>=3/4 seeds)\", \"sig\": 6, \"eliminated\": 8},\n        {\"stage\": 4, \"name\": \"Full Consensus (>=4/5 methods, >=3/4 seeds)\", \"sig\": 6, \"eliminated\": 0}\n      ],\n      \"note\": \"At alpha=1.0, Stages 3 and 4 converge to the same 6 pairs. Multi-seed replication's main value is at lower alphas where single-seed overestimates.\"\n    }\n  },\n  \"final_robust_pairs\": {\n    \"count\": 6,\n    \"confirmed_at\": \"alpha=1.0, 4-seed full consensus\",\n    \"pairs\": [\n      {\"canary\": \"token_entropy\", \"downstream\": \"distinct_1\", \"methods\": \"5/5\", \"interpretation\": \"Entropy collapse Granger-causes unigram diversity loss\"},\n      {\"canary\": \"token_entropy\", \"downstream\": \"distinct_2\", \"methods\": \"5/5\", \"interpretation\": \"Entropy collapse Granger-causes bigram diversity loss\"},\n      {\"canary\": \"token_entropy\", \"downstream\": \"distinct_3\", \"methods\": \"5/5\", \"interpretation\": \"Entropy collapse Granger-causes trigram diversity loss\"},\n      {\"canary\": \"ece\", \"downstream\": \"distinct_1\", \"methods\": \"4/5\", \"interpretation\": \"Calibration degradation Granger-causes unigram diversity loss\"},\n      {\"canary\": \"ece\", \"downstream\": \"distinct_2\", \"methods\": \"4/5\", \"interpretation\": \"Calibration degradation Granger-causes bigram diversity loss\"},\n      {\"canary\": \"ece\", \"downstream\": \"distinct_3\", \"methods\": \"4/5\", \"interpretation\": \"Calibration degradation Granger-causes trigram diversity loss\"}\n    ],\n    \"pattern\": \"Both canary metrics (entropy, ECE) predict all 3 diversity n-grams but NOT perplexity. self_bleu and effective_rank fail as canaries.\",\n    \"pending\": \"D026 multi-seed verification at alpha=0.25/0.50 to confirm dose-response curve\"\n  }\n}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis/filtering_pipeline_data.json",
    "content": "{\n  \"pipeline_version\": \"v1\",\n  \"date\": \"2026-05-15\",\n  \"data_sources\": [\n    \"d028_fpr_null_control.json\",\n    \"d028_fpr_null_control_full.json\",\n    \"cross_alpha_v6.json\",\n    \"cross_alpha_v4.json\",\n    \"mvp/analysis/method_ablation.json\",\n    \"mvp/analysis/consensus/consensus_classification.json\"\n  ],\n  \"stages\": [\n    {\n      \"stage\": 1,\n      \"name\": \"Naive Correlation Scan\",\n      \"description\": \"Undifferenced Pearson correlation, no multiple-testing correction\",\n      \"role_in_pipeline\": \"Baseline showing that raw correlation flags all pairs as significant regardless of true causal structure\",\n      \"data_framework\": \"d028 per-method FPR analysis (8 unidirectional canary->downstream pairs, seed 42)\",\n      \"summary\": {\n        \"total_pairs_per_alpha\": 8,\n        \"sig_rate_all_alphas\": 1.0,\n        \"eliminated\": 0,\n        \"interpretation\": \"Naive Pearson is uninformative: 100% sig rate even at null control\"\n      },\n      \"per_alpha\": {\n        \"0.00\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0,\n          \"note\": \"Null control (zero canary injection) - all 8 significant = 100% FPR\"\n        },\n        \"0.25\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0\n        },\n        \"0.50\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0\n        },\n        \"1.00\": {\n          \"input\": 8,\n          \"sig\": 8,\n          \"eliminated\": 0,\n          \"sig_rate\": 1.0,\n          \"note\": \"4-seed data: 32/32 per-seed tests also all significant\"\n        }\n      },\n      \"case_studies\": [\n        {\n          \"case\": \"alpha=0.0 null control: 100% false positive rate\",\n          \"details\": \"At alpha=0.0 (zero canary injection), naive Pearson reports 8/8 pairs significant (p < 0.05). Textbook spurious regression: shared non-stationarity in iterative training drives co-movement absent any causal link.\",\n          \"data\": {\n            \"pairs\": [\n              \"token_entropy->distinct_1\",\n              \"token_entropy->distinct_2\",\n              \"token_entropy->distinct_3\",\n              \"token_entropy->perplexity\",\n              \"ece->distinct_1\",\n              \"ece->distinct_2\",\n              \"ece->distinct_3\",\n              \"ece->perplexity\"\n            ],\n            \"p_values_raw\": [0.002496, 0.006055, 0.007303, 0.0, 0.005344, 0.009665, 0.022381, 0.018795],\n            \"p_values_fdr\": [0.009984, 0.011685, 0.011685, 0.0, 0.011685, 0.012887, 0.022381, 0.02148],\n            \"all_significant\": true,\n            \"all_significant_after_fdr\": true\n          }\n        }\n      ]\n    },\n    {\n      \"stage\": 2,\n      \"name\": \"First-Differencing\",\n      \"description\": \"First-differenced cross-correlation removes shared non-stationary trends\",\n      \"role_in_pipeline\": \"Eliminates spurious associations driven by common training trends, but retains residual FP from correlated innovations\",\n      \"data_framework\": \"d028 per-method FPR analysis (8 unidirectional pairs, seed 42)\",\n      \"summary\": {\n        \"null_control_fpr_raw\": 0.5,\n        \"null_control_fpr_fdr\": 0.375,\n        \"reduction_from_naive\": \"Eliminates 0-75% of naive-significant pairs depending on alpha\"\n      },\n      \"per_alpha\": {\n        \"0.00\": {\n          \"input\": 8,\n          \"sig_raw\": 4,\n          \"sig_fdr\": 3,\n          \"eliminated_from_naive\": 4,\n          \"fpr_raw\": 0.5,\n          \"fpr_fdr\": 0.375,\n          \"note\": \"Still 50% FPR raw - differencing alone is insufficient\"\n        },\n        \"0.25\": {\n          \"input\": 8,\n          \"sig_raw\": 2,\n          \"sig_fdr\": 2,\n          \"eliminated_from_naive\": 6\n        },\n        \"0.50\": {\n          \"input\": 8,\n          \"sig_raw\": 8,\n          \"sig_fdr\": 8,\n          \"eliminated_from_naive\": 0,\n          \"note\": \"Signal strong enough to survive differencing\"\n        },\n        \"1.00\": {\n          \"input\": 8,\n          \"sig_raw\": 8,\n          \"sig_fdr\": 8,\n          \"eliminated_from_naive\": 0,\n          \"note\": \"4-seed: 32/32 per-seed sig raw, 32/32 sig FDR\"\n        }\n      },\n      \"null_control_pair_detail\": {\n        \"pairs\": [\n          \"token_entropy->distinct_1\",\n          \"token_entropy->distinct_2\",\n          \"token_entropy->distinct_3\",\n          \"token_entropy->perplexity\",\n          \"ece->distinct_1\",\n          \"ece->distinct_2\",\n          \"ece->distinct_3\",\n          \"ece->perplexity\"\n        ],\n        \"p_values_raw\": [0.000157, 0.00325, 0.044726, 2e-06, 0.051439, 0.192837, 0.202654, 0.096018],\n        \"p_values_fdr\": [0.000628, 0.008667, 0.082302, 1.6e-05, 0.082302, 0.202654, 0.202654, 0.128024],\n        \"sig_raw_mask\": [true, true, true, true, false, false, false, false],\n        \"eliminated_pairs\": [\"ece->distinct_1\", \"ece->distinct_2\", \"ece->distinct_3\", \"ece->perplexity\"],\n        \"surviving_fp_pairs\": [\"token_entropy->distinct_1\", \"token_entropy->distinct_2\", \"token_entropy->distinct_3\", \"token_entropy->perplexity\"],\n        \"note\": \"Differencing removes all ECE->downstream spurious correlations at null but leaves all 4 token_entropy->downstream as residual FP\"\n      },\n      \"case_studies\": [\n        {\n          \"case\": \"alpha=0.0: differenced FPR ~50% (D028 finding)\",\n          \"details\": \"At null control, differencing reduces naive 8/8 sig to 4/8 sig (FPR=50% raw, 37.5% FDR). Surviving FP are all token_entropy->downstream. ECE->downstream spurious links are successfully eliminated.\",\n          \"data\": {\n            \"naive_sig\": 8,\n            \"differenced_sig\": 4,\n            \"reduction_pct\": 50.0,\n            \"eliminated_category\": \"ECE->downstream (4 pairs)\",\n            \"surviving_fp_category\": \"token_entropy->downstream (4 pairs)\"\n          }\n        },\n        {\n          \"case\": \"alpha=0.25: differencing eliminates 6/8 pairs\",\n          \"details\": \"At low canary fraction (25%), differencing removes most naive associations, leaving only 2/8 significant. Shows differencing is more effective at low signal-to-noise.\"\n        },\n        {\n          \"case\": \"Method ablation at alpha=1.0: differenced 14/16 sig vs naive 16/16\",\n          \"details\": \"At full canary injection with 4 seeds, differencing eliminates 2/16 pairs that naive finds significant. Source: method_ablation.json summary.\",\n          \"data\": {\n            \"naive_significant\": 16,\n            \"differenced_significant\": 14,\n            \"eliminated_count\": 2,\n            \"source\": \"method_ablation.json\"\n          }\n        }\n      ]\n    },\n    {\n      \"stage\": 3,\n      \"name\": \"Permutation Granger + BH FDR\",\n      \"description\": \"Non-parametric Granger causality (differenced series, 5000 permutations) with Benjamini-Hochberg FDR correction across all tests\",\n      \"role_in_pipeline\": \"Tests directional predictability beyond autocorrelation; FDR controls family-wise false discovery rate\",\n      \"data_framework\": \"v6 cross-alpha (5 alphas x 8 bidirectional directions = 40 tests, BH-corrected together)\",\n      \"summary_v6\": {\n        \"total_tests\": 40,\n        \"raw_sig\": 14,\n        \"fdr_sig\": 6,\n        \"eliminated_by_fdr\": 8,\n        \"raw_sig_rate\": 0.35,\n        \"fdr_sig_rate\": 0.15\n      },\n      \"summary_v4\": {\n        \"total_tests\": 32,\n        \"raw_sig\": 10,\n        \"fdr_sig\": 1,\n        \"eliminated_by_fdr\": 9,\n        \"fdr_sig_rate\": 0.03125,\n        \"only_surviving\": \"ECE->d1 @ alpha=1.0 (p_fdr=0.0192)\",\n        \"note\": \"4-alpha version (no alpha=0.75) for robustness comparison\"\n      },\n      \"null_control_validation\": {\n        \"alpha\": 0.0,\n        \"raw_sig\": 0,\n        \"fdr_sig\": 0,\n        \"fpr\": 0.0,\n        \"note\": \"Permutation Granger achieves 0% FPR at null control (cf. naive 100%, differenced 50%)\",\n        \"p_values_raw\": [0.058941, 0.093906, 0.080919, 0.67033, 0.955045, 0.549451, 0.350649, 0.365634]\n      },\n      \"per_alpha_v6\": {\n        \"0.00\": {\n          \"raw_sig\": 0,\n          \"fdr_sig\": 0,\n          \"note\": \"All 8 directions correctly non-significant at null control\"\n        },\n        \"0.25\": {\n          \"raw_sig\": 3,\n          \"fdr_sig\": 0,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"entropy->d1\", \"p_raw\": 0.0150, \"p_fdr\": 0.0667},\n            {\"direction\": \"d1->entropy\", \"p_raw\": 0.0236, \"p_fdr\": 0.0858},\n            {\"direction\": \"d2->entropy\", \"p_raw\": 0.0498, \"p_fdr\": 0.1285}\n          ],\n          \"note\": \"All 3 raw-sig eliminated by FDR; includes 2 reverse directions\"\n        },\n        \"0.50\": {\n          \"raw_sig\": 2,\n          \"fdr_sig\": 0,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"ECE->d1\", \"p_raw\": 0.0190, \"p_fdr\": 0.0760},\n            {\"direction\": \"ECE->d2\", \"p_raw\": 0.0394, \"p_fdr\": 0.1285}\n          ],\n          \"note\": \"Both raw-sig eliminated by FDR\"\n        },\n        \"0.75\": {\n          \"raw_sig\": 4,\n          \"fdr_sig\": 3,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"entropy->d1\", \"p_raw\": 0.0106, \"p_fdr\": 0.0540, \"fdr_sig\": false},\n            {\"direction\": \"ECE->d1\", \"p_raw\": 0.0038, \"p_fdr\": 0.0460, \"fdr_sig\": true, \"f_stat\": 443.38, \"effect_size_f2\": 73.90},\n            {\"direction\": \"entropy->d2\", \"p_raw\": 0.0072, \"p_fdr\": 0.0480, \"fdr_sig\": true},\n            {\"direction\": \"ECE->d2\", \"p_raw\": 0.0032, \"p_fdr\": 0.0460, \"fdr_sig\": true}\n          ]\n        },\n        \"1.00\": {\n          \"raw_sig\": 5,\n          \"fdr_sig\": 3,\n          \"raw_sig_pairs\": [\n            {\"direction\": \"entropy->d1\", \"p_raw\": 0.0060, \"p_fdr\": 0.0480, \"fdr_sig\": true},\n            {\"direction\": \"ECE->d1\", \"p_raw\": 0.0006, \"p_fdr\": 0.0240, \"fdr_sig\": true},\n            {\"direction\": \"entropy->d2\", \"p_raw\": 0.0108, \"p_fdr\": 0.0540, \"fdr_sig\": false},\n            {\"direction\": \"ECE->d2\", \"p_raw\": 0.0046, \"p_fdr\": 0.0460, \"fdr_sig\": true},\n            {\"direction\": \"d2->ECE\", \"p_raw\": 0.0430, \"p_fdr\": 0.1285, \"fdr_sig\": false}\n          ]\n        }\n      },\n      \"fdr_surviving_pairs\": [\n        {\"alpha\": 0.75, \"direction\": \"ECE->d1\", \"p_raw\": 0.0038, \"p_fdr\": 0.0460, \"f_stat\": 443.38, \"effect_size_f2\": 73.90},\n        {\"alpha\": 0.75, \"direction\": \"entropy->d2\", \"p_raw\": 0.0072, \"p_fdr\": 0.0480},\n        {\"alpha\": 0.75, \"direction\": \"ECE->d2\", \"p_raw\": 0.0032, \"p_fdr\": 0.0460},\n        {\"alpha\": 1.00, \"direction\": \"entropy->d1\", \"p_raw\": 0.0060, \"p_fdr\": 0.0480},\n        {\"alpha\": 1.00, \"direction\": \"ECE->d1\", \"p_raw\": 0.0006, \"p_fdr\": 0.0240},\n        {\"alpha\": 1.00, \"direction\": \"ECE->d2\", \"p_raw\": 0.0046, \"p_fdr\": 0.0460}\n      ],\n      \"fdr_eliminated_pairs\": [\n        {\"alpha\": 0.25, \"direction\": \"entropy->d1\", \"p_raw\": 0.0150, \"p_fdr\": 0.0667},\n        {\"alpha\": 0.25, \"direction\": \"d1->entropy\", \"p_raw\": 0.0236, \"p_fdr\": 0.0858},\n        {\"alpha\": 0.25, \"direction\": \"d2->entropy\", \"p_raw\": 0.0498, \"p_fdr\": 0.1285},\n        {\"alpha\": 0.50, \"direction\": \"ECE->d1\", \"p_raw\": 0.0190, \"p_fdr\": 0.0760},\n        {\"alpha\": 0.50, \"direction\": \"ECE->d2\", \"p_raw\": 0.0394, \"p_fdr\": 0.1285},\n        {\"alpha\": 0.75, \"direction\": \"entropy->d1\", \"p_raw\": 0.0106, \"p_fdr\": 0.0540},\n        {\"alpha\": 1.00, \"direction\": \"entropy->d2\", \"p_raw\": 0.0108, \"p_fdr\": 0.0540},\n        {\"alpha\": 1.00, \"direction\": \"d2->ECE\", \"p_raw\": 0.0430, \"p_fdr\": 0.1285}\n      ],\n      \"case_studies\": [\n        {\n          \"case\": \"v6: FDR reduces raw 14/40 to 6/40 significant tests\",\n          \"details\": \"Of 40 tests (5 alphas x 8 directions), 14 show raw p<0.05 but only 6 survive BH correction. All 6 survivors are at high-canary regimes (alpha>=0.75) and involve entropy/ECE -> diversity directions only. No reverse (downstream->canary) directions survive.\",\n          \"data\": {\n            \"raw_sig_by_alpha\": [0, 3, 2, 4, 5],\n            \"fdr_sig_by_alpha\": [0, 0, 0, 3, 3],\n            \"alpha_labels\": [0.0, 0.25, 0.5, 0.75, 1.0]\n          }\n        },\n        {\n          \"case\": \"v4 vs v6: adding alpha=0.75 changes FDR landscape\",\n          \"details\": \"v4 (32 tests): raw 10/32 -> FDR 1/32 (only ECE->d1 @ alpha=1.0 survives). v6 (40 tests): raw 14/40 -> FDR 6/40. Adding alpha=0.75 contributes 4 raw-sig tests (3 survive FDR), and redistributed BH thresholds allow 2 more alpha=1.0 tests to pass.\",\n          \"data\": {\n            \"v4\": {\"tests\": 32, \"raw_sig\": 10, \"fdr_sig\": 1},\n            \"v6\": {\"tests\": 40, \"raw_sig\": 14, \"fdr_sig\": 6}\n          }\n        },\n        {\n          \"case\": \"0% FPR at null control\",\n          \"details\": \"At alpha=0.0, permutation Granger correctly rejects all 8 directions (0/8 sig), while naive gives 100% FP and differenced gives 50% FP. This validates the method's specificity.\"\n        }\n      ]\n    },\n    {\n      \"stage\": 4,\n      \"name\": \"Multi-seed Replication\",\n      \"description\": \"Cross-seed consistency check: requires >=4/5 methods significant across >=3/4 independent seeds\",\n      \"role_in_pipeline\": \"Guards against seed-specific artifacts; quantifies single-seed overestimation\",\n      \"data_framework\": \"consensus_classification (alpha=1.0, 4 seeds: 42/43/44/45, 16 canary->downstream pairs, 5 methods)\",\n      \"data_availability\": {\n        \"alpha_1.0\": \"Complete (4 seeds)\",\n        \"alpha_0.25_0.50\": \"Pending D026 multi-seed experiments\",\n        \"alpha_0.75\": \"Single-seed only (method agreement, no seed replication)\"\n      },\n      \"summary\": {\n        \"total_pairs_tested\": 16,\n        \"single_seed_robust_alpha075\": 11,\n        \"multi_seed_robust_alpha100\": 6,\n        \"eliminated_by_multi_seed\": 5,\n        \"overestimation_rate\": 0.45,\n        \"note\": \"Single-seed overestimates robustness by ~45% (11 vs 6)\"\n      },\n      \"consensus_params\": {\n        \"method_threshold\": \">=4/5 methods\",\n        \"seed_threshold\": \">=3/4 seeds\",\n        \"methods\": [\"naive_pearson\", \"differenced_xcorr\", \"threshold_onset\", \"toda_yamamoto\", \"permutation_granger\"]\n      },\n      \"robust_pairs_alpha100\": [\n        {\n          \"pair\": \"token_entropy->distinct_1\",\n          \"n_sig_methods\": 5,\n          \"method_verdicts\": [true, true, true, true, true],\n          \"seed_counts\": [4, 4, 4, 4, 4],\n          \"note\": \"Perfect agreement: 5/5 methods, 4/4 seeds each\"\n        },\n        {\n          \"pair\": \"token_entropy->distinct_2\",\n          \"n_sig_methods\": 5,\n          \"method_verdicts\": [true, true, true, true, true],\n          \"seed_counts\": [4, 4, 4, 4, 4]\n        },\n        {\n          \"pair\": \"token_entropy->distinct_3\",\n          \"n_sig_methods\": 5,\n          \"method_verdicts\": [true, true, true, true, true],\n          \"seed_counts\": [4, 4, 4, 4, 3],\n          \"note\": \"perm_granger 3/4 seeds (still passes threshold)\"\n        },\n        {\n          \"pair\": \"ece->distinct_1\",\n          \"n_sig_methods\": 4,\n          \"method_verdicts\": [true, true, true, false, true],\n          \"seed_counts\": [4, 4, 4, 2, 4],\n          \"note\": \"TY fails (2/4 seeds) but other 4 methods pass\"\n        },\n        {\n          \"pair\": \"ece->distinct_2\",\n          \"n_sig_methods\": 4,\n          \"method_verdicts\": [true, true, true, false, true],\n          \"seed_counts\": [4, 4, 4, 2, 4],\n          \"note\": \"TY fails (2/4 seeds)\"\n        },\n        {\n          \"pair\": \"ece->distinct_3\",\n          \"n_sig_methods\": 4,\n          \"method_verdicts\": [true, true, true, false, true],\n          \"seed_counts\": [4, 4, 4, 2, 4],\n          \"note\": \"TY fails (2/4 seeds)\"\n        }\n      ],\n      \"eliminated_pairs_alpha100\": [\n        {\n          \"pair\": \"token_entropy->perplexity\",\n          \"n_sig_methods\": 3,\n          \"method_verdicts\": [true, true, true, false, false],\n          \"seed_counts\": [4, 4, 4, 0, 0],\n          \"elimination_reason\": \"threshold_onset 0/4 seeds, perm_granger 0/4 seeds\"\n        },\n        {\n          \"pair\": \"ece->perplexity\",\n          \"n_sig_methods\": 3,\n          \"method_verdicts\": [true, true, true, false, false],\n          \"seed_counts\": [4, 4, 4, 0, 0],\n          \"elimination_reason\": \"TY 0/4 seeds, perm_granger 0/4 seeds\"\n        },\n        {\n          \"pair\": \"self_bleu->perplexity\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, false, true, false, false],\n          \"seed_counts\": [4, 2, 3, 0, 0],\n          \"elimination_reason\": \"Only naive + threshold pass; differenced, TY, perm all fail\"\n        },\n        {\n          \"pair\": \"self_bleu->distinct_1\",\n          \"n_sig_methods\": 1,\n          \"method_verdicts\": [true, false, false, false, false],\n          \"seed_counts\": [4, 2, 0, 1, 1],\n          \"elimination_reason\": \"Only naive passes\"\n        },\n        {\n          \"pair\": \"self_bleu->distinct_2\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [4, 3, 0, 1, 1],\n          \"elimination_reason\": \"Only naive + differenced pass\"\n        },\n        {\n          \"pair\": \"self_bleu->distinct_3\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [4, 3, 0, 1, 1],\n          \"elimination_reason\": \"Only naive + differenced pass\"\n        },\n        {\n          \"pair\": \"effective_rank->perplexity\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [3, 4, 0, 0, 0],\n          \"elimination_reason\": \"Only naive + differenced; no causal methods pass\"\n        },\n        {\n          \"pair\": \"effective_rank->distinct_1\",\n          \"n_sig_methods\": 2,\n          \"method_verdicts\": [true, true, false, false, false],\n          \"seed_counts\": [4, 3, 0, 1, 1],\n          \"elimination_reason\": \"Only naive + differenced pass\"\n        },\n        {\n          \"pair\": \"effective_rank->distinct_2\",\n          \"n_sig_methods\": 1,\n          \"method_verdicts\": [true, false, false, false, false],\n          \"seed_counts\": [4, 2, 0, 1, 0],\n          \"elimination_reason\": \"Only naive passes\"\n        },\n        {\n          \"pair\": \"effective_rank->distinct_3\",\n          \"n_sig_methods\": 1,\n          \"method_verdicts\": [true, false, false, false, false],\n          \"seed_counts\": [4, 2, 0, 1, 0],\n          \"elimination_reason\": \"Only naive passes\"\n        }\n      ],\n      \"single_seed_overestimation\": {\n        \"alpha_075_single_seed\": {\n          \"mode\": \"method_agreement_only (>=4/5 methods, 1 seed)\",\n          \"robust_count\": 11,\n          \"robust_pairs\": [\n            \"token_entropy->perplexity\",\n            \"token_entropy->distinct_1\",\n            \"token_entropy->distinct_2\",\n            \"token_entropy->distinct_3\",\n            \"ece->perplexity\",\n            \"ece->distinct_1\",\n            \"ece->distinct_2\",\n            \"ece->distinct_3\",\n            \"effective_rank->distinct_1\",\n            \"effective_rank->distinct_2\",\n            \"effective_rank->distinct_3\"\n          ]\n        },\n        \"alpha_100_multi_seed\": {\n          \"mode\": \"full_consensus (>=4/5 methods, >=3/4 seeds)\",\n          \"robust_count\": 6,\n          \"robust_pairs\": [\n            \"token_entropy->distinct_1\",\n            \"token_entropy->distinct_2\",\n            \"token_entropy->distinct_3\",\n            \"ece->distinct_1\",\n            \"ece->distinct_2\",\n            \"ece->distinct_3\"\n          ]\n        },\n        \"eliminated_by_multi_seed\": {\n          \"count\": 5,\n          \"pairs\": [\n            \"token_entropy->perplexity\",\n            \"ece->perplexity\",\n            \"effective_rank->distinct_1\",\n            \"effective_rank->distinct_2\",\n            \"effective_rank->distinct_3\"\n          ],\n          \"note\": \"These 5 pairs appeared ROBUST with single-seed method agreement at alpha=0.75 but fail the stricter multi-seed criterion at alpha=1.0\"\n        }\n      },\n      \"cross_alpha_regime_summary\": {\n        \"source\": \"v6 consensus comparison\",\n        \"per_alpha_robust_count\": {\n          \"0.00\": 0,\n          \"0.25\": 1,\n          \"0.50\": 0,\n          \"0.75\": 11,\n          \"1.00\": 6\n        },\n        \"regime_dependent_pairs\": 11,\n        \"stable_pairs\": 5,\n        \"note\": \"Regime comparison uses single-seed method agreement for alpha<1.0 and 4-seed full consensus for alpha=1.0\"\n      },\n      \"constraint_c001\": \"DO NOT cite TY cross-alpha trends from Phase 2 single-seed data. D026 multi-seed needed to confirm TY non-monotonic pattern (0%->62.5%->0%->59.4%) is reproducible vs noise.\",\n      \"pending\": \"D026 multi-seed experiments for alpha=0.25/0.50 still in progress\",\n      \"case_studies\": [\n        {\n          \"case\": \"Single-seed overestimation: alpha=0.75 (11 robust) vs alpha=1.0 multi-seed (6 robust)\",\n          \"details\": \"At alpha=0.75 with one seed, method agreement alone marks 11/16 pairs ROBUST. At alpha=1.0 with 4-seed consensus, only 6/16 survive. The 5 eliminated pairs appeared robust in seed 42 but fail cross-seed replication: token_entropy->ppl (threshold_onset/perm_granger 0/4 seeds), ece->ppl (TY/perm_granger 0/4), effective_rank->d1/d2/d3 (only 1-2 seeds for causal methods).\"\n        },\n        {\n          \"case\": \"token_entropy->perplexity: single-seed ROBUST, multi-seed spurious\",\n          \"details\": \"At alpha=0.75 (seed 42), token_entropy->ppl achieves 4/5 method agreement -> ROBUST. At alpha=1.0 across 4 seeds, only 3/5 methods pass: threshold_onset sig in 0/4 seeds (onset detection unreliable), perm_granger sig in 0/4 seeds. Classification: NOT ROBUST.\",\n          \"data\": {\n            \"alpha_075_methods\": 4,\n            \"alpha_100_methods\": 3,\n            \"alpha_100_seed_counts\": [4, 4, 4, 0, 0],\n            \"failing_methods\": [\"threshold_onset (0/4 seeds)\", \"permutation_granger (0/4 seeds)\"]\n          }\n        }\n      ]\n    }\n  ],\n  \"pipeline_funnels\": {\n    \"funnel_A_null_control\": {\n      \"description\": \"Pipeline filtering at alpha=0.0 (null control) - all significance is FP\",\n      \"framework\": \"d028, 8 canary->downstream pairs\",\n      \"stages\": [\n        {\"stage\": 1, \"name\": \"Naive\", \"sig\": 8, \"eliminated\": 0, \"fpr\": 1.0},\n        {\"stage\": 2, \"name\": \"Differenced\", \"sig\": 4, \"eliminated\": 4, \"fpr\": 0.5},\n        {\"stage\": 3, \"name\": \"Perm Granger\", \"sig\": 0, \"eliminated\": 4, \"fpr\": 0.0}\n      ],\n      \"note\": \"Pipeline correctly rejects all FP at null control by Stage 3\"\n    },\n    \"funnel_B_cross_alpha_granger\": {\n      \"description\": \"Granger + FDR filtering across all alphas\",\n      \"framework_v6\": {\n        \"total_tests\": 40,\n        \"raw_sig\": 14,\n        \"fdr_sig\": 6,\n        \"note\": \"5 alphas x 8 bidirectional directions\"\n      },\n      \"framework_v4\": {\n        \"total_tests\": 32,\n        \"raw_sig\": 10,\n        \"fdr_sig\": 1,\n        \"note\": \"4 alphas x 8 bidirectional directions\"\n      }\n    },\n    \"funnel_C_method_consensus\": {\n      \"description\": \"Full pipeline at alpha=1.0 with 4-seed consensus\",\n      \"framework\": \"method_ablation, 16 canary->downstream pairs, 4 seeds\",\n      \"stages\": [\n        {\"stage\": 1, \"name\": \"Naive\", \"sig\": 16, \"eliminated\": 0},\n        {\"stage\": 2, \"name\": \"Differenced\", \"sig\": 14, \"eliminated\": 2},\n        {\"stage\": 3, \"name\": \"Perm Granger (>=3/4 seeds)\", \"sig\": 6, \"eliminated\": 8},\n        {\"stage\": 4, \"name\": \"Full Consensus (>=4/5 methods, >=3/4 seeds)\", \"sig\": 6, \"eliminated\": 0}\n      ],\n      \"note\": \"At alpha=1.0, Stages 3 and 4 converge to the same 6 pairs. Multi-seed replication's main value is at lower alphas where single-seed overestimates.\"\n    }\n  },\n  \"final_robust_pairs\": {\n    \"count\": 6,\n    \"confirmed_at\": \"alpha=1.0, 4-seed full consensus\",\n    \"pairs\": [\n      {\"canary\": \"token_entropy\", \"downstream\": \"distinct_1\", \"methods\": \"5/5\", \"interpretation\": \"Entropy collapse Granger-causes unigram diversity loss\"},\n      {\"canary\": \"token_entropy\", \"downstream\": \"distinct_2\", \"methods\": \"5/5\", \"interpretation\": \"Entropy collapse Granger-causes bigram diversity loss\"},\n      {\"canary\": \"token_entropy\", \"downstream\": \"distinct_3\", \"methods\": \"5/5\", \"interpretation\": \"Entropy collapse Granger-causes trigram diversity loss\"},\n      {\"canary\": \"ece\", \"downstream\": \"distinct_1\", \"methods\": \"4/5\", \"interpretation\": \"Calibration degradation Granger-causes unigram diversity loss\"},\n      {\"canary\": \"ece\", \"downstream\": \"distinct_2\", \"methods\": \"4/5\", \"interpretation\": \"Calibration degradation Granger-causes bigram diversity loss\"},\n      {\"canary\": \"ece\", \"downstream\": \"distinct_3\", \"methods\": \"4/5\", \"interpretation\": \"Calibration degradation Granger-causes trigram diversity loss\"}\n    ],\n    \"pattern\": \"Both canary metrics (entropy, ECE) predict all 3 diversity n-grams but NOT perplexity. self_bleu and effective_rank fail as canaries.\",\n    \"pending\": \"D026 multi-seed verification at alpha=0.25/0.50 to confirm dose-response curve\"\n  }\n}\n"
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-15T15:42:03.798424+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis/filtering_pipeline_data.json

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-15T15:42:03.798588+00:00_

called mcp__agent-ml-research__register_artifact

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact</summary>

```json
{
  "name": "filtering_pipeline_data",
  "type": "data",
  "description": "4-stage sequential filtering pipeline structured data (naive -> differencing -> Granger+FDR -> multi-seed). Contains per-stage sig counts, case studies, FDR-surviving/eliminated pair lists, null control validation, and 3 pipeline funnels for paper figure.",
  "project": "distrib_canary_collapse",
  "exp_id": "D040",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis/filtering_pipeline_data.json",
  "tags": "['pipeline', 'filtering', 'figure-data', 'D028', 'v6', 'consensus']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__register_artifact",
  "tool_args": {
    "name": "filtering_pipeline_data",
    "type": "data",
    "description": "4-stage sequential filtering pipeline structured data (naive -> differencing -> Granger+FDR -> multi-seed). Contains per-stage sig counts, case studies, FDR-surviving/eliminated pair lists, null control validation, and 3 pipeline funnels for paper figure.",
    "project": "distrib_canary_collapse",
    "exp_id": "D040",
    "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/pipeline_analysis/filtering_pipeline_data.json",
    "tags": "['pipeline', 'filtering', 'figure-data', 'D028', 'v6', 'consensus']"
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-15T15:42:03.798745+00:00_

{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_4ac8b4\", \"name\": \"filtering_pipeline_data\", \"type\": \"data\", \"description\": \"4-stage sequential filtering pipeline structured data (naive -> differencing -> Granger+FDR -> multi-seed). Contains per-stage sig counts, case studies, FDR-surviving/eliminated pair lists, null control validation, and 3 pipeline funnels for paper figure.\", \"path\": \"projects/distrib_canary_collapse/artifacts/D040/data/filtering_pipeline_data.json\", \"url\": null, \"project\": \"distrib_canary_collapse\", \"exp_id\": \"D040\", \"skill\": \"\", \"created_at\": \"2026-05-15T15:41:52.995516+00:00\", \"tags\": [\"pipeline\", \"filtering\", \"figure-data\", \"D028\", \"v6\", \"consensus\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235",
  "tool": "mcp__agent-ml-research__register_artifact",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 37 · 2026-05-15T15:42:03.798906+00:00_

产出完成。

**文件**: `artifacts/D040/data/filtering_pipeline_data.json` (art_20260515_4ac8b4)

**内容结构**:
- **Stage 1 (Naive)**: α=0.0 null control 8/8 sig (100% FPR)，所有 α 均 100%
- **Stage 2 (Differencing)**: α=0.0 降至 4/8 sig (50% FPR)；消除全部 ECE→downstream，保留 4 个 token_entropy→downstream 残余 FP
- **Stage 3 (Granger+FDR)**: v6 40 tests: raw 14→FDR 6；v4 32 tests: raw 10→FDR 1；null control 0% FPR 验证；6 个 FDR 存活 pair 全在 α≥0.75 的 entropy/ECE→diversity 方向
- **Stage 4 (Multi-seed)**: α=0.75 单 seed 11/16 robust → α=1.0 四 seed 6/16 robust，单 seed 高估 ~45%
- **3 个 funnel**: A=null control 漏斗(8→4→0), B=cross-alpha Granger FDR 对比(v4 vs v6), C=α=1.0 全方法漏斗(16→14→6→6)
- **最终 6 个 robust pairs**: token_entropy→d1/d2/d3 + ece→d1/d2/d3；C001 约束已标注

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_analysis_filtering-pipeline-d040_20260515T153235"
}
```

</details>

---

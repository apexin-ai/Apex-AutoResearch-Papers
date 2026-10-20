# paper figure fig2 reward trajectories

**How Pruning Criteria Shape Post-RLVR Recovery: A Controlled Study of Structured MLP Pruning in a Reasoning LLM** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 15
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/chats/worker_paper_figure_fig2_reward_trajectories_20260518T022200.jsonl`
- **Structured JSON:** [`bd4c3fb1c3ec38a137fb.json`](../../sessions/bd/bd4c3fb1c3ec38a137fb.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

15 recorded events

### Tool call

_source line 1 · 2026-05-18T02:23:01.236319+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/draw-paper-figure.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/draw-paper-figure.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-18T02:23:01.236936+00:00_

1	---
2	description: 生成学术论文级 matplotlib 图表——reliability diagrams、ECE heatmap、T* scatter plot、模型对比图，直接在 A6000 服务器上执行，输出 PDF/PNG
3	name: draw-paper-figure
4	scope: global
5	tags:
6	  - research
7	  - visualization
8	  - paper
9	  - matplotlib
10	version: 1
11	tools:
12	  - ssh_execute
13	---
14	
15	# Draw Paper Figure — 学术图表生成
16	
17	为 ML 论文生成发表级图表。通过 SSH 在 A6000 上运行 matplotlib 脚本，直接输出到实验目录。
18	
19	## 触发条件
20	
21	- 用户说"画个图"、"生成 reliability diagram"、"做个 heatmap"
22	- 论文写作阶段需要插图
23	- 实验结果需要可视化汇总
24	
25	## 通用样式标准（所有图表必须遵守）
26	
27	```python
28	import matplotlib
29	matplotlib.use('Agg')
30	import matplotlib.pyplot as plt
31	import matplotlib.patches as mpatches
32	import numpy as np
33	
34	# 字体和全局样式
35	plt.rcParams.update({
36	    'font.family': 'DejaVu Sans',
37	    'font.size': 11,
38	    'axes.titlesize': 13,
39	    'axes.labelsize': 12,
40	    'xtick.labelsize': 10,
41	    'ytick.labelsize': 10,
42	    'legend.fontsize': 10,
43	    'figure.dpi': 300,
44	    'savefig.dpi': 300,
45	    'savefig.bbox': 'tight',
46	    'savefig.pad_inches': 0.05,
47	    'axes.spines.top': False,
48	    'axes.spines.right': False,
49	    'lines.linewidth': 1.8,
50	})
51	
52	# 色盲友好配色（Okabe-Ito）
53	COLORS = {
54	    'fp16':   '#E69F00',  # 橙黄
55	    'nf4':    '#56B4E9',  # 天蓝
56	    'int8':   '#009E73',  # 绿
57	    'gptq':   '#F0E442',  # 黄
58	    'awq':    '#CC79A7',  # 粉紫
59	    'llama':  '#0072B2',  # 深蓝
60	    'qwen3':  '#D55E00',  # 橙红
61	    'gemma':  '#009E73',  # 绿
62	    'mistral':'#CC79A7',  # 粉紫
63	    'phi3':   '#F0E442',  # 黄
64	}
65	
66	# 方法标签
67	METHOD_LABELS = {
68	    'fp16': 'FP16', 'nf4': 'BNB-NF4',
69	    'int8': 'BNB-INT8', 'gptq': 'GPTQ-4bit', 'awq': 'AWQ-4bit'
70	}
71	```
72	
73	---
74	
75	## 1. Reliability Diagram（校准图）
76	
77	**用途**：显示模型 confidence bin vs accuracy，对角线 = 完美校准。
78	
79	```python
80	def plot_reliability_diagram(confidences, accuracies, n_bins=10,
81	                              label='', color='#0072B2',
82	                              title='Reliability
…[truncated 8160 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-18T02:23:01.237154+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/ 2>/dev/null || echo \"directory does not exist\"",
  "description": "Check if output directory exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/ 2>/dev/null || echo \"directory does not exist\"",
    "description": "Check if output directory exists"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-18T02:23:01.237397+00:00_

fig1_framework.pdf
fig1_framework.png
fig2_reward_accuracy.pdf
fig2_reward_accuracy.png
fig3_collapse_dynamics.pdf
fig3_collapse_dynamics.png
gen_fig1_framework.py
gen_fig2_reward_accuracy.py
gen_fig3_collapse_dynamics.py

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-18T02:23:01.237585+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/gen_fig2_reward_trajectories.py",
  "content": "import matplotlib\nmatplotlib.use('Agg')\nimport matplotlib.pyplot as plt\nimport numpy as np\n\nplt.rcParams.update({\n    'font.family': 'DejaVu Sans',\n    'font.size': 11,\n    'axes.titlesize': 13,\n    'axes.labelsize': 12,\n    'xtick.labelsize': 10,\n    'ytick.labelsize': 10,\n    'legend.fontsize': 10,\n    'figure.dpi': 300,\n    'savefig.dpi': 300,\n    'savefig.bbox': 'tight',\n    'savefig.pad_inches': 0.05,\n    'axes.spines.top': False,\n    'axes.spines.right': False,\n})\n\ndata = {\n    'Unpruned': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90, 100],\n        'reward': [0.20, 0.35, 0.425, 0.50, 0.55, 0.60, 0.63, 0.669, 0.65, 0.661],\n        'color': '#0072B2', 'ls': '-', 'lw': 2.5,\n    },\n    'CKA-only (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90],\n        'reward': [0.10, 0.15, 0.18, 0.22, 0.264, 0.29, 0.31, 0.342, 0.242],\n        'color': '#009E73', 'ls': '-', 'lw': 2.0,\n    },\n    'Random (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90],\n        'reward': [0.14, 0.16, 0.15, 0.17, 0.190, 0.16, 0.190, 0.18, 0.17],\n        'color': '#E69F00', 'ls': '--', 'lw': 1.8,\n    },\n    'Standard (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90, 100],\n        'reward': [0.051, 0.056, 0.067, 0.081, 0.019, 0.043, 0.047, 0.046, 0.031, 0.054],\n        'color': '#CC79A7', 'ls': '-', 'lw': 1.8,\n    },\n    'RASP (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90, 100],\n        'reward': [0.04, 0.03, 0.02, 0.015, 0.01, 0.01, 0.01, 0.01, 0.01, 0.01],\n        'color': '#D55E00', 'ls': '-', 'lw': 1.8,\n    },\n}\n\nfig, ax = plt.subplots(figsize=(7.5, 4.2))\n\nfor name, d in data.items():\n    ax.plot(d['steps'], d['reward'], color=d['color'], linestyle=d['ls'],\n            linewidth=d['lw'], marker='o', markersize=4, label=name, zorder=3)\n\nax.set_xlabel('Training Step')\nax.set_ylabel('Mean Reward')\nax.set_xlim(0, 105)\nax.set_ylim(0, 0.75)\nax.set_xticks(np.arange(0, 110, 10))\n\nax.grid(True, axis='y', alpha=0.3, color='#cccccc', zorder=0)\n\nax.annotate('peak 0.342',\n            xy=(80, 0.342), xytext=(62, 0.42),\n            fontsize=9, color='#009E73',\n            arrowprops=dict(arrowstyle='->', color='#009E73', lw=1.2),\n            ha='center')\n\nax.annotate('late decline',\n            xy=(90, 0.242), xytext=(95, 0.30),\n            fontsize=8, color='#009E73', ha='center',\n            arrowprops=dict(arrowstyle='->', color='#009E73', lw=1.0))\n\nax.legend(loc='upper left', frameon=False, ncol=1)\n\nplt.tight_layout()\n\noutdir = '/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper'\nfig.savefig(f'{outdir}/fig2_reward_trajectories.pdf')\nfig.savefig(f'{outdir}/fig2_reward_trajectories.png')\nplt.close()\nprint('Done')\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/gen_fig2_reward_trajectories.py",
    "content": "import matplotlib\nmatplotlib.use('Agg')\nimport matplotlib.pyplot as plt\nimport numpy as np\n\nplt.rcParams.update({\n    'font.family': 'DejaVu Sans',\n    'font.size': 11,\n    'axes.titlesize': 13,\n    'axes.labelsize': 12,\n    'xtick.labelsize': 10,\n    'ytick.labelsize': 10,\n    'legend.fontsize': 10,\n    'figure.dpi': 300,\n    'savefig.dpi': 300,\n    'savefig.bbox': 'tight',\n    'savefig.pad_inches': 0.05,\n    'axes.spines.top': False,\n    'axes.spines.right': False,\n})\n\ndata = {\n    'Unpruned': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90, 100],\n        'reward': [0.20, 0.35, 0.425, 0.50, 0.55, 0.60, 0.63, 0.669, 0.65, 0.661],\n        'color': '#0072B2', 'ls': '-', 'lw': 2.5,\n    },\n    'CKA-only (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90],\n        'reward': [0.10, 0.15, 0.18, 0.22, 0.264, 0.29, 0.31, 0.342, 0.242],\n        'color': '#009E73', 'ls': '-', 'lw': 2.0,\n    },\n    'Random (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90],\n        'reward': [0.14, 0.16, 0.15, 0.17, 0.190, 0.16, 0.190, 0.18, 0.17],\n        'color': '#E69F00', 'ls': '--', 'lw': 1.8,\n    },\n    'Standard (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90, 100],\n        'reward': [0.051, 0.056, 0.067, 0.081, 0.019, 0.043, 0.047, 0.046, 0.031, 0.054],\n        'color': '#CC79A7', 'ls': '-', 'lw': 1.8,\n    },\n    'RASP (20%)': {\n        'steps':  [10, 20, 30, 40, 50, 60, 70, 80, 90, 100],\n        'reward': [0.04, 0.03, 0.02, 0.015, 0.01, 0.01, 0.01, 0.01, 0.01, 0.01],\n        'color': '#D55E00', 'ls': '-', 'lw': 1.8,\n    },\n}\n\nfig, ax = plt.subplots(figsize=(7.5, 4.2))\n\nfor name, d in data.items():\n    ax.plot(d['steps'], d['reward'], color=d['color'], linestyle=d['ls'],\n            linewidth=d['lw'], marker='o', markersize=4, label=name, zorder=3)\n\nax.set_xlabel('Training Step')\nax.set_ylabel('Mean Reward')\nax.set_xlim(0, 105)\nax.set_ylim(0, 0.75)\nax.set_xticks(np.arange(0, 110, 10))\n\nax.grid(True, axis='y', alpha=0.3, color='#cccccc', zorder=0)\n\nax.annotate('peak 0.342',\n            xy=(80, 0.342), xytext=(62, 0.42),\n            fontsize=9, color='#009E73',\n            arrowprops=dict(arrowstyle='->', color='#009E73', lw=1.2),\n            ha='center')\n\nax.annotate('late decline',\n            xy=(90, 0.242), xytext=(95, 0.30),\n            fontsize=8, color='#009E73', ha='center',\n            arrowprops=dict(arrowstyle='->', color='#009E73', lw=1.0))\n\nax.legend(loc='upper left', frameon=False, ncol=1)\n\nplt.tight_layout()\n\noutdir = '/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper'\nfig.savefig(f'{outdir}/fig2_reward_trajectories.pdf')\nfig.savefig(f'{outdir}/fig2_reward_trajectories.png')\nplt.close()\nprint('Done')\n"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-18T02:23:01.237811+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/gen_fig2_reward_trajectories.py

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-18T02:23:01.237952+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper && python gen_fig2_reward_trajectories.py",
  "description": "Generate fig2 reward trajectories figure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper && python gen_fig2_reward_trajectories.py",
    "description": "Generate fig2 reward trajectories figure"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-18T02:23:01.238077+00:00_

Exit code 127
/bin/bash: line 1: python: command not found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-18T02:23:01.238197+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper && python3 gen_fig2_reward_trajectories.py",
  "description": "Generate fig2 with python3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper && python3 gen_fig2_reward_trajectories.py",
    "description": "Generate fig2 with python3"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-18T02:23:01.238344+00:00_

Done

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-18T02:23:01.238466+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/fig2_reward_trajectories.*",
  "description": "Verify output files exist and are non-empty"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "tool_args": {
    "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/fig2_reward_trajectories.*",
    "description": "Verify output files exist and are non-empty"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-18T02:23:01.238583+00:00_

-rw-r--r-- 1 ubuntu ubuntu  19562 May 18 02:22 /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/fig2_reward_trajectories.pdf
-rw-r--r-- 1 ubuntu ubuntu 189665 May 18 02:22 /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/fig2_reward_trajectories.png

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-18T02:23:01.238715+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/fig2_reward_trajectories.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/figures/paper/fig2_reward_trajectories.png"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-18T02:23:01.239210+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-18T02:23:01.239408+00:00_

Figure looks good. All 5 trajectories are clearly distinguishable, annotations are readable, and the visual hierarchy is correct.

**Generated files:**
- PDF: `figures/paper/fig2_reward_trajectories.pdf` (19.5 KB)
- PNG: `figures/paper/fig2_reward_trajectories.png` (189 KB)
- Script: `figures/paper/gen_fig2_reward_trajectories.py`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_figure_fig2_reward_trajectories_20260518T022200"
}
```

</details>

---

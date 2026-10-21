# writing abstract placeholder

**How Action Collapse Creates Illusory Safety in Diffusion-Based VLA Collision Avoidance Evaluation** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 23
- **Recorded user turns:** 0
- **Tool calls:** 11
- **Original source:** `logs/chats/worker_writing_abstract_placeholder_20260527T065533.jsonl`
- **Structured JSON:** [`7269eede923477e67fe4.json`](../../sessions/72/7269eede923477e67fe4.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

23 recorded events

### Tool call

_source line 1 · 2026-05-27T06:58:05.276304+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file",
  "max_results": "2"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file",
    "max_results": "2"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-27T06:58:05.276654+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-27T06:58:05.276836+00:00_

called mcp__agent-ml-research__read_project_file

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file</summary>

```json
{
  "project": "diff_collision_sdf",
  "file": "paper_framing.md",
  "max_chars": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "mcp__agent-ml-research__read_project_file",
  "tool_args": {
    "project": "diff_collision_sdf",
    "file": "paper_framing.md",
    "max_chars": "0"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-27T06:58:05.277109+00:00_

{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/paper_framing.md\", \"content\": \"# ColliForce-VLA Paper Framing\\n\\n> 维护者: Director | 最后更新: 2026-05-27 01:15 UTC | D035: Scenario B 双 seed 确认，Core Insight 修正 | Post-MVP research phase\\n\\n## Core Insight\\n\\nVLA safety 评估存在系统性缺陷：collision avoidance rate (CAR) 被 action collapse 和几何路径安全严重污染，导致 \\\"安全\\\" 指标虚高。我们通过大规模实证分析（90+ 实验, 6000+ episodes）揭示这一系统性缺陷，提出 EE displacement-filtered CAR 作为修正指标，并证明碰撞避免能力隐式来自 collision-free demonstration data，而非显式几何监督——SDF auxiliary loss 在全测试范围 λ∈[0.005, 0.1] 完全冗余，binding constraint 是 EE-only 的结构性不匹配。\\n\\n## Working Title\\n\\n\\\"Rethinking VLA Safety Evaluation: When 98% of Collision Avoidance is an Illusion\\\"\\n\\n> 聚焦评估方法论贡献（影响面广、scope-proof），SDF 作为验证工具而非主贡献\\n\\n## Target Venue\\n\\n**Primary**: CoRL 2026 Main / ICRA 2027 (用户明确要求主会)\\n**定位**: Diagnostic/evaluation methodology paper with positive method contribution\\n**Fit**: Robotics safety track — \\\"VLA safety metrics are fundamentally broken\\\" 对社区有直接影响\\n\\n## Core Claims (D028 重组: 4→3 claims)\\n\\n### Claim 1: CAR Metric Contaminated by Fake Safety (Primary — 证据强度 ★★★★★)\\n\\nStandard CAR metric is systematically contaminated by two distinct mechanisms: (a) action collapse producing frozen robots falsely counted as \\\"safe\\\", and (b) geometric path safety where capable robots happen to avoid obstacles without any avoidance behavior. \\\"Collision-free\\\" ≠ \\\"collision-avoiding.\\\"\\n\\n**Primary evidence — Action collapse (fake safety)**:\\n- 800 episodes A1 per-episode analysis: CAR=91.5%, but 99.6% of safe episodes show obstacle displacement < 0.1mm (~5nm median) — robot is frozen\\n- TSR=0% 独立确认 action collapse\\n- 术语修正 (D023): fake safety 判定以 TSR=0% + obstacle displacement < 0.1mm 双证据链为主\\n\\n**Supporting evidence — Capability-safety anti-correlation (原 Claim 2)**:\\n- Pi0.5 3-seed eval: TSR=74.7±1.5%, CAR=26.8±1.6% — 更强模型完成更多任务
…[truncated 9749 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "mcp__agent-ml-research__read_project_file",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-27T06:58:05.277284+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/paper/**",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/paper/**",
    "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-27T06:58:05.277460+00:00_

artifacts/_project/paper/method_draft.md
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/method.tex
docs/paper/_archive/method.tex
artifacts/_project/paper/related_work.tex
docs/paper/_archive/experiments.tex
docs/paper/_archive/conclusion_DEPRECATED.tex
artifacts/_project/paper/analysis_claim1.tex
artifacts/_project/paper/analysis_claim2.tex
artifacts/_project/paper/analysis_claim3.tex
artifacts/_project/paper/experimental_framework.tex
artifacts/_project/paper/introduction_v2.tex
artifacts/_project/paper/abstract_v2.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/related_work_v2.tex
docs/paper/archive/analysis_claim4.tex
docs/paper/_pdf_images/main_p1.png
docs/paper/_pdf_images/main_p2.png
docs/paper/_pdf_images/main_p3.png
docs/paper/_pdf_images/main_p4.png
docs/paper/_pdf_images/main_p5.png
docs/paper/_pdf_images/main_p6.png
docs/paper/_pdf_images/main_p7.png
docs/paper/_pdf_images/main_p8.png
docs/paper/_pdf_images/main_p9.png
docs/paper/_pdf_images/main_p10.png
docs/paper/_pdf_images/main_p11.png
docs/paper/_pdf_images/main_p12.png
docs/paper/_pdf_images/main_p13.png
docs/paper/_pdf_images/main_p14.png
artifacts/_project/paper/section5_5_method_boundaries.md
paper/section5_5_method_boundaries.md
docs/paper/experimental_framework.tex
docs/paper/archive/analysis_claim3.tex
docs/paper/archive/analysis_claim1.tex
docs/paper/archive/analysis_claim2.tex
artifacts/_project/paper/paper_draft.pdf
docs/paper/references.bib
docs/paper/related_work.tex
docs/paper/corl_2026.sty
docs/paper/corlabbrvnat.bst
docs/paper/main.tex
docs/paper/contingency_claim3.tex
docs/paper/method.tex
docs/paper/claim1.tex
docs/paper/claim2.tex
artifacts/_project/paper/abc_scenario_patches.md
docs/paper/abstract.tex
docs/paper/introduction.tex
docs/paper/discussion.tex
docs/paper/main.blg
docs/paper/main.bbl
docs/paper/main.aux
docs/paper/main.out
docs/paper/main.fls
docs/paper/main.log
docs/paper/main.pdf
docs/paper/main.fdb_latexmk
docs/paper/appendix.t
…[truncated 24 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-27T06:58:05.277670+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-27T06:58:05.277824+00:00_

1	\begin{abstract}
2	Vision-Language-Action (VLA) models report high Collision Avoidance Rate (CAR) on safety benchmarks, but this reported safety can be illusory: an artifact of action collapse rather than learned avoidance. On SafeLIBERO, an SDF-augmented Pi0 configuration achieves 91.5\% CAR with 0\% Task Success Rate (TSR); 99.6\% of its safe episodes exhibit displacement below 0.1\,mm, and 73.9\% remain below 1\,$\mu$m. The robot is frozen, not safe. In contrast, Pi0.5 achieves 74.7\%\,$\pm$\,1.5\% TSR and 26.8\%\,$\pm$\,1.6\% CAR with zero fake safe episodes, all exceeding 288\,mm displacement. We propose displacement-filtered CAR (CAR$_\text{f}$), which excludes episodes below a displacement threshold $\tau_d$. The bimodal displacement distribution (five orders of magnitude gap between collapsed and active episodes) makes $\tau_d$ robust across $[2, 200]$\,mm; applying CAR$_\text{f}$ collapses Pi0+A1 from 91.5\% to approximately 0\%. Beyond metric contamination, EE-only Signed Distance Field (SDF) refinement is structurally counterproductive: three ground-truth oracle variants achieve 73.1--76.9\% CAR, all below unrefined baselines (82--83\%), because SDF gradients that repel the EE simultaneously drive arm links into obstacle volumes. Attribution experiments show that collision-free demonstrations are sufficient for collision avoidance learning: LoRA-only fine-tuning raises CAR by ${\sim}$28 points (26.8\% $\to$ 54.5\%) and matches LoRA+SDF at $\lambda \in \{0.005, 0.01, 0.1\}$ ($p > 0.1$), rendering EE-only SDF supervision redundant across a 20$\times$ loss weight range. Fine-tuning produces genuine avoidance with zero frozen episodes but incurs moderate TSR degradation of ${\sim}$21--23 percentage points (74.7\% $\to$ 51.5--54.0\%). Displacement filtering is necessary for meaningful VLA safety evaluation. EE-only SDF supervision is neither necessary nor structurally sufficient for collision avoidance: across a 20$\times$ range of loss weights ($\lambda \in
…[truncated 246 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-27T06:58:05.277969+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/_project/paper/abstract_v2.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/_project/paper/abstract_v2.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-27T06:58:05.278098+00:00_

1	\begin{abstract}
2	Recent methods for collision avoidance in Vision-Language-Action (VLA) models report high Collision Avoidance Rate (CAR) on safety benchmarks and claim effective obstacle avoidance. We show that these metrics are systematically contaminated by action collapse: the model ceases to produce meaningful motion, and the resulting inaction is counted as successful avoidance. On the SafeLIBERO benchmark, a Signed Distance Field (SDF)-augmented VLA reports 91.5\% CAR, yet 99.6\% of its safe episodes exhibit end-effector displacement below 0.1\,mm. This contamination is not method-specific; a baseline without any collision objective achieves 82\% CAR with 99.4\% of safe episodes below the same threshold, and a more capable model shows the same pattern. We propose displacement-filtered CAR (CAR$_\text{f}$), which excludes sub-threshold episodes, as a corrective metric. Further analysis reveals two structural issues. First, Task Success Rate (TSR) and CAR are anti-correlated: models that move the robot through the workspace collide, while collapsed models appear safe. Second, ground-truth SDF oracle experiments demonstrate that end-effector-only refinement cannot prevent full-body collisions, as SDF gradients that repel the end-effector simultaneously drive arm links into obstacle volumes. Preliminary results indicate that training-time SDF supervision on a sufficiently capable VLA can produce genuine collision avoidance with zero frozen-action rate. Our findings establish that displacement filtering is necessary for meaningful VLA safety evaluation.
3	\end{abstract}
4	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-27T06:58:05.278226+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/main.tex",
  "limit": "50"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/main.tex",
    "limit": "50"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-27T06:58:05.278354+00:00_

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
13	\newcommand{\placeholder}[1]{\textcolor{red}{\textbf{[#1]}}}
14	
15	\title{Rethinking VLA Safety Evaluation:\\When 98\% of Collision Avoidance is an Illusion}
16	
17	\author{
18	  Anonymous Authors
19	}
20	
21	\begin{document}
22	
23	\maketitle
24	
25	\input{abstract}
26	
27	\keywords{VLA safety, collision avoidance, action collapse, signed distance fields}
28	
29	\input{introduction}
30	
31	\input{related_work}
32	
33	\input{method}
34	
35	\input{claim1}
36	
37	\input{claim2}
38	
39	\input{claim3}
40	
41	\input{discussion}
42	
43	\bibliography{references}
44	
45	\appendix
46	\input{appendix}
47	
48	\end{document}
49	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-27T06:58:05.278579+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "write_paper_section edit_paper_section",
  "max_results": "3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "write_paper_section edit_paper_section",
    "max_results": "3"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-27T06:58:05.278712+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-27T06:58:05.278827+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__write_paper_section",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__write_paper_section",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-27T06:58:05.278939+00:00_

No matching deferred tools found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-27T06:58:05.279063+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "paper section write",
  "max_results": "5"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "paper section write",
    "max_results": "5"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-27T06:58:05.279178+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-27T06:58:05.279328+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex",
  "old_string": "\\begin{abstract}\nVision-Language-Action (VLA) models report high Collision Avoidance Rate (CAR) on safety benchmarks, but this reported safety can be illusory: an artifact of action collapse rather than learned avoidance. On SafeLIBERO, an SDF-augmented Pi0 configuration achieves 91.5\\% CAR with 0\\% Task Success Rate (TSR); 99.6\\% of its safe episodes exhibit displacement below 0.1\\,mm, and 73.9\\% remain below 1\\,$\\mu$m. The robot is frozen, not safe. In contrast, Pi0.5 achieves 74.7\\%\\,$\\pm$\\,1.5\\% TSR and 26.8\\%\\,$\\pm$\\,1.6\\% CAR with zero fake safe episodes, all exceeding 288\\,mm displacement. We propose displacement-filtered CAR (CAR$_\\text{f}$), which excludes episodes below a displacement threshold $\\tau_d$. The bimodal displacement distribution (five orders of magnitude gap between collapsed and active episodes) makes $\\tau_d$ robust across $[2, 200]$\\,mm; applying CAR$_\\text{f}$ collapses Pi0+A1 from 91.5\\% to approximately 0\\%. Beyond metric contamination, EE-only Signed Distance Field (SDF) refinement is structurally counterproductive: three ground-truth oracle variants achieve 73.1--76.9\\% CAR, all below unrefined baselines (82--83\\%), because SDF gradients that repel the EE simultaneously drive arm links into obstacle volumes. Attribution experiments show that collision-free demonstrations are sufficient for collision avoidance learning: LoRA-only fine-tuning raises CAR by ${\\sim}$28 points (26.8\\% $\\to$ 54.5\\%) and matches LoRA+SDF at $\\lambda \\in \\{0.005, 0.01, 0.1\\}$ ($p > 0.1$), rendering EE-only SDF supervision redundant across a 20$\\times$ loss weight range. Fine-tuning produces genuine avoidance with zero frozen episodes but incurs moderate TSR degradation of ${\\sim}$21--23 percentage points (74.7\\% $\\to$ 51.5--54.0\\%). Displacement filtering is necessary for meaningful VLA safety evaluation. EE-only SDF supervision is neither necessary nor structurally sufficient for collision avoidance: across a 20$\\times$ range of loss weights ($\\lambda \\in [0.005, 0.1]$), collision-free demonstrations account for the entire avoidance gain with identical per-task patterns, while ground-truth oracle refinement produces more collisions by redistributing them to unmonitored arm links.\n\\end{abstract}",
  "new_string": "\\begin{abstract}\nVision-Language-Action (VLA) models report high Collision Avoidance Rates (CAR) on safety benchmarks, yet we show these metrics are systematically contaminated by action collapse.\nOn SafeLIBERO, an SDF-augmented Pi0 achieves 91.5\\% CAR while 99.6\\% of its safe episodes exhibit end-effector displacement below 0.1\\,mm---the robot is frozen, not safe.\nWe present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\\,mm threshold range.\nOur analysis further reveals that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.\nIt is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as SDF gradients repelling the end-effector drive arm links into obstacles.\nIt is redundant during training: LoRA-only fine-tuning raises CAR from 28.5\\% to 54.5\\%$\\,\\pm\\,$2.83, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61) \\placeholder{$\\lambda{=}0.1$ 30K three-seed results pending}.\nPer-task avoidance patterns remain identical across all conditions, indicating that collision avoidance arises from collision-free demonstration data rather than geometric supervision.\nDisplacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.\n\\end{abstract}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex",
    "old_string": "\\begin{abstract}\nVision-Language-Action (VLA) models report high Collision Avoidance Rate (CAR) on safety benchmarks, but this reported safety can be illusory: an artifact of action collapse rather than learned avoidance. On SafeLIBERO, an SDF-augmented Pi0 configuration achieves 91.5\\% CAR with 0\\% Task Success Rate (TSR); 99.6\\% of its safe episodes exhibit displacement below 0.1\\,mm, and 73.9\\% remain below 1\\,$\\mu$m. The robot is frozen, not safe. In contrast, Pi0.5 achieves 74.7\\%\\,$\\pm$\\,1.5\\% TSR and 26.8\\%\\,$\\pm$\\,1.6\\% CAR with zero fake safe episodes, all exceeding 288\\,mm displacement. We propose displacement-filtered CAR (CAR$_\\text{f}$), which excludes episodes below a displacement threshold $\\tau_d$. The bimodal displacement distribution (five orders of magnitude gap between collapsed and active episodes) makes $\\tau_d$ robust across $[2, 200]$\\,mm; applying CAR$_\\text{f}$ collapses Pi0+A1 from 91.5\\% to approximately 0\\%. Beyond metric contamination, EE-only Signed Distance Field (SDF) refinement is structurally counterproductive: three ground-truth oracle variants achieve 73.1--76.9\\% CAR, all below unrefined baselines (82--83\\%), because SDF gradients that repel the EE simultaneously drive arm links into obstacle volumes. Attribution experiments show that collision-free demonstrations are sufficient for collision avoidance learning: LoRA-only fine-tuning raises CAR by ${\\sim}$28 points (26.8\\% $\\to$ 54.5\\%) and matches LoRA+SDF at $\\lambda \\in \\{0.005, 0.01, 0.1\\}$ ($p > 0.1$), rendering EE-only SDF supervision redundant across a 20$\\times$ loss weight range. Fine-tuning produces genuine avoidance with zero frozen episodes but incurs moderate TSR degradation of ${\\sim}$21--23 percentage points (74.7\\% $\\to$ 51.5--54.0\\%). Displacement filtering is necessary for meaningful VLA safety evaluation. EE-only SDF supervision is neither necessary nor structurally sufficient for collision avoidance: across a 20$\\times$ range of loss weights ($\\lambda \\in [0.005, 0.1]$), collision-free demonstrations account for the entire avoidance gain with identical per-task patterns, while ground-truth oracle refinement produces more collisions by redistributing them to unmonitored arm links.\n\\end{abstract}",
    "new_string": "\\begin{abstract}\nVision-Language-Action (VLA) models report high Collision Avoidance Rates (CAR) on safety benchmarks, yet we show these metrics are systematically contaminated by action collapse.\nOn SafeLIBERO, an SDF-augmented Pi0 achieves 91.5\\% CAR while 99.6\\% of its safe episodes exhibit end-effector displacement below 0.1\\,mm---the robot is frozen, not safe.\nWe present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\\,mm threshold range.\nOur analysis further reveals that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.\nIt is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as SDF gradients repelling the end-effector drive arm links into obstacles.\nIt is redundant during training: LoRA-only fine-tuning raises CAR from 28.5\\% to 54.5\\%$\\,\\pm\\,$2.83, matching SDF-augmented training at $\\lambda{=}0.005$ (54.5\\%$\\,\\pm\\,$2.29) and $\\lambda{=}0.01$ (56.33\\%$\\,\\pm\\,$1.61) \\placeholder{$\\lambda{=}0.1$ 30K three-seed results pending}.\nPer-task avoidance patterns remain identical across all conditions, indicating that collision avoidance arises from collision-free demonstration data rather than geometric supervision.\nDisplacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.\n\\end{abstract}"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-27T06:58:05.279545+00:00_

The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-27T06:58:05.279672+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-27T06:58:05.279800+00:00_

1	\begin{abstract}
2	Vision-Language-Action (VLA) models report high Collision Avoidance Rates (CAR) on safety benchmarks, yet we show these metrics are systematically contaminated by action collapse.
3	On SafeLIBERO, an SDF-augmented Pi0 achieves 91.5\% CAR while 99.6\% of its safe episodes exhibit end-effector displacement below 0.1\,mm---the robot is frozen, not safe.
4	We present displacement-filtered CAR (dfCAR), which excludes sub-threshold episodes, as a corrective metric; the bimodal displacement distribution makes it robust across a $[2, 200]$\,mm threshold range.
5	Our analysis further reveals that end-effector-only Signed Distance Field (SDF) supervision is neither necessary nor structurally sufficient for collision avoidance.
6	It is counterproductive at inference time: three ground-truth oracle variants all reduce CAR below unrefined baselines, as SDF gradients repelling the end-effector drive arm links into obstacles.
7	It is redundant during training: LoRA-only fine-tuning raises CAR from 28.5\% to 54.5\%$\,\pm\,$2.83, matching SDF-augmented training at $\lambda{=}0.005$ (54.5\%$\,\pm\,$2.29) and $\lambda{=}0.01$ (56.33\%$\,\pm\,$1.61) \placeholder{$\lambda{=}0.1$ 30K three-seed results pending}.
8	Per-task avoidance patterns remain identical across all conditions, indicating that collision avoidance arises from collision-free demonstration data rather than geometric supervision.
9	Displacement filtering is necessary for meaningful VLA safety evaluation; EE-only geometric supervision can be neither credited with nor expected to deliver collision avoidance.
10	\end{abstract}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_abstract_placeholder_20260527T065533",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-27T06:58:05.279966+00:00_

Abstract 初稿已写入 `docs/paper/abstract.tex`，约 185 words。

结构：Problem (CAR contaminated by action collapse) → Evidence (91.5% CAR, 99.6% frozen) → Method contribution (dfCAR) → Finding 1 (SDF counterproductive at inference) → Finding 2 (SDF redundant during training, with λ=0.1 placeholder) → Mechanistic insight (demo data is the source) → Takeaway。

需要 patch 的部分：第 7 行 `\placeholder{λ=0.1 30K three-seed results pending}`，λ=0.1 30K 数据出来后替换为实际数字并补入 λ 范围。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_writing_abstract_placeholder_20260527T065533"
}
```

</details>

---

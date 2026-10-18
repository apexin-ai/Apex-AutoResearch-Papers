# paper writing experiments

**Why Token Pruning Crashes Some Robot Policies but Not Others: Vision Connectors and VLA Token Compressibility** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 29
- **Recorded user turns:** 0
- **Tool calls:** 14
- **Original source:** `logs/chats/worker_paper_writing_experiments_20260517T131612.jsonl`
- **Structured JSON:** [`0438fabdd44b70686869.json`](../../sessions/04/0438fabdd44b70686869.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

29 recorded events

### Tool call

_source line 1 · 2026-05-17T13:18:00.874628+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-17T13:18:00.875200+00:00_

1	---
2	name: paper-writing-norms
3	description: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。
4	allowed-tools: [Read, Write, Edit, Glob, Grep]
5	scope: global
6	version: 2
7	priority: 9
8	tags:
9	  - writing
10	  - paper
11	  - style
12	  - norms
13	roles:
14	  - agent
15	  - worker
16	  - paper_agent
17	---
18	
19	# 论文写作风格规范
20	
21	> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。
22	
23	---
24	
25	## 一、总体写作哲学
26	
27	### 1.1 故事驱动，不是数据堆砌
28	
29	- 论文必须以"故事线"为核心展开：问题 → 洞察 → 方法 → 验证
30	- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进
31	- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌
32	- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing
33	
34	### 1.2 主线统一性
35	
36	- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**
37	- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C
38	- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机
39	- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线
40	
41	### 1.3 专有名词必须有定义
42	
43	- 首次出现的专有名词/缩写必须给出完整定义和解释
44	- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）
45	- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用
46	- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug
47	
48	### 1.4 写作前必读同类优秀论文
49	
50	- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可
51	- 重点学：
52	  - Abstract 怎么用最少篇幅讲完故事
53	  - Introduction 怎么从大问题切入到具体贡献
54	  - Related Work 怎么 positioning 自己（不是 survey）
55	  - Table/Figure 怎么压缩信息密度
56	- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大
57	- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文
58	
59	---
60	
61	## 二、Abstract 写作规范
62	
63	### 2.1 四个必答问题（150-250 words）
64	
65	Abstract 必须在很短的篇幅内清楚回答：
66	1. **研究什么问题** — 1-2 句话交代背景和痛点
67	2. **为什么重要** — 现有方法的不足（不用写太多）
68	3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）
69	4. **结果说明什么** — 用具体实验结论支撑贡献
70	
71	### 2.2 禁忌
72	
73	- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim
74	- **
…[truncated 4866 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-17T13:18:00.875400+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-17T13:18:00.875749+00:00_

1	---
2	name: latex-paper
3	description: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。
4	scope: global
5	tags:
6	- latex
7	- paper-writing
8	- academic
9	- citation
10	- submission
11	version: 1
12	roles:
13	- agent
14	- worker
15	---
16	
17	# LaTeX 论文写作全流程
18	
19	ML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。
20	
21	---
22	
23	## 1. 工作模式
24	
25	开始前选择模式：
26	
27	| 模式 | 说明 | 适用 |
28	|------|------|------|
29	| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |
30	| **Improve** | 改写已有章节，强化论证 | 修改稿 |
31	| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |
32	
33	---
34	
35	## 2. Claim-Evidence 方法论
36	
37	**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**
38	
39	### 2.1 一句话贡献
40	
41	在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。
42	
43	### 2.2 Claim-Evidence Map
44	
45	为每个 contribution 建立 claim→evidence 映射表：
46	
47	| Contribution | Claim | Evidence | Table/Figure |
48	|-------------|-------|----------|-------------|
49	| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |
50	| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |
51	| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |
52	
53	**没有直接证据支撑的 claim 必须删除或降级为 discussion。**
54	
55	### 2.3 章节起草顺序
56	
57	```
58	1. Introduction + Experiments（先确定 claim 和 evidence）
59	2. Method（评估问题稳定后再写细节）
60	3. Related Work
61	4. Abstract + Title（核心 claim 定型后最后写）
62	```
63	
64	### 2.4 Quality Gates
65	
66	投稿前必须通过：
67	- [ ] 前两段出现显式 novelty 声明
68	- [ ] 每个 contribution 有可验证的 evidence
69	- [ ] Abstract / Intro / Conclusion 的 claim 一致
70	- [ ] Limitations 真实且技术性诚实
71	- [ ] 审稿人两分钟内能识别 delta
72	
73	---
74	
75	## 3. 引用防幻觉（CRITICAL）
76	
77	**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**
78	
79	### 3.1 黄金法则
80	
81	```
82	IF 无法程序化获取引用:
83	    → 标记 [CITATION NEEDED] 或 \cite{PLACEHOLDER_verify}
84	    → 明确告知用户
85	    → 绝不编造看似合理的引用
86	```
87	
88	### 3.2 五步验证流程
89	
90	```
91	1. SEARCH  → Semantic Scholar API 搜索关键词
92	2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）
93	3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）
94	4. CHECK   → 确认
…[truncated 7201 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T13:18:00.875913+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/ 2>/dev/null || echo \"Directory does not exist\"",
  "description": "Check if output directory exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/ 2>/dev/null || echo \"Directory does not exist\"",
    "description": "Check if output directory exists"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-17T13:18:00.876039+00:00_

Directory does not exist

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T13:18:00.876204+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "mkdir -p /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/",
  "description": "Create output directory for paper sections"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "tool_args": {
    "command": "mkdir -p /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/",
    "description": "Create output directory for paper sections"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-17T13:18:00.876331+00:00_

(Bash completed with no output)

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T13:18:00.876444+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.tex",
    "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-17T13:18:00.876556+00:00_

No files found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T13:18:00.876663+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*",
    "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-17T13:18:00.876772+00:00_

docs/paper/corl_2026.cls
docs/paper/references.bib

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T13:18:00.876879+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/references.bib"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T13:18:00.877040+00:00_

1	% References for: The Cliff Edge — Why Vision Token Reduction Fails
2	% Catastrophically in VLA Closed-Loop Control
3	% Auto-generated from literature_map.yaml (verified entries only)
4	% 2026-05-17
5	
6	% ============================================================
7	% VLA Models
8	% ============================================================
9	
10	@article{shukor2025smolvla,
11	  title={{SmolVLA}: A Vision-Language-Action Model for Affordable and Efficient Robotics},
12	  author={Shukor, Mustafa and Aubakirova, Dana and Casas, Adrien and others},
13	  journal={arXiv preprint arXiv:2506.01844},
14	  year={2025}
15	}
16	
17	@inproceedings{kim2024openvla,
18	  title={{OpenVLA}: An Open-Source Vision-Language-Action Model},
19	  author={Kim, Moo Jin and Pertsch, Karl and Karamcheti, Siddharth and others},
20	  booktitle={Proceedings of the 8th Conference on Robot Learning (CoRL)},
21	  year={2024}
22	}
23	
24	@inproceedings{zitkovich2023rt2,
25	  title={{RT-2}: Vision-Language-Action Models Transfer Web Knowledge to Robotic Control},
26	  author={Zitkovich, Brianna and Yu, Tianhe and Xu, Sichun and others},
27	  booktitle={Proceedings of the 7th Conference on Robot Learning (CoRL)},
28	  year={2023}
29	}
30	
31	@article{ghosh2024octo,
32	  title={Octo: An Open-Source Generalist Robot Policy},
33	  author={Ghosh, Dibya and Walke, Homer and Pertsch, Karl and others},
34	  journal={arXiv preprint arXiv:2405.12213},
35	  year={2024}
36	}
37	
38	@article{black2024pi0,
39	  title={$\pi_0$: A Vision-Language-Action Flow Model for General Robot Control},
40	  author={Black, Kevin and Brown, Noah and Driess, Danny and others},
41	  journal={arXiv preprint arXiv:2410.24164},
42	  year={2024}
43	}
44	
45	@inproceedings{openxembodiment2024,
46	  title={Open {X-Embodiment}: Robotic Learning Datasets and {RT-X} Models},
47	  author={{Open X-Embodiment Collaboration}},
48	  booktitle={IEEE International Conference on Robotics and Automation (ICRA)},
49	  year={2024}
50	}
51	
52	%
…[truncated 5739 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-17T13:18:00.877251+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.pdf",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.pdf",
    "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-17T13:18:00.877423+00:00_

No files found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-17T13:18:00.877545+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/figures/**/*",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/figures/**/*",
    "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-17T13:18:00.877658+00:00_

No files found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-17T13:18:00.877814+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex",
  "content": "% experiments.tex — Section 4: Main Results\n% Experiment IDs (provenance):\n%   Baseline 44.8%:              eval_stage1_only\n%   ACIS k=0.5 zero-mask:       eval_stage1only_object_v2_fixed\n%   ACIS k=0.7 zero-mask:       eval_k07_zero_mask\n%   ACIS k=0.9 zero-mask:       eval_stage1only_k09\n%   Random k=0.5:               eval_random_prune_k05\n%   True removal k=0.5:         eval_true_removal_k05\n%   Merge k=0.5:                eval_merge_k05\n%   Spatial suite:              eval_spatial_prune_k05 (baseline 51.8%)\n%   Goal suite:                 eval_goal_prune_k05 (baseline 63%)\n\n\\section{Main Results}\n\\label{sec:results}\n\nVision token pruning in Vision Transformers (ViTs) is widely regarded as a reliable efficiency technique.\nDynamicViT~\\cite{rao2021dynamicvit} removes 30\\%--50\\% of tokens with less than 0.5\\% accuracy loss on ImageNet, and Token Merging (ToMe)~\\cite{bolya2023tome} merges up to 40\\% of tokens while retaining over 99\\% of classification accuracy.\nEViT~\\cite{liang2022evit} similarly discards 50\\% of inattentive tokens with negligible degradation.\nThese results have motivated recent proposals to apply similar strategies to Vision-Language-Action (VLA) models for real-time robotic control~\\cite{hsu2025vlacache,wang2026vlaiap}.\nOur experiments test whether this transfer holds: we apply six pruning configurations to a VLA policy and evaluate closed-loop Success Rate (SR) on the LIBERO benchmark~\\cite{liu2023libero}.\nThe result is unambiguous.\nEvery configuration produces 0\\% SR, a complete collapse we term the \\emph{cliff edge}.\n\n\\begin{table}[t]\n\\centering\n\\caption{Ablation matrix across scoring functions, retention ratios, and pruning mechanisms. All six pruning conditions produce 0\\% SR. The baseline runs the same checkpoint with pruning disabled (bypass mode). Wilson 95\\% confidence intervals (CI) are computed over independent episodes. Experiment IDs are listed for reproducibility.}\n\\label{tab:ablation_matrix}\n\\small\n\\begin{tabular}{@{}llccrrc@{}}\n\\toprule\nMethod & Scoring & $k$ & Mechanism & SR (\\%) & Episodes & Wilson 95\\% CI \\\\\n\\midrule\n\\textbf{Baseline} & \\textbf{--} & \\textbf{1.0} & \\textbf{--} & \\textbf{44.8} & \\textbf{500} & \\textbf{[40.5, 49.2]} \\\\\n\\midrule\nACIS & Learned & 0.5 & Zero-mask & 0.0 & 300+ & [0.0, 1.26] \\\\\nACIS & Learned & 0.7 & Zero-mask & 0.0 & 500 & [0.0, 0.76] \\\\\nACIS & Learned & 0.9 & Zero-mask & 0.0 & 500 & [0.0, 0.76] \\\\\nRandom & Random & 0.5 & Zero-mask & 0.0 & 500 & [0.0, 0.76] \\\\\nACIS & Learned & 0.5 & True removal & 0.0 & 500 & [0.0, 0.80] \\\\\nACIS & Learned & 0.5 & Merge & 0.0 & 500 & [0.0, 0.76] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:ablation_matrix} presents the full ablation matrix.\nWe systematically vary three axes: (1)~the scoring function that selects which tokens to prune, (2)~the retention ratio $k$ that controls how many tokens survive, and (3)~the mechanism by which pruned tokens are handled.\nThe baseline achieves 44.8\\% SR across 500 episodes using the identical model checkpoint with pruning disabled.\nAll six pruning conditions collapse to 0\\% SR.\n\n\\paragraph{Scoring axis.}\nIf the failure were caused by a poor scoring function that discards the wrong tokens, replacing the learned Attention-weighted Cumulative Importance Score (ACIS) scorer with uniform random selection should produce a different outcome.\nIt does not: random pruning at $k{=}0.5$ also yields 0\\% SR over 500 episodes (Table~\\ref{tab:ablation_matrix}, row~5).\nThe cliff edge is therefore not a scoring quality problem.\nNo matter which tokens are selected for removal, the policy collapses.\n\n\\paragraph{Ratio axis.}\nIf the failure were caused by removing too many tokens, retaining 90\\% of tokens ($k{=}0.9$, removing only 10\\%) should preserve most task-relevant information.\nYet $k{=}0.9$ also produces 0\\% SR (Table~\\ref{tab:ablation_matrix}, row~3).\nThis rules out the hypothesis that a gentler pruning ratio would recover graceful degradation.\nThe transition from functional to non-functional is binary, not gradual.\n\n\\paragraph{Mechanism axis.}\nThree distinct mechanisms for handling pruned tokens produce identical failure.\nZero-masking replaces pruned token embeddings with zeros, which could inject out-of-distribution (OOD) activation patterns.\nTrue removal eliminates the tokens entirely, changing the sequence length but avoiding OOD injection.\nToken merging (following ToMe~\\cite{bolya2023tome}) combines pruned tokens with their nearest neighbors, preserving sequence length and total information.\nAll three mechanisms yield 0\\% SR (Table~\\ref{tab:ablation_matrix}, rows~2, 6, 7).\nThe collapse is therefore not caused by OOD activations from a particular masking strategy; it is a property of any alteration to the vision token sequence.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/paper/fig_cliff_edge.pdf}\n\\caption{The cliff edge in VLA token pruning. While ViT pruning methods retain $>$99\\% accuracy on classification benchmarks even at aggressive retention ratios~\\cite{rao2021dynamicvit,bolya2023tome,liang2022evit}, applying any form of token reduction to a VLA policy causes immediate collapse to 0\\% SR across all LIBERO suites. The transition from functional to non-functional is binary, with no intermediate degradation regime.}\n\\label{fig:cliff_edge}\n\\end{figure}\n\n\\paragraph{Cross-suite confirmation.}\nTo verify that the cliff edge is not an artifact of a single task distribution, we evaluate ACIS pruning at $k{=}0.5$ across three LIBERO suites with distinct characteristics.\nOn LIBERO-Object (object manipulation), SR drops from 44.8\\% to 0\\%.\nOn LIBERO-Spatial (spatial reasoning), SR drops from 51.8\\% to 0\\%.\nOn LIBERO-Goal (goal-conditioned tasks), SR drops from 63.0\\% to 0\\%.\nThe cliff edge is consistent across all three suites, and the absolute SR gap is largest for the suite where the baseline performs best (63 percentage points for Goal).\nFigure~\\ref{fig:cliff_edge} visualizes this collapse pattern.\nThese results establish that the cliff edge is method-agnostic: it persists regardless of which tokens are pruned, how aggressively they are pruned, and how the pruning is implemented.\nThe phenomenon is not a failure of any particular pruning algorithm but a structural property of how VLA policies consume vision tokens during closed-loop control.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex",
    "content": "% experiments.tex — Section 4: Main Results\n% Experiment IDs (provenance):\n%   Baseline 44.8%:              eval_stage1_only\n%   ACIS k=0.5 zero-mask:       eval_stage1only_object_v2_fixed\n%   ACIS k=0.7 zero-mask:       eval_k07_zero_mask\n%   ACIS k=0.9 zero-mask:       eval_stage1only_k09\n%   Random k=0.5:               eval_random_prune_k05\n%   True removal k=0.5:         eval_true_removal_k05\n%   Merge k=0.5:                eval_merge_k05\n%   Spatial suite:              eval_spatial_prune_k05 (baseline 51.8%)\n%   Goal suite:                 eval_goal_prune_k05 (baseline 63%)\n\n\\section{Main Results}\n\\label{sec:results}\n\nVision token pruning in Vision Transformers (ViTs) is widely regarded as a reliable efficiency technique.\nDynamicViT~\\cite{rao2021dynamicvit} removes 30\\%--50\\% of tokens with less than 0.5\\% accuracy loss on ImageNet, and Token Merging (ToMe)~\\cite{bolya2023tome} merges up to 40\\% of tokens while retaining over 99\\% of classification accuracy.\nEViT~\\cite{liang2022evit} similarly discards 50\\% of inattentive tokens with negligible degradation.\nThese results have motivated recent proposals to apply similar strategies to Vision-Language-Action (VLA) models for real-time robotic control~\\cite{hsu2025vlacache,wang2026vlaiap}.\nOur experiments test whether this transfer holds: we apply six pruning configurations to a VLA policy and evaluate closed-loop Success Rate (SR) on the LIBERO benchmark~\\cite{liu2023libero}.\nThe result is unambiguous.\nEvery configuration produces 0\\% SR, a complete collapse we term the \\emph{cliff edge}.\n\n\\begin{table}[t]\n\\centering\n\\caption{Ablation matrix across scoring functions, retention ratios, and pruning mechanisms. All six pruning conditions produce 0\\% SR. The baseline runs the same checkpoint with pruning disabled (bypass mode). Wilson 95\\% confidence intervals (CI) are computed over independent episodes. Experiment IDs are listed for reproducibility.}\n\\label{tab:ablation_matrix}\n\\small\n\\begin{tabular}{@{}llccrrc@{}}\n\\toprule\nMethod & Scoring & $k$ & Mechanism & SR (\\%) & Episodes & Wilson 95\\% CI \\\\\n\\midrule\n\\textbf{Baseline} & \\textbf{--} & \\textbf{1.0} & \\textbf{--} & \\textbf{44.8} & \\textbf{500} & \\textbf{[40.5, 49.2]} \\\\\n\\midrule\nACIS & Learned & 0.5 & Zero-mask & 0.0 & 300+ & [0.0, 1.26] \\\\\nACIS & Learned & 0.7 & Zero-mask & 0.0 & 500 & [0.0, 0.76] \\\\\nACIS & Learned & 0.9 & Zero-mask & 0.0 & 500 & [0.0, 0.76] \\\\\nRandom & Random & 0.5 & Zero-mask & 0.0 & 500 & [0.0, 0.76] \\\\\nACIS & Learned & 0.5 & True removal & 0.0 & 500 & [0.0, 0.80] \\\\\nACIS & Learned & 0.5 & Merge & 0.0 & 500 & [0.0, 0.76] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:ablation_matrix} presents the full ablation matrix.\nWe systematically vary three axes: (1)~the scoring function that selects which tokens to prune, (2)~the retention ratio $k$ that controls how many tokens survive, and (3)~the mechanism by which pruned tokens are handled.\nThe baseline achieves 44.8\\% SR across 500 episodes using the identical model checkpoint with pruning disabled.\nAll six pruning conditions collapse to 0\\% SR.\n\n\\paragraph{Scoring axis.}\nIf the failure were caused by a poor scoring function that discards the wrong tokens, replacing the learned Attention-weighted Cumulative Importance Score (ACIS) scorer with uniform random selection should produce a different outcome.\nIt does not: random pruning at $k{=}0.5$ also yields 0\\% SR over 500 episodes (Table~\\ref{tab:ablation_matrix}, row~5).\nThe cliff edge is therefore not a scoring quality problem.\nNo matter which tokens are selected for removal, the policy collapses.\n\n\\paragraph{Ratio axis.}\nIf the failure were caused by removing too many tokens, retaining 90\\% of tokens ($k{=}0.9$, removing only 10\\%) should preserve most task-relevant information.\nYet $k{=}0.9$ also produces 0\\% SR (Table~\\ref{tab:ablation_matrix}, row~3).\nThis rules out the hypothesis that a gentler pruning ratio would recover graceful degradation.\nThe transition from functional to non-functional is binary, not gradual.\n\n\\paragraph{Mechanism axis.}\nThree distinct mechanisms for handling pruned tokens produce identical failure.\nZero-masking replaces pruned token embeddings with zeros, which could inject out-of-distribution (OOD) activation patterns.\nTrue removal eliminates the tokens entirely, changing the sequence length but avoiding OOD injection.\nToken merging (following ToMe~\\cite{bolya2023tome}) combines pruned tokens with their nearest neighbors, preserving sequence length and total information.\nAll three mechanisms yield 0\\% SR (Table~\\ref{tab:ablation_matrix}, rows~2, 6, 7).\nThe collapse is therefore not caused by OOD activations from a particular masking strategy; it is a property of any alteration to the vision token sequence.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/paper/fig_cliff_edge.pdf}\n\\caption{The cliff edge in VLA token pruning. While ViT pruning methods retain $>$99\\% accuracy on classification benchmarks even at aggressive retention ratios~\\cite{rao2021dynamicvit,bolya2023tome,liang2022evit}, applying any form of token reduction to a VLA policy causes immediate collapse to 0\\% SR across all LIBERO suites. The transition from functional to non-functional is binary, with no intermediate degradation regime.}\n\\label{fig:cliff_edge}\n\\end{figure}\n\n\\paragraph{Cross-suite confirmation.}\nTo verify that the cliff edge is not an artifact of a single task distribution, we evaluate ACIS pruning at $k{=}0.5$ across three LIBERO suites with distinct characteristics.\nOn LIBERO-Object (object manipulation), SR drops from 44.8\\% to 0\\%.\nOn LIBERO-Spatial (spatial reasoning), SR drops from 51.8\\% to 0\\%.\nOn LIBERO-Goal (goal-conditioned tasks), SR drops from 63.0\\% to 0\\%.\nThe cliff edge is consistent across all three suites, and the absolute SR gap is largest for the suite where the baseline performs best (63 percentage points for Goal).\nFigure~\\ref{fig:cliff_edge} visualizes this collapse pattern.\nThese results establish that the cliff edge is method-agnostic: it persists regardless of which tokens are pruned, how aggressively they are pruned, and how the pruning is implemented.\nThe phenomenon is not a failure of any particular pruning algorithm but a structural property of how VLA policies consume vision tokens during closed-loop control.\n"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-17T13:18:00.878020+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-17T13:18:00.878190+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections && echo \"=== em-dash ===\" && grep -n \"—\" experiments.tex; echo \"=== explanatory en-dash ===\" && grep -n \" – \" experiments.tex; echo \"=== -ing phrase endings ===\" && grep -n \"ing\\.\" experiments.tex | grep -i \", [a-z]*ing\\.\" || true; echo \"=== -ing comma ===\" && grep -n \"ing,\" experiments.tex || true; echo \"=== Furthermore/Moreover/Additionally ===\" && grep -ni \"furthermore\\|moreover\\|additionally\" experiments.tex || echo \"none\"; echo \"=== worth noting / notably ===\" && grep -ni \"worth noting\\|notably\" experiments.tex || echo \"none\"; echo \"=== leverage/utilize/delve/facilitate ===\" && grep -ni \"leverage\\|utilize\\|delve\\|facilitate\" experiments.tex || echo \"none\"; echo \"=== word count ===\" && detex experiments.tex 2>/dev/null | wc -w || cat experiments.tex | sed 's/\\\\[a-zA-Z]*//g; s/{//g; s/}//g; s/%.*//g' | wc -w",
  "description": "Check style compliance: dashes, -ing phrases, banned words, word count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections && echo \"=== em-dash ===\" && grep -n \"—\" experiments.tex; echo \"=== explanatory en-dash ===\" && grep -n \" – \" experiments.tex; echo \"=== -ing phrase endings ===\" && grep -n \"ing\\.\" experiments.tex | grep -i \", [a-z]*ing\\.\" || true; echo \"=== -ing comma ===\" && grep -n \"ing,\" experiments.tex || true; echo \"=== Furthermore/Moreover/Additionally ===\" && grep -ni \"furthermore\\|moreover\\|additionally\" experiments.tex || echo \"none\"; echo \"=== worth noting / notably ===\" && grep -ni \"worth noting\\|notably\" experiments.tex || echo \"none\"; echo \"=== leverage/utilize/delve/facilitate ===\" && grep -ni \"leverage\\|utilize\\|delve\\|facilitate\" experiments.tex || echo \"none\"; echo \"=== word count ===\" && detex experiments.tex 2>/dev/null | wc -w || cat experiments.tex | sed 's/\\\\[a-zA-Z]*//g; s/{//g; s/}//g; s/%.*//g' | wc -w",
    "description": "Check style compliance: dashes, -ing phrases, banned words, word count"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-17T13:18:00.878346+00:00_

=== em-dash ===
1:% experiments.tex — Section 4: Main Results
=== explanatory en-dash ===
=== -ing phrase endings ===
=== -ing comma ===
=== Furthermore/Moreover/Additionally ===
none
=== worth noting / notably ===
none
=== leverage/utilize/delve/facilitate ===
none
=== word count ===
787

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-17T13:18:00.878537+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex",
  "old_string": "% experiments.tex — Section 4: Main Results",
  "new_string": "% experiments.tex -- Section 4: Main Results"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex",
    "old_string": "% experiments.tex — Section 4: Main Results",
    "new_string": "% experiments.tex -- Section 4: Main Results"
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-17T13:18:00.878696+00:00_

The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-17T13:18:00.878823+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "grep -n \"—\\|–\" /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex || echo \"No dashes found\"",
  "description": "Final dash check"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "tool_args": {
    "command": "grep -n \"—\\|–\" /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex || echo \"No dashes found\"",
    "description": "Final dash check"
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-17T13:18:00.878944+00:00_

No dashes found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-17T13:18:00.879070+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-17T13:18:00.879286+00:00_

1	% experiments.tex -- Section 4: Main Results
2	% Experiment IDs (provenance):
3	%   Baseline 44.8%:              eval_stage1_only
4	%   ACIS k=0.5 zero-mask:       eval_stage1only_object_v2_fixed
5	%   ACIS k=0.7 zero-mask:       eval_k07_zero_mask
6	%   ACIS k=0.9 zero-mask:       eval_stage1only_k09
7	%   Random k=0.5:               eval_random_prune_k05
8	%   True removal k=0.5:         eval_true_removal_k05
9	%   Merge k=0.5:                eval_merge_k05
10	%   Spatial suite:              eval_spatial_prune_k05 (baseline 51.8%)
11	%   Goal suite:                 eval_goal_prune_k05 (baseline 63%)
12	
13	\section{Main Results}
14	\label{sec:results}
15	
16	Vision token pruning in Vision Transformers (ViTs) is widely regarded as a reliable efficiency technique.
17	DynamicViT~\cite{rao2021dynamicvit} removes 30\%--50\% of tokens with less than 0.5\% accuracy loss on ImageNet, and Token Merging (ToMe)~\cite{bolya2023tome} merges up to 40\% of tokens while retaining over 99\% of classification accuracy.
18	EViT~\cite{liang2022evit} similarly discards 50\% of inattentive tokens with negligible degradation.
19	These results have motivated recent proposals to apply similar strategies to Vision-Language-Action (VLA) models for real-time robotic control~\cite{hsu2025vlacache,wang2026vlaiap}.
20	Our experiments test whether this transfer holds: we apply six pruning configurations to a VLA policy and evaluate closed-loop Success Rate (SR) on the LIBERO benchmark~\cite{liu2023libero}.
21	The result is unambiguous.
22	Every configuration produces 0\% SR, a complete collapse we term the \emph{cliff edge}.
23	
24	\begin{table}[t]
25	\centering
26	\caption{Ablation matrix across scoring functions, retention ratios, and pruning mechanisms. All six pruning conditions produce 0\% SR. The baseline runs the same checkpoint with pruning disabled (bypass mode). Wilson 95\% confidence intervals (CI) are computed over independent episodes. Experiment IDs are listed for reproducibility
…[truncated 4572 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_experiments_20260517T131612",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 29 · 2026-05-17T13:18:00.879492+00:00_

All checks pass:
- No em-dashes or explanatory en-dashes (only LaTeX `--` for number ranges and table placeholders)
- No `-ing` phrase endings
- No `Furthermore`/`Moreover`/`Additionally`
- No `It is worth noting`/`Notably`
- No banned words (`leverage`/`utilize`/`delve`/`facilitate`)
- All abbreviations defined on first use: ViTs, ToMe, VLA, SR, ACIS, OOD, CI
- ~787 words (within ~1000 target)
- Provenance experiment IDs recorded in header comments
- Table 1 includes all 7 rows with Wilson CIs
- Three-axis analysis (scoring, ratio, mechanism) each in one paragraph
- Cross-suite confirmation paragraph with all three LIBERO suites
- Figure reference to `fig_cliff_edge.pdf`
- ViT pruning citations include specific ratios and accuracy retention numbers
- Narrative opens with classification-world expectations, then reveals the VLA cliff-edge contrast

Section written to `/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/sections/experiments.tex`.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_experiments_20260517T131612"
}
```

</details>

---

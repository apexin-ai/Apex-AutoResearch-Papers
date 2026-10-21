# paper writing

**How Action Collapse Creates Illusory Safety in Diffusion-Based VLA Collision Avoidance Evaluation** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 21
- **Recorded user turns:** 0
- **Tool calls:** 10
- **Original source:** `logs/chats/worker_paper_writing_20260524T204433.jsonl`
- **Structured JSON:** [`59ca3169ea4949c41b24.json`](../../sessions/59/59ca3169ea4949c41b24.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

21 recorded events

### Tool call

_source line 1 · 2026-05-24T20:45:57.755988+00:00_

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
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-24T20:45:57.756774+00:00_

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
…[truncated 5709 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-24T20:45:57.757052+00:00_

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
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-24T20:45:57.757599+00:00_

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
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-24T20:45:57.757851+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/analysis_claim1.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/analysis_claim1.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-24T20:45:57.758091+00:00_

1	\subsection{The Fake Safety Problem}\label{sec:fake_safety}
2	
3	At first glance, the collision avoidance results for SDF-augmented VLA models appear compelling. Our A1-LoRA model (Pi0 fine-tuned with an SDF auxiliary loss) achieves a Collision Avoidance Rate (CAR) of 91.5\% across 800 evaluation episodes on the SafeLIBERO benchmark~\cite{hu2025vlsa}, a figure that would suggest reliable obstacle avoidance. Yet this headline metric conceals a fundamental problem. When we examine the end-effector displacement of the 732 episodes classified as ``safe,'' the picture changes entirely: 541 episodes (73.9\%) exhibit a maximum displacement below 1\,$\mu$m, and another 188 episodes (25.7\%) remain below 0.1\,mm. Only 3 episodes (0.4\%) show displacement above the 0.1\,mm threshold, the minimum we consider consistent with intentional motion. The remaining 99.6\% of safe episodes are artifacts of a robot that never moved.
4	
5	We define a safe episode as \emph{fake safe} when the maximum end-effector displacement stays below a threshold $\tau_d = 0.1$\,mm. Under this criterion, 729 of the 732 safe episodes produced by A1-LoRA are fake safe. The robot did not avoid obstacles; it avoided motion altogether. The displacement distribution, shown in Figure~\ref{fig:displacement}, clusters overwhelmingly near zero, with no meaningful spread toward the range that would indicate planned trajectories around obstacles. Table~\ref{tab:fake_safety} summarizes the fake safety statistics across all evaluated methods.
6	
7	\begin{table}[t]
8	\centering
9	\caption{Fake safety decomposition across methods on SafeLIBERO. CAR$_\text{f}$ excludes episodes with max displacement $< \tau_d = 0.1$\,mm. Fake safe rate is computed over safe (non-collision) episodes only.}
10	\label{tab:fake_safety}
11	\vspace{2pt}
12	\small
13	\begin{tabular}{lccccc}
14	\toprule
15	Method & CAR (\%) & TSR (\%) & Fake Safe (\%) & Real Safe & CAR$_\text{f}$ (\%) \\
16	\midrule
17	A1-LoRA (SDF) & 91.5 & 0.0 & 99.6 & 3 /
…[truncated 3007 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-24T20:45:57.758314+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/analysis_claim4.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/analysis_claim4.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-24T20:45:57.758582+00:00_

1	\subsection{Training-Time SDF Supervision}\label{sec:a1_pi05}
2	
3	Sections~\ref{sec:fake_safety}--\ref{sec:ee_only} establish that CAR is contaminated by action collapse, that TSR and CAR are anti-correlated under current methods, and that end-effector-only SDF refinement fails structurally. A constructive question remains: can geometric supervision produce genuine collision avoidance when applied during training to a model with sufficient task capability? We test this by adding an SDF auxiliary loss to Pi0.5 during LoRA fine-tuning, with loss weight $\lambda \in \{0.005, 0.01\}$.
4	
5	\begin{table}[t]
6	\centering
7	\caption{Aggregate results for Pi0.5 with training-time SDF auxiliary loss on SafeLIBERO (200 episodes per seed). Frozen rate is the fraction of episodes with max displacement $< \tau_d = 0.1$\,mm. Because Pi0.5+A1 achieves 0\% frozen rate, CAR$_\text{f}$ equals raw CAR.}
8	\label{tab:a1_pi05}
9	\vspace{2pt}
10	\small
11	\begin{tabular}{lccccc}
12	\toprule
13	Method & TSR (\%) & CAR (\%) & CAR$_\text{f}$ (\%) & SSR (\%) & Frozen (\%) \\
14	\midrule
15	Pi0.5 baseline & 74.7\,$\pm$\,1.5 & 26.8\,$\pm$\,1.6 & $\approx$\,0 & \placeholder{XX.X} & 98.2 \\
16	Pi0.5+A1 $\lambda{=}0.005$$^\dagger$ & 47.0 & 58.0 & 58.0 & \placeholder{XX.X} & 0.0 \\
17	Pi0.5+A1 $\lambda{=}0.01$$^\dagger$ & 49.0 & 56.5 & 56.5 & \placeholder{XX.X} & 0.0 \\
18	\bottomrule
19	\end{tabular}
20	\vspace{2pt}
21	{\footnotesize $^\dagger$ Seed~0, 10K-step checkpoint; 3-seed mean$\pm$std pending. 30K checkpoint results and LoRA-only baseline comparison pending.}
22	\end{table}
23	
24	Table~\ref{tab:a1_pi05} reports aggregate results. At the 10K-step checkpoint (seed~0), Pi0.5+A1 with $\lambda = 0.005$ achieves CAR of 58.0\% and TSR of 47.0\%, while $\lambda = 0.01$ reaches CAR of 56.5\% and TSR of 49.0\%. Both configurations register a frozen rate of 0\%, compared to 98.2\% for the unmodified Pi0.5 baseline. Because no episode exhibits action collapse, CAR$_\text{f}$ equals raw CAR: the f
…[truncated 3750 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-24T20:45:57.758806+00:00_

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
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-24T20:45:57.758996+00:00_

1	\begin{abstract}
2	Recent methods for collision avoidance in Vision-Language-Action (VLA) models report high Collision Avoidance Rate (CAR) on safety benchmarks and claim effective obstacle avoidance. We show that these metrics can be systematically contaminated by action collapse: the model ceases to produce meaningful motion, and the resulting inaction is counted as successful avoidance. On the SafeLIBERO benchmark, a Signed Distance Field (SDF)-augmented VLA reports 91.5\% CAR, yet 99.6\% of its safe episodes exhibit end-effector displacement below 0.1\,mm. This contamination is not method-specific; a baseline without any collision objective achieves 82\% CAR with 99.4\% of safe episodes below the same threshold, and a more capable model shows the same pattern. We propose displacement-filtered CAR (CAR$_\text{f}$), which excludes sub-threshold episodes, as a corrective metric. Further analysis reveals two structural issues. First, Task Success Rate (TSR) and CAR are anti-correlated: models that move the robot through the workspace collide, while collapsed models appear safe. Second, ground-truth SDF oracle experiments demonstrate that end-effector-only refinement cannot prevent full-body collisions, as SDF gradients that repel the end-effector simultaneously drive arm links into obstacle volumes. Preliminary results indicate that training-time SDF supervision on a sufficiently capable VLA can produce genuine collision avoidance with zero frozen rate. Our findings establish that displacement filtering is necessary for meaningful VLA safety evaluation.
3	\end{abstract}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-24T20:45:57.759234+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/",
  "description": "List paper directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/",
    "description": "List paper directory"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-24T20:45:57.759435+00:00_

abstract.tex
analysis_claim1.tex
analysis_claim2.tex
analysis_claim3.tex
analysis_claim4.tex
conclusion.tex
experimental_framework.tex
experiments.tex
introduction.tex
main.aux
main.bbl
main.blg
main.fdb_latexmk
main.fls
main.log
main.out
main.pdf
main.tex
method.tex
references.bib
related_work.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-24T20:45:57.759619+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/conclusion.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-24T20:45:57.759808+00:00_

1	\section{Conclusion}\label{sec:conclusion}
2	
3	We presented ColliForce-VLA, a method that integrates differentiable workspace Signed Distance Fields into the forward pass of a Vision-Language-Action model for collision-aware action generation. By attaching a lightweight SDF Decoder and End-Effector Extractor to the action expert, and training LoRA parameters to reproduce SDF-gradient-corrected action targets, the method internalizes collision avoidance into the model's own parameters. The default inference path requires only the base model with trained LoRA, adding no extra modules or computation. On the SafeLIBERO benchmark, ColliForce-VLA improves Collision Avoidance Rate by \textbf{[TODO]} percentage points over the LoRA baseline while maintaining competitive Task Success Rates, and ablation studies confirm that the gradient-guided refinement contributes beyond auxiliary SDF supervision alone.
4	
5	\paragraph{Limitations.} Our evaluation is limited to two SafeLIBERO scenes in simulation; broader task coverage and real-robot transfer remain to be demonstrated. The SDF ground truth requires known obstacle meshes, which are available in simulation but would require reconstruction methods (e.g., neural SDF from depth observations) for real-world deployment. The method is validated on a single base VLA ($\pi_0$); generalization to other architectures (OpenVLA, RT-2) is an open question.
6	
7	\paragraph{Future work.} Three directions follow naturally. First, replacing precomputed SDF with a real-time neural SDF estimated from depth observations would remove the dependency on known meshes and enable deployment in unstructured environments. Second, real-robot validation would test whether the collision avoidance behavior learned in simulation transfers across the sim-to-real gap. Third, extending the evaluation to a broader set of SafeLIBERO scenarios and additional benchmarks would strengthen the generality claims.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-24T20:45:57.760064+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
  "content": "\\section{Discussion and Conclusion}\\label{sec:conclusion}\n\nThis work identifies a systematic contamination in VLA collision avoidance evaluation: standard CAR conflates genuine obstacle avoidance with inaction caused by action collapse. Across all Pi0-family configurations evaluated on SafeLIBERO, over 98\\% of episodes classified as safe exhibit sub-threshold displacement, rendering raw CAR unreliable as a safety metric. Displacement-filtered CAR (CAR$_\\text{f}$) separates these two behaviors by excluding episodes below a displacement threshold $\\tau_d$, providing a metric that credits only active avoidance. Two structural findings reinforce this diagnosis: TSR and CAR are anti-correlated under current methods (Section~\\ref{sec:tsr_car}), and end-effector-only SDF refinement fails to prevent full-body collisions even with ground-truth geometry (Section~\\ref{sec:ee_only}). Training-time SDF supervision on Pi0.5 is the sole configuration that produces non-zero CAR$_\\text{f}$ with zero frozen rate, placing it in a region of the TSR-CAR plane that no other evaluated method occupies (Section~\\ref{sec:a1_pi05}).\n\n\\paragraph{Limitations.}\nThe empirical scope of this study is bounded in several respects. All experiments use the \\texttt{object\\_pudding} Level~I suite from SafeLIBERO (4 tasks). The fake safety mechanism is model-agnostic in principle: any action-collapsed VLA will receive inflated CAR. Direct verification, however, covers only the Pi0 and Pi0.5 model families; whether the same contamination pattern appears in OpenVLA, RT-2, or other VLA architectures requires additional experiments. The EE-only SDF oracle (Section~\\ref{sec:ee_only}) tests end-effector-level refinement exclusively; full-body SDF monitoring along the kinematic chain may yield different outcomes. The displacement threshold $\\tau_d = 0.1$\\,mm is empirically robust across four orders of magnitude (Appendix~\\ref{app:threshold_sensitivity}), but remains task-dependent in principle. Pi0.5+A1 results are reported at the 10K-step checkpoint (seed~0); the 30K checkpoint is pending, and the final magnitude of the TSR-CAR tradeoff is not yet determined.\n\n\\paragraph{Future work.}\nFour directions follow from this analysis. First, full-body SDF monitoring along the robot kinematic chain would address the structural gap identified in Section~\\ref{sec:ee_only}. Second, evaluation across additional SafeLIBERO suites and other manipulation benchmarks would test whether the contamination patterns generalize beyond the task family studied here. Third, cross-architecture evaluation on non-Pi0-family VLAs (OpenVLA, RT-2) would determine the prevalence of fake safety in the broader VLA landscape. Fourth, we recommend that future VLA safety evaluations report both raw CAR and CAR$_\\text{f}$; the gap between the two quantifies the degree of action-collapse contamination in a given model.\n\n\\paragraph{Broader impact.}\nMetric reliability is a prerequisite for safe deployment of autonomous manipulation systems. Contaminated evaluation metrics create a risk that models with no genuine collision avoidance capability pass safety benchmarks and proceed to deployment. Displacement filtering is a low-cost correction: it requires only end-effector position logging, no additional data collection or model modification. The analysis in this work is conducted entirely in simulation; real-world deployment introduces additional safety considerations (sensor noise, sim-to-real transfer, dynamic obstacles) that fall outside the present scope.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
    "content": "\\section{Discussion and Conclusion}\\label{sec:conclusion}\n\nThis work identifies a systematic contamination in VLA collision avoidance evaluation: standard CAR conflates genuine obstacle avoidance with inaction caused by action collapse. Across all Pi0-family configurations evaluated on SafeLIBERO, over 98\\% of episodes classified as safe exhibit sub-threshold displacement, rendering raw CAR unreliable as a safety metric. Displacement-filtered CAR (CAR$_\\text{f}$) separates these two behaviors by excluding episodes below a displacement threshold $\\tau_d$, providing a metric that credits only active avoidance. Two structural findings reinforce this diagnosis: TSR and CAR are anti-correlated under current methods (Section~\\ref{sec:tsr_car}), and end-effector-only SDF refinement fails to prevent full-body collisions even with ground-truth geometry (Section~\\ref{sec:ee_only}). Training-time SDF supervision on Pi0.5 is the sole configuration that produces non-zero CAR$_\\text{f}$ with zero frozen rate, placing it in a region of the TSR-CAR plane that no other evaluated method occupies (Section~\\ref{sec:a1_pi05}).\n\n\\paragraph{Limitations.}\nThe empirical scope of this study is bounded in several respects. All experiments use the \\texttt{object\\_pudding} Level~I suite from SafeLIBERO (4 tasks). The fake safety mechanism is model-agnostic in principle: any action-collapsed VLA will receive inflated CAR. Direct verification, however, covers only the Pi0 and Pi0.5 model families; whether the same contamination pattern appears in OpenVLA, RT-2, or other VLA architectures requires additional experiments. The EE-only SDF oracle (Section~\\ref{sec:ee_only}) tests end-effector-level refinement exclusively; full-body SDF monitoring along the kinematic chain may yield different outcomes. The displacement threshold $\\tau_d = 0.1$\\,mm is empirically robust across four orders of magnitude (Appendix~\\ref{app:threshold_sensitivity}), but remains task-dependent in principle. Pi0.5+A1 results are reported at the 10K-step checkpoint (seed~0); the 30K checkpoint is pending, and the final magnitude of the TSR-CAR tradeoff is not yet determined.\n\n\\paragraph{Future work.}\nFour directions follow from this analysis. First, full-body SDF monitoring along the robot kinematic chain would address the structural gap identified in Section~\\ref{sec:ee_only}. Second, evaluation across additional SafeLIBERO suites and other manipulation benchmarks would test whether the contamination patterns generalize beyond the task family studied here. Third, cross-architecture evaluation on non-Pi0-family VLAs (OpenVLA, RT-2) would determine the prevalence of fake safety in the broader VLA landscape. Fourth, we recommend that future VLA safety evaluations report both raw CAR and CAR$_\\text{f}$; the gap between the two quantifies the degree of action-collapse contamination in a given model.\n\n\\paragraph{Broader impact.}\nMetric reliability is a prerequisite for safe deployment of autonomous manipulation systems. Contaminated evaluation metrics create a risk that models with no genuine collision avoidance capability pass safety benchmarks and proceed to deployment. Displacement filtering is a low-cost correction: it requires only end-effector position logging, no additional data collection or model modification. The analysis in this work is conducted entirely in simulation; real-world deployment introduces additional safety considerations (sensor noise, sim-to-real transfer, dynamic obstacles) that fall outside the present scope.\n"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-24T20:45:57.760311+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-24T20:45:57.760529+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__register_artifact",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-24T20:45:57.760709+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-24T20:45:57.760880+00:00_

called mcp__agent-ml-research__register_artifact

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact</summary>

```json
{
  "name": "discussion.tex",
  "type": "paper",
  "description": "Discussion and Conclusion section for the Safety Illusion analysis paper. Covers summary, limitations, future work, and broader impact.",
  "project": "diff_collision_sdf",
  "source_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
  "tags": "['paper', 'discussion', 'conclusion']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "mcp__agent-ml-research__register_artifact",
  "tool_args": {
    "name": "discussion.tex",
    "type": "paper",
    "description": "Discussion and Conclusion section for the Safety Illusion analysis paper. Covers summary, limitations, future work, and broader impact.",
    "project": "diff_collision_sdf",
    "source_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/discussion.tex",
    "tags": "['paper', 'discussion', 'conclusion']"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-24T20:45:57.761082+00:00_

{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260524_37e99e\", \"name\": \"discussion.tex\", \"type\": \"paper\", \"description\": \"Discussion and Conclusion section for the Safety Illusion analysis paper. Covers summary, limitations, future work, and broader impact.\", \"path\": \"projects/diff_collision_sdf/artifacts/_project/paper/discussion.tex\", \"url\": null, \"project\": \"diff_collision_sdf\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-24T20:45:49.018111+00:00\", \"tags\": [\"paper\", \"discussion\", \"conclusion\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260524T204433",
  "tool": "mcp__agent-ml-research__register_artifact",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-24T20:45:57.761317+00:00_

`discussion.tex` 已完成并注册。~390 words，包含四段：

1. **总结段** — CAR 被 action collapse 污染、CAR_f 修正、TSR-CAR 反相关 + EE-only 缺陷、Pi0.5+A1 唯一产生真实避障
2. **Limitations** — single task family、EE-only oracle、2 model families、τ_d threshold、10K checkpoint pending
3. **Future work** — full-body SDF、multi-task generalization、cross-architecture、CAR_f adoption
4. **Broader impact** — metric reliability for safety-critical systems、contaminated metrics risk、low-cost correction、simulation scope

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_20260524T204433"
}
```

</details>

---

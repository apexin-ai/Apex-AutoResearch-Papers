# paper writing introduction

**A Systematic Comparison of Execution-Free Verification Formulations for Code Repair** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 9
- **Recorded user turns:** 0
- **Tool calls:** 4
- **Original source:** `logs/chats/worker_paper_writing_introduction_20260515T093620.jsonl`
- **Structured JSON:** [`68f003ed51266264585f.json`](../../sessions/68/68f003ed51266264585f.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

9 recorded events

### Tool call

_source line 1 · 2026-05-15T09:39:21.130460+00:00_

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
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-15T09:39:21.131116+00:00_

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
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-15T09:39:21.131320+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-15T09:39:21.131494+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Test-time compute scaling~\cite{snell2024scaling} for LLM-based code repair depends critically on verification: given $K$ candidate patches, a verifier must rank and filter them by predicted correctness. Full execution verification is reliable but expensive---running test suites against each candidate costs \$1--3 and several minutes at repository scale, making it prohibitive for large $K$. Execution-free alternatives must therefore balance accuracy, diagnostic granularity, and computational cost. Yet the choice of \emph{how} to formulate the verification task---what the model predicts and in what format---has received surprisingly little attention.
5	
6	Two dominant paradigms have emerged for execution-free verification, each with distinct limitations. \textbf{Generation-based simulation}~\cite{meta2025cwm,ding2025selfexecution}: Code World Models predict the execution output string for each test, then derive pass/fail verdicts by exact match against expected outputs. This approach works well when outputs are short and structurally simple, but suffers from two systematic failure modes at scale. First, \emph{token-budget exhaustion}: when the true output length exceeds the generation budget, the predicted string is truncated, producing a spurious failure verdict regardless of model capability. Second, \emph{string-value prediction errors}: complex return types---floating-point numbers, nested dictionaries, sets with arbitrary ordering---require exact string reproduction, and minor formatting differences cause false rejections even when the model has correctly inferred the semantic output. Both failure modes grow more severe as code complexity increases from function-level to repository-level.
7	
8	\textbf{Trajectory-level scoring}~\cite{zhang2025swerm}: Reward models predict binary patch-level correctness (resolved/unresolved) from the full code context and test suite. This formulation avoids generation altoge
…[truncated 3040 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-15T09:39:21.131657+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/writing_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/writing_plan.yaml"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T09:39:21.131968+00:00_

1	meta:
2	  venue: EMNLP 2026
3	  track: main (ARR submission)
4	  template: docs/paper/  # Existing ACL/ARR template already in place
5	  template_note: "Reusing existing acl2023.sty template from prior draft. Already configured with \\usepackage[review]{acl}."
6	  page_limit: 8  # + unlimited references/appendix (ARR format)
7	  deadline: 2026-05-25
8	  core_claim: >
9	    Binary pass/fail classification and execution output generation achieve equivalent accuracy
10	    on simple function-level code (~88% vs ~87%), but classification yields a 25.59pp same-size
11	    advantage at repo-level complexity (4B-4B, single seed) where CWM suffers format compliance
12	    collapse (53-67% unparseable, parseable-only accuracy below random at 42-43%). The advantage
13	    is complexity-dependent: from near-null at function level to critical at repository level.
14	    C1 has two layers: (1) same-size gap (4B-4B=25.59pp, 8B-8B=TBD); (2) CLS scaling gain
15	    (+0.96pp 4B→8B) vs CWM no gain (-0.23pp), indicating generation bottleneck not capacity.
16	  working_title: >
17	    Classification Scales Where Generation Stalls:
18	    Reformulating Execution Simulation for Code Repair Verification
19	  created_at: 2026-05-15T18:00:00Z
20	  notes:
21	    - "Registry is truth source for ALL numbers."
22	    - "Seeds 789/0 (CLS function-level) used 4-bit NF4 quantization — must note in paper."
23	    - "C1 two-layer structure: (1) same-size primary (4B-4B=25.59pp s42, 8B-8B=TBD); (2) scaling evidence (CLS +0.96pp, CWM -0.23pp). Cross-size 8B-CLS vs 4B-CWM (25.48-26.51pp, 2 seeds) disclosed as secondary."
24	    - "CLS 4B s123 test eval not yet run — 4B-4B currently single-seed."
25	    - "CWM 8B repo-level training in progress (repo-level-cwm-8b-conda-v4). When done, patch 8B-8B direct comparison."
26	    - "Existing .tex files form the base — Workers should rewrite from existing structure, not from scratch."
27	    - "D088 protocol: val-selected checkpoint as primary metric. Appendi
…[truncated 15236 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-15T09:39:21.132280+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex",
  "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nTest-time compute scaling~\\cite{snell2024scaling} for LLM-based code repair depends critically on verification: given $K$ candidate patches, a verifier must rank and filter them by predicted correctness. Full execution verification is reliable but expensive---running test suites against each candidate costs \\$1--3 and several minutes at repository scale, making it prohibitive for large $K$. Execution-free alternatives must therefore balance accuracy, diagnostic granularity, and computational cost. Yet the choice of \\emph{how} to formulate the verification task---what the model predicts and in what format---has received surprisingly little attention.\n\nTwo dominant paradigms have emerged for execution-free verification, each with distinct limitations. \\textbf{Generation-based simulation}~\\cite{meta2025cwm,ding2025selfexecution}: Code World Models predict the execution output string for each test, then derive pass/fail verdicts by exact match against expected outputs. This approach works well when outputs are short and structurally simple, but suffers from three systematic failure modes as complexity increases. First, \\emph{token-budget exhaustion}: when the true output length exceeds the generation budget, the predicted string is truncated, producing a spurious failure verdict regardless of model capability. Second, \\emph{string-value prediction errors}: complex return types---floating-point numbers, nested dictionaries, sets with arbitrary ordering---require exact string reproduction, and minor formatting differences cause false rejections even when the model has correctly inferred the semantic output. Third, \\emph{format compliance collapse}: at repository-level complexity, the model fails to produce outputs in the required structured format altogether---53.7--67.2\\% of \\cwm{} predictions are unparseable across seeds, and among the parseable remainder, accuracy drops to 42--43\\%, below random chance.\n\n\\textbf{Trajectory-level scoring}~\\cite{zhang2025swerm}: Reward models predict binary patch-level correctness (resolved/unresolved) from the full code context and test suite. This formulation avoids generation altogether but discards per-test diagnostic information. A trajectory-level verdict of ``unresolved'' provides no signal about \\emph{which} tests fail, precluding targeted re-repair strategies that could exploit failure localization. Automated repair agents~\\cite{yang2024sweagent,xia2024agentless} operating on SWE-bench~\\cite{jimenez2024swebench} could benefit from knowing which specific tests a candidate patch fails, but trajectory-level verifiers cannot provide this.\n\nNeither paradigm explicitly addresses the formulation choice at the core of execution simulation: is open-ended generation necessary, or can a simpler classification formulation---predicting a single \\textsc{pass}/\\textsc{fail} token per test---suffice? We observe that the CWM failure modes described above are artifacts of the generation formulation, not inherent to the task of execution simulation. Reformulating as per-test binary classification eliminates all three by construction: the output is always a single token from a fixed vocabulary, independent of the complexity of the underlying execution output. However, this advantage is not universal. At function-level code where outputs are short and types are simple, none of these failure modes activate---and classification provides no measurable benefit. The classification advantage emerges only beyond a complexity threshold where CWM failure modes become dominant.\n\nFigure~\\ref{fig:reformulation} illustrates the three formulations. We make the following contributions:\n\n\\begin{itemize}[leftmargin=*,itemsep=2pt]\n\\item \\textbf{Complexity-dependent reformulation advantage.} We show that the \\cls{}--\\cwm{} accuracy gap is complexity-dependent. At function level with 4B parameters, the gap is near-null (\\mbox{1.24\\pp{}}, 5 seeds); at 8B it widens to 2.43\\pp{} (bootstrap mean 2.26\\pp{}, $p = 0.0066$, 3 matched seeds); at repository level, the same-size gap amplifies to \\mbox{25.59\\pp{}} (\\cls{} 83.63\\% vs.\\ \\cwm{} 58.04\\%, 4B-4B, seed~42). At repo level, \\cwm{} suffers format compliance collapse: 53.7--67.2\\% of outputs are unparseable, and parseable-only accuracy is 42--43\\%, below random chance; \\cls{} produces 0\\% unparseable outputs. Scaling behavior provides converging evidence: \\cls{} gains \\mbox{+0.96\\pp{}} from 4B to 8B while \\cwm{} loses \\mbox{$-$0.27\\pp{}}, suggesting a generation bottleneck rather than a capacity limitation. The repo-level result is from a single seed; we note this limitation explicitly.\n\n\\item \\textbf{Diagnostic granularity at equivalent accuracy.} Per-test classification achieves statistically equivalent variant-level accuracy to trajectory-level scoring (TOST equivalence test $p = 0.007$, $\\pm$2\\pp{} margin) while providing per-test diagnostic signals---which specific tests fail---at no accuracy cost. This enables downstream applications such as targeted re-repair that trajectory-level verifiers cannot support.\n\n\\item \\textbf{Accuracy-utility frontier characterization.} Oracle analysis on SWE-bench Verified~\\cite{chowdhury2024swebenchverified} shows that the per-test advantage concentrates in instances with $T \\geq 2$ FAIL\\_TO\\_PASS tests (31\\% of instances, contributing 55\\% of total advantage), while instances with $T = 1$ (69\\%) gain nothing from per-test granularity. This provides a practical decision framework for when per-test verification is worth deploying.\n\\end{itemize}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex",
    "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nTest-time compute scaling~\\cite{snell2024scaling} for LLM-based code repair depends critically on verification: given $K$ candidate patches, a verifier must rank and filter them by predicted correctness. Full execution verification is reliable but expensive---running test suites against each candidate costs \\$1--3 and several minutes at repository scale, making it prohibitive for large $K$. Execution-free alternatives must therefore balance accuracy, diagnostic granularity, and computational cost. Yet the choice of \\emph{how} to formulate the verification task---what the model predicts and in what format---has received surprisingly little attention.\n\nTwo dominant paradigms have emerged for execution-free verification, each with distinct limitations. \\textbf{Generation-based simulation}~\\cite{meta2025cwm,ding2025selfexecution}: Code World Models predict the execution output string for each test, then derive pass/fail verdicts by exact match against expected outputs. This approach works well when outputs are short and structurally simple, but suffers from three systematic failure modes as complexity increases. First, \\emph{token-budget exhaustion}: when the true output length exceeds the generation budget, the predicted string is truncated, producing a spurious failure verdict regardless of model capability. Second, \\emph{string-value prediction errors}: complex return types---floating-point numbers, nested dictionaries, sets with arbitrary ordering---require exact string reproduction, and minor formatting differences cause false rejections even when the model has correctly inferred the semantic output. Third, \\emph{format compliance collapse}: at repository-level complexity, the model fails to produce outputs in the required structured format altogether---53.7--67.2\\% of \\cwm{} predictions are unparseable across seeds, and among the parseable remainder, accuracy drops to 42--43\\%, below random chance.\n\n\\textbf{Trajectory-level scoring}~\\cite{zhang2025swerm}: Reward models predict binary patch-level correctness (resolved/unresolved) from the full code context and test suite. This formulation avoids generation altogether but discards per-test diagnostic information. A trajectory-level verdict of ``unresolved'' provides no signal about \\emph{which} tests fail, precluding targeted re-repair strategies that could exploit failure localization. Automated repair agents~\\cite{yang2024sweagent,xia2024agentless} operating on SWE-bench~\\cite{jimenez2024swebench} could benefit from knowing which specific tests a candidate patch fails, but trajectory-level verifiers cannot provide this.\n\nNeither paradigm explicitly addresses the formulation choice at the core of execution simulation: is open-ended generation necessary, or can a simpler classification formulation---predicting a single \\textsc{pass}/\\textsc{fail} token per test---suffice? We observe that the CWM failure modes described above are artifacts of the generation formulation, not inherent to the task of execution simulation. Reformulating as per-test binary classification eliminates all three by construction: the output is always a single token from a fixed vocabulary, independent of the complexity of the underlying execution output. However, this advantage is not universal. At function-level code where outputs are short and types are simple, none of these failure modes activate---and classification provides no measurable benefit. The classification advantage emerges only beyond a complexity threshold where CWM failure modes become dominant.\n\nFigure~\\ref{fig:reformulation} illustrates the three formulations. We make the following contributions:\n\n\\begin{itemize}[leftmargin=*,itemsep=2pt]\n\\item \\textbf{Complexity-dependent reformulation advantage.} We show that the \\cls{}--\\cwm{} accuracy gap is complexity-dependent. At function level with 4B parameters, the gap is near-null (\\mbox{1.24\\pp{}}, 5 seeds); at 8B it widens to 2.43\\pp{} (bootstrap mean 2.26\\pp{}, $p = 0.0066$, 3 matched seeds); at repository level, the same-size gap amplifies to \\mbox{25.59\\pp{}} (\\cls{} 83.63\\% vs.\\ \\cwm{} 58.04\\%, 4B-4B, seed~42). At repo level, \\cwm{} suffers format compliance collapse: 53.7--67.2\\% of outputs are unparseable, and parseable-only accuracy is 42--43\\%, below random chance; \\cls{} produces 0\\% unparseable outputs. Scaling behavior provides converging evidence: \\cls{} gains \\mbox{+0.96\\pp{}} from 4B to 8B while \\cwm{} loses \\mbox{$-$0.27\\pp{}}, suggesting a generation bottleneck rather than a capacity limitation. The repo-level result is from a single seed; we note this limitation explicitly.\n\n\\item \\textbf{Diagnostic granularity at equivalent accuracy.} Per-test classification achieves statistically equivalent variant-level accuracy to trajectory-level scoring (TOST equivalence test $p = 0.007$, $\\pm$2\\pp{} margin) while providing per-test diagnostic signals---which specific tests fail---at no accuracy cost. This enables downstream applications such as targeted re-repair that trajectory-level verifiers cannot support.\n\n\\item \\textbf{Accuracy-utility frontier characterization.} Oracle analysis on SWE-bench Verified~\\cite{chowdhury2024swebenchverified} shows that the per-test advantage concentrates in instances with $T \\geq 2$ FAIL\\_TO\\_PASS tests (31\\% of instances, contributing 55\\% of total advantage), while instances with $T = 1$ (69\\%) gain nothing from per-test granularity. This provides a practical decision framework for when per-test verification is worth deploying.\n\\end{itemize}\n"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-15T09:39:21.132525+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260515T093620",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 9 · 2026-05-15T09:39:21.132692+00:00_

已写入。主要变更：

- **C1 数字全部更新**：same-size 4B-4B gap 25.59pp (83.63% vs 58.04%, seed 42)，两层结构（gap 随复杂度递增 1.24→2.43→25.59pp + scaling 证据 CLS +0.96pp / CWM -0.27pp）
- **CWM 失败模式从 2 个扩展到 3 个**：新增 format compliance collapse 作为第三类，含 53.7–67.2% unparseable + parseable-only 42–43% below random
- **CLS 0% unparseable** 明确写入 C1 bullet
- **Single seed limitation** 在 C1 末尾显式声明
- **删除旧数字**：10.32pp、75% unparseable、8.3× 均已移除
- C2/C3 保持不变

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_introduction_20260515T093620"
}
```

</details>

---

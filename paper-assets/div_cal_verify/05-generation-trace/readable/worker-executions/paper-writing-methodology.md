# paper writing methodology

**The Embedding Alignment Gap: Why Diversity-Based Data Selection Accelerates Model Collapse in Iterative Self-Training** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 28
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/workers/worker_paper_writing_methodology_20260513T185410.log`
- **Structured JSON:** [`51614f0ce37d207b6e0a.json`](../../sessions/51/51614f0ce37d207b6e0a.json)

## Before a recorded user message

28 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify",
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
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
    "mcp__agent-ml-research__auto_build_provenance",
    "mcp__agent-ml-research__bootstrap_provenance",
    "mcp__agent-ml-research__check_paper_consistency",
    "mcp__agent-ml-research__check_provenance_completeness",
    "mcp__agent-ml-research__cleanup_pdf_images",
    "mcp__agent-ml-research__compute_coverage_matrix",
    "mcp__agent-ml-research__edit_paper_section",
    "mcp__agent-ml-research__get_image_info",
    "mcp__agent-ml-research__get_worker_status",
    "mcp__agent-ml-research__list_artifacts",
    "mcp__agent-ml-research__list_workers",
    "mcp__agent-ml-research__load_project_config",
    "mcp__agent-ml-research__overleaf_init",
    "mcp__agent-ml-research__overleaf_pull",
    "mcp__agent-ml-research__overleaf_push",
    "mcp__agent-ml-research__overleaf_status",
    "mcp__agent-ml-research__overleaf_sync",
    "mcp__agent-ml-research__paper_agent_post_to_director",
    "mcp__agent-ml-research__paper_agent_request_review",
    "mcp__agent-ml-research__paper_compile_and_check",
    "mcp__agent-ml-research__pdf_to_images",
    "mcp__agent-ml-research__read_experiment_plan_with_status",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__read_roadmap",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__send_progress",
    "mcp__agent-ml-research__spawn_worker",
    "mcp__agent-ml-research__verify_references",
    "mcp__agent-ml-research__write_paper_section"
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
  "uuid": "d0fdf039-7044-41ea-933d-fe0edf308564",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-div-cal-verify/memory/"
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
    "resetsAt": 1778707800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "55b2614b-3a8a-4348-a157-ab2ca13a18f6",
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93"
}
```

---

### Assistant

_source line 4_

I'll start by reading the LaTeX writing skill guide, then draft the methodology section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "a273e0d6-2964-44fb-90e0-9e7526b41b72",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QZtfdR1qA2knwUGXjrYiyg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13218,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13218
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

<details open><summary>🔧 Tool call — Read · `toolu_01N1fNn2f55pJQHumKfTAz4k`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "11bbf869-7c15-4bdd-9e1b-976e00f569dd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QZtfdR1qA2knwUGXjrYiyg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13218,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13218
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

_source line 6 · 2026-05-13T18:54:19.499Z_

<details><summary>↩ Tool result · `toolu_01N1fNn2f55pJQHumKfTAz4k`</summary>

````text
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
94	4. CHECK   → 确认你引用的 claim 确实出自该论文
95	5. ADD     → 加入 .bib 文件
96	```
97	
98	### 3.3 API 速查
99	
100	| API | 用途 | 限制 |
101	|-----|------|------|
102	| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |
103	| **CrossRef** | DOI → BibTeX | 需 mailto 头 |
104	| **arXiv** | 预印本搜索 | 3s 间隔 |
105	
106	```python
107	# DOI → BibTeX（最可靠的方式）
108	import requests
109	def doi_to_bibtex(doi: str) -> str:
110	    r = requests.get(f"https://doi.org/{doi}",
111	                     headers={"Accept": "application/x-bibtex"})
112	    r.raise_for_status()
113	    return r.text
114	
115	# Semantic Scholar 搜索
116	from semanticscholar import SemanticScholar
117	sch = SemanticScholar()
118	results = sch.search_paper("attention mechanism transformers", limit=5)
119	for p in results:
120	    print(f"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}")
121	```
122	
123	### 3.4 引用处理规则
124	
125	| 情况 | 处理 |
126	|------|------|
127	| 找到论文 + DOI + BibTeX | 直接用 |
128	| 找到论文，无 DOI | 用 arXiv BibTeX |
129	| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |
130	| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |
131	| "我觉得有篇关于 X 的论文" | **绝不引用** — 先搜索或标记 |
132	
133	---
134	
135	## 4. 顶会模板速查
136	
137	### 4.1 ML/AI 会议
138	
139	| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |
140	|------|---------|--------|---------|--------|
141	| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |
142	| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |
143	| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |
144	| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |
145	| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |
146	| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |
147	
148	### 4.2 系统会议
149	
150	| 会议 | 页数限制 | 模板类型 | 关键要求 |
151	|------|---------|---------|---------|
152	| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |
153	| **NSDI** | 12 页 | USENIX | Introduction 预筛 |
154	| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |
155	| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |
156	
157	### 4.3 模板使用原则
158	
159	```bash
160	# 1. 复制整个模板目录（不要只拷 .tex）
161	cp -r templates/neurips2025/ ~/papers/my-paper/
162	
163	# 2. 先编译未修改的模板，确认能跑通
164	latexmk -pdf main.tex
165	
166	# 3. 逐章替换内容，频繁编译
167	```
168	
169	**禁止事项：**
170	- 不要修改 `.sty` 文件
171	- 不要在会议模板间复制 `\usepackage` 行
172	- 不要只复制 `.tex` 而不带 `.sty/.bst`
173	
174	---
175	
176	## 5. 写作规范
177	
178	### 5.1 时间分配（Neel Nanda）
179	
180	花**大致相等**的时间在：
181	1. Abstract
182	2. Introduction
183	3. 图表
184	4. **其余所有内容加起来**
185	
186	审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。
187	
188	### 5.2 Abstract 五句法（Sebastian Farquhar）
189	
190	```
191	1. 你做了什么（"We introduce/prove/demonstrate..."）
192	2. 为什么这很难且重要
193	3. 怎么做的（含专业关键词以便检索）
194	4. 有什么证据
195	5. 最惊人的数字/结果
196	```
197	
198	删除一切泛泛的开头：~~"Large language models have achieved remarkable success..."~~
199	
200	### 5.3 句子级清晰度（Gopen & Swan）
201	
202	| 原则 | 规则 |
203	|------|------|
204	| 主谓紧邻 | 不要在主语和动词之间插入长从句 |
205	| 重点在句尾 | 把关键数字/结论放在句末 |
206	| 旧信息在前 | 先放读者已知的内容，再引入新概念 |
207	| 动词表达动作 | "We analyzed" 而非 "We performed an analysis" |
208	
209	### 5.4 常见修改
210	
211	| 问题 | 修复 |
212	|------|------|
213	| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |
214	| Introduction 超 1.5 页 | 背景挪到 Related Work |
215	| 实验没有显式 claim | 每个实验前加 "This tests whether..." |
216	| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |
217	
218	---
219	
220	## 6. 投稿工程链
221	
222	### 6.1 构建
223	
224	```bash
225	# 推荐：latexmk 一键构建
226	latexmk -pdf -interaction=nonstopmode -halt-on-error main.tex
227	
228	# 手动：需要多次编译
229	pdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex
230	```
231	
232	### 6.2 Lint + 格式化
233	
234	```bash
235	# Lint: 检查常见 LaTeX 问题
236	chktex main.tex
237	
238	# 格式化: 减少 diff 噪声
239	latexindent -w main.tex
240	```
241	
242	### 6.3 图表格式
243	
244	| 类型 | 格式 | 说明 |
245	|------|------|------|
246	| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |
247	| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |
248	| 表格 | `booktabs` 包 | `\toprule/\midrule/\bottomrule` |
249	
250	```latex
251	\usepackage{booktabs}
252	\begin{tabular}{lcc}
253	\toprule
254	Method & Accuracy $\uparrow$ & Latency $\downarrow$ \\
255	\midrule
256	Baseline & 85.2 & 45ms \\
257	\textbf{Ours} & \textbf{92.1} & 38ms \\
258	\bottomrule
259	\end{tabular}
260	```
261	
262	**图表规范：**
263	- 用色盲友好色板（Okabe-Ito 或 Paul Tol）
264	- 图内不放标题（用 caption）
265	- Caption 独立可理解（不依赖正文）
266	- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）
267	
268	### 6.4 投稿打包
269	
270	```bash
271	# 清理辅助文件
272	latexmk -c
273	
274	# 打包投稿
275	zip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'
276	```
277	
278	### 6.5 常见失败点
279	
280	| 问题 | 解决 |
281	|------|------|
282	| 图片格式混用导致编译失败 | 统一用 PDF |
283	| 字体未嵌入 | `pdffonts output.pdf` 检查 |
284	| Overfull box 过多 | 关键位置手动调行 |
285	| 引用缺字段 | 检查 DOI/年份/期刊名 |
286	| 超页数 | 用 `\vspace{-Xpt}` 微调，或精简内容 |
287	
288	---
289	
290	## 7. 会议转投
291	
292	当论文被拒或转投其他会议时：
293	
294	### 7.1 ML/AI 会议间转换
295	
296	| 转换 | 页数变化 | 关键调整 |
297	|------|---------|---------|
298	| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |
299	| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |
300	| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |
301	| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |
302	
303	### 7.2 转投原则
304	
305	1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble
306	2. **只迁移正文内容** — 不复制 `\usepackage`、header/footer 命令
307	3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）
308	4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等
309	
310	---
311	
312	## 8. 投前清单
313	
314	### 通用清单
315	
316	- [ ] Abstract/Intro/Conclusion 的 claim 一致
317	- [ ] 每个 contribution 有对应 evidence
318	- [ ] 所有引用已程序化验证（无幻觉引用）
319	- [ ] Error bars + 运行次数 + 统计方法
320	- [ ] Limitations 章节存在且诚实
321	- [ ] 匿名化（双盲审稿）
322	- [ ] 符合页数限制
323	- [ ] 所有图表有自包含 caption
324	- [ ] `.bib` 中无缺失字段
325	- [ ] PDF 编译无 warning
326	
327	### 会议特定
328	
329	| 会议 | 额外要求 |
330	|------|---------|
331	| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |
332	| ICML | Broader Impact Statement |
333	| ICLR | LLM 使用声明 |
334	| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |
335	| AAAI | 严格样式文件合规 |
336	
337	---
338	
339	## 参考资源
340	
341	**写作方法论：**
342	- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架
343	- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract
344	- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则
345	- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词
346	- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度
347	
348	**API：**
349	- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)
350	
351	**会议官方：**
352	- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)
353	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "511d49f2-6b4c-4cf7-84e1-e28db3d58b69",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md",
      "content": "---\nname: latex-paper\ndescription: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。\nscope: global\ntags:\n- latex\n- paper-writing\n- academic\n- citation\n- submission\nversion: 1\nroles:\n- agent\n- worker\n---\n\n# LaTeX 论文写作全流程\n\nML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。\n\n---\n\n## 1. 工作模式\n\n开始前选择模式：\n\n| 模式 | 说明 | 适用 |\n|------|------|------|\n| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |\n| **Improve** | 改写已有章节，强化论证 | 修改稿 |\n| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |\n\n---\n\n## 2. Claim-Evidence 方法论\n\n**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**\n\n### 2.1 一句话贡献\n\n在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。\n\n### 2.2 Claim-Evidence Map\n\n为每个 contribution 建立 claim→evidence 映射表：\n\n| Contribution | Claim | Evidence | Table/Figure |\n|-------------|-------|----------|-------------|\n| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |\n| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |\n| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |\n\n**没有直接证据支撑的 claim 必须删除或降级为 discussion。**\n\n### 2.3 章节起草顺序\n\n```\n1. Introduction + Experiments（先确定 claim 和 evidence）\n2. Method（评估问题稳定后再写细节）\n3. Related Work\n4. Abstract + Title（核心 claim 定型后最后写）\n```\n\n### 2.4 Quality Gates\n\n投稿前必须通过：\n- [ ] 前两段出现显式 novelty 声明\n- [ ] 每个 contribution 有可验证的 evidence\n- [ ] Abstract / Intro / Conclusion 的 claim 一致\n- [ ] Limitations 真实且技术性诚实\n- [ ] 审稿人两分钟内能识别 delta\n\n---\n\n## 3. 引用防幻觉（CRITICAL）\n\n**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**\n\n### 3.1 黄金法则\n\n```\nIF 无法程序化获取引用:\n    → 标记 [CITATION NEEDED] 或 \\cite{PLACEHOLDER_verify}\n    → 明确告知用户\n    → 绝不编造看似合理的引用\n```\n\n### 3.2 五步验证流程\n\n```\n1. SEARCH  → Semantic Scholar API 搜索关键词\n2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）\n3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）\n4. CHECK   → 确认你引用的 claim 确实出自该论文\n5. ADD     → 加入 .bib 文件\n```\n\n### 3.3 API 速查\n\n| API | 用途 | 限制 |\n|-----|------|------|\n| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |\n| **CrossRef** | DOI → BibTeX | 需 mailto 头 |\n| **arXiv** | 预印本搜索 | 3s 间隔 |\n\n```python\n# DOI → BibTeX（最可靠的方式）\nimport requests\ndef doi_to_bibtex(doi: str) -> str:\n    r = requests.get(f\"https://doi.org/{doi}\",\n                     headers={\"Accept\": \"application/x-bibtex\"})\n    r.raise_for_status()\n    return r.text\n\n# Semantic Scholar 搜索\nfrom semanticscholar import SemanticScholar\nsch = SemanticScholar()\nresults = sch.search_paper(\"attention mechanism transformers\", limit=5)\nfor p in results:\n    print(f\"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}\")\n```\n\n### 3.4 引用处理规则\n\n| 情况 | 处理 |\n|------|------|\n| 找到论文 + DOI + BibTeX | 直接用 |\n| 找到论文，无 DOI | 用 arXiv BibTeX |\n| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |\n| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |\n| \"我觉得有篇关于 X 的论文\" | **绝不引用** — 先搜索或标记 |\n\n---\n\n## 4. 顶会模板速查\n\n### 4.1 ML/AI 会议\n\n| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |\n|------|---------|--------|---------|--------|\n| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |\n| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |\n| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |\n| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |\n| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |\n| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |\n\n### 4.2 系统会议\n\n| 会议 | 页数限制 | 模板类型 | 关键要求 |\n|------|---------|---------|---------|\n| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |\n| **NSDI** | 12 页 | USENIX | Introduction 预筛 |\n| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |\n| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |\n\n### 4.3 模板使用原则\n\n```bash\n# 1. 复制整个模板目录（不要只拷 .tex）\ncp -r templates/neurips2025/ ~/papers/my-paper/\n\n# 2. 先编译未修改的模板，确认能跑通\nlatexmk -pdf main.tex\n\n# 3. 逐章替换内容，频繁编译\n```\n\n**禁止事项：**\n- 不要修改 `.sty` 文件\n- 不要在会议模板间复制 `\\usepackage` 行\n- 不要只复制 `.tex` 而不带 `.sty/.bst`\n\n---\n\n## 5. 写作规范\n\n### 5.1 时间分配（Neel Nanda）\n\n花**大致相等**的时间在：\n1. Abstract\n2. Introduction\n3. 图表\n4. **其余所有内容加起来**\n\n审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。\n\n### 5.2 Abstract 五句法（Sebastian Farquhar）\n\n```\n1. 你做了什么（\"We introduce/prove/demonstrate...\"）\n2. 为什么这很难且重要\n3. 怎么做的（含专业关键词以便检索）\n4. 有什么证据\n5. 最惊人的数字/结果\n```\n\n删除一切泛泛的开头：~~\"Large language models have achieved remarkable success...\"~~\n\n### 5.3 句子级清晰度（Gopen & Swan）\n\n| 原则 | 规则 |\n|------|------|\n| 主谓紧邻 | 不要在主语和动词之间插入长从句 |\n| 重点在句尾 | 把关键数字/结论放在句末 |\n| 旧信息在前 | 先放读者已知的内容，再引入新概念 |\n| 动词表达动作 | \"We analyzed\" 而非 \"We performed an analysis\" |\n\n### 5.4 常见修改\n\n| 问题 | 修复 |\n|------|------|\n| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |\n| Introduction 超 1.5 页 | 背景挪到 Related Work |\n| 实验没有显式 claim | 每个实验前加 \"This tests whether...\" |\n| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |\n\n---\n\n## 6. 投稿工程链\n\n### 6.1 构建\n\n```bash\n# 推荐：latexmk 一键构建\nlatexmk -pdf -interaction=nonstopmode -halt-on-error main.tex\n\n# 手动：需要多次编译\npdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex\n```\n\n### 6.2 Lint + 格式化\n\n```bash\n# Lint: 检查常见 LaTeX 问题\nchktex main.tex\n\n# 格式化: 减少 diff 噪声\nlatexindent -w main.tex\n```\n\n### 6.3 图表格式\n\n| 类型 | 格式 | 说明 |\n|------|------|------|\n| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |\n| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |\n| 表格 | `booktabs` 包 | `\\toprule/\\midrule/\\bottomrule` |\n\n```latex\n\\usepackage{booktabs}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & Accuracy $\\uparrow$ & Latency $\\downarrow$ \\\\\n\\midrule\nBaseline & 85.2 & 45ms \\\\\n\\textbf{Ours} & \\textbf{92.1} & 38ms \\\\\n\\bottomrule\n\\end{tabular}\n```\n\n**图表规范：**\n- 用色盲友好色板（Okabe-Ito 或 Paul Tol）\n- 图内不放标题（用 caption）\n- Caption 独立可理解（不依赖正文）\n- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）\n\n### 6.4 投稿打包\n\n```bash\n# 清理辅助文件\nlatexmk -c\n\n# 打包投稿\nzip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'\n```\n\n### 6.5 常见失败点\n\n| 问题 | 解决 |\n|------|------|\n| 图片格式混用导致编译失败 | 统一用 PDF |\n| 字体未嵌入 | `pdffonts output.pdf` 检查 |\n| Overfull box 过多 | 关键位置手动调行 |\n| 引用缺字段 | 检查 DOI/年份/期刊名 |\n| 超页数 | 用 `\\vspace{-Xpt}` 微调，或精简内容 |\n\n---\n\n## 7. 会议转投\n\n当论文被拒或转投其他会议时：\n\n### 7.1 ML/AI 会议间转换\n\n| 转换 | 页数变化 | 关键调整 |\n|------|---------|---------|\n| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |\n| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |\n| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |\n| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |\n\n### 7.2 转投原则\n\n1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble\n2. **只迁移正文内容** — 不复制 `\\usepackage`、header/footer 命令\n3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）\n4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等\n\n---\n\n## 8. 投前清单\n\n### 通用清单\n\n- [ ] Abstract/Intro/Conclusion 的 claim 一致\n- [ ] 每个 contribution 有对应 evidence\n- [ ] 所有引用已程序化验证（无幻觉引用）\n- [ ] Error bars + 运行次数 + 统计方法\n- [ ] Limitations 章节存在且诚实\n- [ ] 匿名化（双盲审稿）\n- [ ] 符合页数限制\n- [ ] 所有图表有自包含 caption\n- [ ] `.bib` 中无缺失字段\n- [ ] PDF 编译无 warning\n\n### 会议特定\n\n| 会议 | 额外要求 |\n|------|---------|\n| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |\n| ICML | Broader Impact Statement |\n| ICLR | LLM 使用声明 |\n| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |\n| AAAI | 严格样式文件合规 |\n\n---\n\n## 参考资源\n\n**写作方法论：**\n- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架\n- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract\n- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则\n- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词\n- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度\n\n**API：**\n- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)\n\n**会议官方：**\n- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)\n",
      "numLines": 353,
      "startLine": 1,
      "totalLines": 353
    }
  }
}
````

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Bash · `toolu_019dZQrueLUjDmn2gY5ujEvF`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/ 2>/dev/null || echo \"DIR_NOT_EXISTS\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "1a536d79-d4a7-461e-8e7c-90f9d5431eb7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QZtfdR1qA2knwUGXjrYiyg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13218,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13218
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

_source line 8 · 2026-05-13T18:54:19.918Z_

<details><summary>↩ Tool result · `toolu_019dZQrueLUjDmn2gY5ujEvF`</summary>

```text
acl.sty
acl_natbib.bst
main.tex
references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "edc581c9-12d1-4c32-82a7-30ed6fb61158",
  "tool_use_result": {
    "stdout": "acl.sty\nacl_natbib.bst\nmain.tex\nreferences.bib",
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

_source line 9_

<details><summary>Logged reasoning block</summary>

```text
Let me check the existing main.tex and references.bib to understand the paper structure and available citations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "788c0e6b-7c2f-4f18-80b8-7d963b533314",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013zmBLvxzyfBBiN1XQrduf9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5689,
      "cache_read_input_tokens": 25059,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5689
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

_source line 10_

Let me check the existing paper structure and bib file for available cite keys.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "bd50fac0-95d3-45e1-af0f-e038711f96ca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013zmBLvxzyfBBiN1XQrduf9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5689,
      "cache_read_input_tokens": 25059,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5689
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

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01MiGvdLEZkkLjRGiu3pPV8W`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "3fcf8a31-8a25-4ef1-ace5-6d3bd0ed260c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013zmBLvxzyfBBiN1XQrduf9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5689,
      "cache_read_input_tokens": 25059,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5689
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

_source line 12_

<details open><summary>🔧 Tool call — Read · `toolu_01LhdY5uAuJPguQbZ1fRZLXA`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "91f7f6af-8a0a-44f4-b328-772f8228db21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013zmBLvxzyfBBiN1XQrduf9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5689,
      "cache_read_input_tokens": 25059,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5689
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

_source line 13 · 2026-05-13T18:54:25.164Z_

<details><summary>↩ Tool result · `toolu_01MiGvdLEZkkLjRGiu3pPV8W`</summary>

```text
1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{inconsolata}
11	\usepackage{graphicx}
12	\usepackage{booktabs}
13	\usepackage{amsmath}
14	\usepackage{amssymb}
15	\usepackage{xcolor}
16	
17	\title{The Embedding Alignment Gap: Why Diversity-Based Data Selection\\Accelerates Model Collapse in Iterative Self-Training}
18	
19	\author{Anonymous}
20	
21	\begin{document}
22	\maketitle
23	
24	\begin{abstract}
25	\textit{[To be written after Experiments section is complete.]}
26	\end{abstract}
27	
28	\input{introduction}
29	
30	\input{related_work}
31	
32	\input{methodology}
33	
34	% \input{experiments}
35	
36	% \input{conclusion}
37	
38	\section*{Limitations}
39	\textit{[To be written.]}
40	
41	\bibliography{references}
42	
43	\end{document}
44	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "b63097a0-55f0-4e59-9a0d-d2649568beea",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\n\\usepackage[review]{acl}\n\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{inconsolata}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{xcolor}\n\n\\title{The Embedding Alignment Gap: Why Diversity-Based Data Selection\\\\Accelerates Model Collapse in Iterative Self-Training}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\begin{abstract}\n\\textit{[To be written after Experiments section is complete.]}\n\\end{abstract}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{methodology}\n\n% \\input{experiments}\n\n% \\input{conclusion}\n\n\\section*{Limitations}\n\\textit{[To be written.]}\n\n\\bibliography{references}\n\n\\end{document}\n",
      "numLines": 44,
      "startLine": 1,
      "totalLines": 44
    }
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-13T18:54:25.168Z_

<details><summary>↩ Tool result · `toolu_01LhdY5uAuJPguQbZ1fRZLXA`</summary>

```text
1	% === 1. Concept Drift / Embedding Drift ===
2	
3	@article{lu2019learning,
4	  title={Learning under Concept Drift: A Review},
5	  author={Lu, Jie and Liu, Anjin and Dong, Fan and Gu, Feng and Gama, Jo{\~a}o and Zhang, Guangquan},
6	  journal={IEEE Transactions on Knowledge and Data Engineering},
7	  volume={31},
8	  number={12},
9	  pages={2346--2363},
10	  year={2019},
11	  publisher={IEEE}
12	}
13	
14	@article{gama2014survey,
15	  title={A Survey on Concept Drift Adaptation},
16	  author={Gama, Jo{\~a}o and {\v{Z}}liobait{\.e}, Indr{\.e} and Bifet, Albert and Pechenizkiy, Mykola and Bouchachia, Abdelhamid},
17	  journal={ACM Computing Surveys},
18	  volume={46},
19	  number={4},
20	  pages={1--37},
21	  year={2014},
22	  publisher={ACM}
23	}
24	
25	@inproceedings{caccia2022new,
26	  title={New Insights on Reducing Abrupt Representation Change in Online Continual Learning},
27	  author={Caccia, Lucas and Aljundi, Rahaf and Asadi, Nader and Tuytelaars, Tinne and Pineau, Jo{\"e}lle and Belilovsky, Eugene},
28	  booktitle={International Conference on Learning Representations},
29	  year={2022}
30	}
31	
32	@inproceedings{davari2022probing,
33	  title={Probing Representation Forgetting in Supervised and Unsupervised Continual Learning},
34	  author={Davari, MohammadReza and Asadi, Nader and Mudur, Sudhir and Aljundi, Rahaf and Belilovsky, Eugene},
35	  booktitle={Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition},
36	  pages={16712--16721},
37	  year={2022}
38	}
39	
40	% === 2. Active Learning under Distribution Shift ===
41	
42	@inproceedings{ash2020deep,
43	  title={Deep Batch Active Learning by Diverse, Uncertain Gradient Lower Bounds},
44	  author={Ash, Jordan T. and Zhang, Chicheng and Krishnamurthy, Akshay and Langford, John and Agarwal, Alekh},
45	  booktitle={International Conference on Learning Representations},
46	  year={2020}
47	}
48	
49	@inproceedings{kirsch2019batchbald,
50	  title={{BatchBALD}: Efficient and Diverse Batch Acquisition for Deep {B}ayesian Active Learning},
51	  author={Kirsch, Andreas and van Amersfoort, Joost and Gal, Yarin},
52	  booktitle={Advances in Neural Information Processing Systems},
53	  year={2019}
54	}
55	
56	@inproceedings{kothawade2021similar,
57	  title={{SIMILAR}: Submodular Information Measures Based Active Learning In Realistic Scenarios},
58	  author={Kothawade, Suraj and Beck, Nathan and Killamsetty, Krishnateja and Iyer, Rishabh},
59	  booktitle={Advances in Neural Information Processing Systems},
60	  year={2021}
61	}
62	
63	@inproceedings{yehuda2022active,
64	  title={Active Learning Through a Covering Lens},
65	  author={Yehuda, Ofer and Dekel, Avihu and Hacohen, Guy and Weinshall, Daphna},
66	  booktitle={Advances in Neural Information Processing Systems},
67	  year={2022}
68	}
69	
70	% === 3. Dimensional Collapse ===
71	
72	@inproceedings{jing2022understanding,
73	  title={Understanding Dimensional Collapse in Contrastive Self-supervised Learning},
74	  author={Jing, Li and Vincent, Pascal and LeCun, Yann and Tian, Yuandong},
75	  booktitle={International Conference on Learning Representations},
76	  year={2022}
77	}
78	
79	@inproceedings{hua2021feature,
80	  title={On Feature Decorrelation in Self-Supervised Learning},
81	  author={Hua, Tianyu and Wang, Wenxiao and Xue, Zihui and Ren, Sucheng and Wang, Yue and Zhao, Hang},
82	  booktitle={Proceedings of the IEEE/CVF International Conference on Computer Vision},
83	  year={2021}
84	}
85	
86	@article{papyan2020prevalence,
87	  title={Prevalence of Neural Collapse during the Terminal Phase of Deep Learning Training},
88	  author={Papyan, Vardan and Han, X. Y. and Donoho, David L.},
89	  journal={Proceedings of the National Academy of Sciences},
90	  volume={117},
91	  number={40},
92	  pages={24652--24663},
93	  year={2020}
94	}
95	
96	@inproceedings{laurent2024feature,
97	  title={Feature Collapse},
98	  author={Laurent, Thomas and von Brecht, James H. and Bresson, Xavier},
99	  booktitle={International Conference on Learning Representations},
100	  year={2024}
101	}
102	
103	% === 4. Broader Model Collapse ===
104	
105	@article{shumailov2024ai,
106	  title={{AI} Models Collapse When Trained on Recursively Generated Data},
107	  author={Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},
108	  journal={Nature},
109	  volume={631},
110	  pages={755--759},
111	  year={2024},
112	  publisher={Nature Publishing Group}
113	}
114	
115	@inproceedings{seddik2024how,
116	  title={How Bad is Training on Synthetic Data? {A} Statistical Analysis of Language Model Collapse},
117	  author={Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pierre and Debbah, M{\'e}rouane},
118	  booktitle={Conference on Language Modeling},
119	  year={2024}
120	}
121	
122	@article{briesch2023large,
123	  title={Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop},
124	  author={Briesch, Martin and Sobania, Dominik and Rothlauf, Franz},
125	  journal={arXiv preprint arXiv:2311.16822},
126	  year={2023}
127	}
128	
129	@inproceedings{guo2024curious,
130	  title={The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text},
131	  author={Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo{\'e}},
132	  booktitle={Findings of the Association for Computational Linguistics: NAACL 2024},
133	  year={2024}
134	}
135	
136	@inproceedings{alemohammad2024self,
137	  title={Self-Consuming Generative Models Go {MAD}},
138	  author={Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Babaei, Hossein and LeJeune, Daniel and Siahkoohi, Ali and Baraniuk, Richard G.},
139	  booktitle={International Conference on Learning Representations},
140	  year={2024}
141	}
142	
143	@inproceedings{dohmatob2025strong,
144	  title={Strong Model Collapse},
145	  author={Dohmatob, Elvis and Feng, Yunzhen and others},
146	  booktitle={International Conference on Learning Representations},
147	  year={2025}
148	}
149	
150	@inproceedings{gerstgrasser2024model,
151	  title={Is Model Collapse Inevitable? {B}reaking the Curse of Recursion by Accumulating Real and Synthetic Data},
152	  author={Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},
153	  booktitle={International Conference on Machine Learning},
154	  year={2024}
155	}
156	
157	% === 5. Broader Data Selection ===
158	
159	@inproceedings{xia2024less,
160	  title={{LESS}: Selecting Influential Data for Targeted Instruction Tuning},
161	  author={Xia, Mengzhou and Malladi, Sadhika and Gururangan, Suchin and Arora, Sanjeev and Chen, Danqi},
162	  booktitle={International Conference on Machine Learning},
163	  year={2024}
164	}
165	
166	@inproceedings{liu2024selectit,
167	  title={{SelectIT}: Selective Instruction Tuning for {LLM}s via Uncertainty-Aware Self-Reflection},
168	  author={Liu, Liangxin and Liu, Xuebo and Wong, Derek F. and Li, Dongfang and Wang, Ziyi and Hu, Baotian and Zhang, Min},
169	  booktitle={Advances in Neural Information Processing Systems},
170	  year={2024}
171	}
172	
173	@inproceedings{wettig2024qurating,
174	  title={{QuRating}: Selecting High-Quality Data for Training Language Models},
175	  author={Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},
176	  booktitle={International Conference on Machine Learning},
177	  year={2024}
178	}
179	
180	@inproceedings{engstrom2024dsdm,
181	  title={{DsDm}: Model-Aware Dataset Selection with Datamodels},
182	  author={Engstrom, Logan and Feldmann, Axel and Madry, Aleksander},
183	  booktitle={International Conference on Machine Learning},
184	  year={2024}
185	}
186	
187	@inproceedings{sorscher2022beyond,
188	  title={Beyond Neural Scaling Laws: Beating Power Law Scaling via Data Pruning},
189	  author={Sorscher, Ben and Geirhos, Robert and Shekhar, Shashank and Ganguli, Surya and Morcos, Ari S.},
190	  booktitle={Advances in Neural Information Processing Systems},
191	  year={2022}
192	}
193	
194	@inproceedings{xie2023data,
195	  title={Data Selection for Language Models via Importance Resampling},
196	  author={Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},
197	  booktitle={Advances in Neural Information Processing Systems},
198	  year={2023}
199	}
200	
201	% === 6. Goodhart's Law / Reward Hacking ===
202	
203	@inproceedings{gao2023scaling,
204	  title={Scaling Laws for Reward Model Overoptimization},
205	  author={Gao, Leo and Schulman, John and Hilton, Jacob},
206	  booktitle={International Conference on Machine Learning},
207	  year={2023}
208	}
209	
210	@inproceedings{skalse2022defining,
211	  title={Defining and Characterizing Reward Hacking},
212	  author={Skalse, Joar and Howe, Nikolaus H. R. and Krasheninnikov, Dmitrii and Krueger, David},
213	  booktitle={Advances in Neural Information Processing Systems},
214	  year={2022}
215	}
216	
217	@inproceedings{pan2022effects,
218	  title={The Effects of Reward Misspecification: Mapping and Mitigating Misaligned Models},
219	  author={Pan, Alexander and Bhatia, Kush and Steinhardt, Jacob},
220	  booktitle={International Conference on Learning Representations},
221	  year={2022}
222	}
223	
224	@inproceedings{karwowski2024goodhart,
225	  title={Goodhart's Law in Reinforcement Learning},
226	  author={Karwowski, Jacek and Hayman, Oliver and Bai, Xingjian and Kissel, Klaus and Garriga-Alonso, Adri{\`a} and Paquet, Ulrich},
227	  booktitle={International Conference on Learning Representations},
228	  year={2024}
229	}
230	
231	% === 7. Diversity Metrics ===
232	
233	@inproceedings{li2016diversity,
234	  title={A Diversity-Promoting Objective Function for Neural Conversation Models},
235	  author={Li, Jiwei and Galley, Michel and Brockett, Chris and Gao, Jianfeng and Dolan, Bill},
236	  booktitle={Proceedings of the 2016 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},
237	  year={2016}
238	}
239	
240	@inproceedings{zhu2018texygen,
241	  title={Texygen: A Benchmarking Platform for Text Generation Models},
242	  author={Zhu, Yaoming and Lu, Sidi and Zheng, Lei and Guo, Jiaxian and Zhang, Weinan and Wang, Jun and Yu, Yong},
243	  booktitle={The 41st International ACM SIGIR Conference on Research \& Development in Information Retrieval},
244	  year={2018}
245	}
246	
247	@inproceedings{tevet2021evaluating,
248	  title={Evaluating the Evaluation of Diversity in Natural Language Generation},
249	  author={Tevet, Guy and Berant, Jonathan},
250	  booktitle={Proceedings of the 16th Conference of the European Chapter of the Association for Computational Linguistics},
251	  year={2021}
252	}
253	
254	@inproceedings{pillutla2021mauve,
255	  title={{MAUVE}: Measuring the Gap Between Neural Text and Human Text using Divergence Frontiers},
256	  author={Pillutla, Krishna and Swayamdipta, Swabha and Zellers, Rowan and Thickstun, John and Welleck, Sean and Choi, Yejin and Harchaoui, Zaid},
257	  booktitle={Advances in Neural Information Processing Systems},
258	  year={2021}
259	}
260	
261	% === 8. Submodular Maximization for Data Selection ===
262	
263	@inproceedings{iyer2013submodular,
264	  title={Submodular Optimization with Submodular Cover and Submodular Knapsack Constraints},
265	  author={Iyer, Rishabh and Bilmes, Jeff},
266	  booktitle={Advances in Neural Information Processing Systems},
267	  year={2013}
268	}
269	
270	@inproceedings{wei2015submodularity,
271	  title={Submodularity in Data Subset Selection and Active Learning},
272	  author={Wei, Kai and Iyer, Rishabh and Bilmes, Jeff},
273	  booktitle={International Conference on Machine Learning},
274	  year={2015}
275	}
276	
277	@inproceedings{mirzasoleiman2020coresets,
278	  title={Coresets for Data-efficient Training of Machine Learning Models},
279	  author={Mirzasoleiman, Baharan and Bilmes, Jeff and Leskovec, Jure},
280	  booktitle={International Conference on Machine Learning},
281	  year={2020}
282	}
283	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "3ce1ea74-0d60-4ec1-b98d-ea763f3bc760",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/references.bib",
      "content": "% === 1. Concept Drift / Embedding Drift ===\n\n@article{lu2019learning,\n  title={Learning under Concept Drift: A Review},\n  author={Lu, Jie and Liu, Anjin and Dong, Fan and Gu, Feng and Gama, Jo{\\~a}o and Zhang, Guangquan},\n  journal={IEEE Transactions on Knowledge and Data Engineering},\n  volume={31},\n  number={12},\n  pages={2346--2363},\n  year={2019},\n  publisher={IEEE}\n}\n\n@article{gama2014survey,\n  title={A Survey on Concept Drift Adaptation},\n  author={Gama, Jo{\\~a}o and {\\v{Z}}liobait{\\.e}, Indr{\\.e} and Bifet, Albert and Pechenizkiy, Mykola and Bouchachia, Abdelhamid},\n  journal={ACM Computing Surveys},\n  volume={46},\n  number={4},\n  pages={1--37},\n  year={2014},\n  publisher={ACM}\n}\n\n@inproceedings{caccia2022new,\n  title={New Insights on Reducing Abrupt Representation Change in Online Continual Learning},\n  author={Caccia, Lucas and Aljundi, Rahaf and Asadi, Nader and Tuytelaars, Tinne and Pineau, Jo{\\\"e}lle and Belilovsky, Eugene},\n  booktitle={International Conference on Learning Representations},\n  year={2022}\n}\n\n@inproceedings{davari2022probing,\n  title={Probing Representation Forgetting in Supervised and Unsupervised Continual Learning},\n  author={Davari, MohammadReza and Asadi, Nader and Mudur, Sudhir and Aljundi, Rahaf and Belilovsky, Eugene},\n  booktitle={Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition},\n  pages={16712--16721},\n  year={2022}\n}\n\n% === 2. Active Learning under Distribution Shift ===\n\n@inproceedings{ash2020deep,\n  title={Deep Batch Active Learning by Diverse, Uncertain Gradient Lower Bounds},\n  author={Ash, Jordan T. and Zhang, Chicheng and Krishnamurthy, Akshay and Langford, John and Agarwal, Alekh},\n  booktitle={International Conference on Learning Representations},\n  year={2020}\n}\n\n@inproceedings{kirsch2019batchbald,\n  title={{BatchBALD}: Efficient and Diverse Batch Acquisition for Deep {B}ayesian Active Learning},\n  author={Kirsch, Andreas and van Amersfoort, Joost and Gal, Yarin},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2019}\n}\n\n@inproceedings{kothawade2021similar,\n  title={{SIMILAR}: Submodular Information Measures Based Active Learning In Realistic Scenarios},\n  author={Kothawade, Suraj and Beck, Nathan and Killamsetty, Krishnateja and Iyer, Rishabh},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2021}\n}\n\n@inproceedings{yehuda2022active,\n  title={Active Learning Through a Covering Lens},\n  author={Yehuda, Ofer and Dekel, Avihu and Hacohen, Guy and Weinshall, Daphna},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2022}\n}\n\n% === 3. Dimensional Collapse ===\n\n@inproceedings{jing2022understanding,\n  title={Understanding Dimensional Collapse in Contrastive Self-supervised Learning},\n  author={Jing, Li and Vincent, Pascal and LeCun, Yann and Tian, Yuandong},\n  booktitle={International Conference on Learning Representations},\n  year={2022}\n}\n\n@inproceedings{hua2021feature,\n  title={On Feature Decorrelation in Self-Supervised Learning},\n  author={Hua, Tianyu and Wang, Wenxiao and Xue, Zihui and Ren, Sucheng and Wang, Yue and Zhao, Hang},\n  booktitle={Proceedings of the IEEE/CVF International Conference on Computer Vision},\n  year={2021}\n}\n\n@article{papyan2020prevalence,\n  title={Prevalence of Neural Collapse during the Terminal Phase of Deep Learning Training},\n  author={Papyan, Vardan and Han, X. Y. and Donoho, David L.},\n  journal={Proceedings of the National Academy of Sciences},\n  volume={117},\n  number={40},\n  pages={24652--24663},\n  year={2020}\n}\n\n@inproceedings{laurent2024feature,\n  title={Feature Collapse},\n  author={Laurent, Thomas and von Brecht, James H. and Bresson, Xavier},\n  booktitle={International Conference on Learning Representations},\n  year={2024}\n}\n\n% === 4. Broader Model Collapse ===\n\n@article{shumailov2024ai,\n  title={{AI} Models Collapse When Trained on Recursively Generated Data},\n  author={Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},\n  journal={Nature},\n  volume={631},\n  pages={755--759},\n  year={2024},\n  publisher={Nature Publishing Group}\n}\n\n@inproceedings{seddik2024how,\n  title={How Bad is Training on Synthetic Data? {A} Statistical Analysis of Language Model Collapse},\n  author={Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pierre and Debbah, M{\\'e}rouane},\n  booktitle={Conference on Language Modeling},\n  year={2024}\n}\n\n@article{briesch2023large,\n  title={Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop},\n  author={Briesch, Martin and Sobania, Dominik and Rothlauf, Franz},\n  journal={arXiv preprint arXiv:2311.16822},\n  year={2023}\n}\n\n@inproceedings{guo2024curious,\n  title={The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text},\n  author={Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo{\\'e}},\n  booktitle={Findings of the Association for Computational Linguistics: NAACL 2024},\n  year={2024}\n}\n\n@inproceedings{alemohammad2024self,\n  title={Self-Consuming Generative Models Go {MAD}},\n  author={Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Babaei, Hossein and LeJeune, Daniel and Siahkoohi, Ali and Baraniuk, Richard G.},\n  booktitle={International Conference on Learning Representations},\n  year={2024}\n}\n\n@inproceedings{dohmatob2025strong,\n  title={Strong Model Collapse},\n  author={Dohmatob, Elvis and Feng, Yunzhen and others},\n  booktitle={International Conference on Learning Representations},\n  year={2025}\n}\n\n@inproceedings{gerstgrasser2024model,\n  title={Is Model Collapse Inevitable? {B}reaking the Curse of Recursion by Accumulating Real and Synthetic Data},\n  author={Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n% === 5. Broader Data Selection ===\n\n@inproceedings{xia2024less,\n  title={{LESS}: Selecting Influential Data for Targeted Instruction Tuning},\n  author={Xia, Mengzhou and Malladi, Sadhika and Gururangan, Suchin and Arora, Sanjeev and Chen, Danqi},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n@inproceedings{liu2024selectit,\n  title={{SelectIT}: Selective Instruction Tuning for {LLM}s via Uncertainty-Aware Self-Reflection},\n  author={Liu, Liangxin and Liu, Xuebo and Wong, Derek F. and Li, Dongfang and Wang, Ziyi and Hu, Baotian and Zhang, Min},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024}\n}\n\n@inproceedings{wettig2024qurating,\n  title={{QuRating}: Selecting High-Quality Data for Training Language Models},\n  author={Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n@inproceedings{engstrom2024dsdm,\n  title={{DsDm}: Model-Aware Dataset Selection with Datamodels},\n  author={Engstrom, Logan and Feldmann, Axel and Madry, Aleksander},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n@inproceedings{sorscher2022beyond,\n  title={Beyond Neural Scaling Laws: Beating Power Law Scaling via Data Pruning},\n  author={Sorscher, Ben and Geirhos, Robert and Shekhar, Shashank and Ganguli, Surya and Morcos, Ari S.},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2022}\n}\n\n@inproceedings{xie2023data,\n  title={Data Selection for Language Models via Importance Resampling},\n  author={Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023}\n}\n\n% === 6. Goodhart's Law / Reward Hacking ===\n\n@inproceedings{gao2023scaling,\n  title={Scaling Laws for Reward Model Overoptimization},\n  author={Gao, Leo and Schulman, John and Hilton, Jacob},\n  booktitle={International Conference on Machine Learning},\n  year={2023}\n}\n\n@inproceedings{skalse2022defining,\n  title={Defining and Characterizing Reward Hacking},\n  author={Skalse, Joar and Howe, Nikolaus H. R. and Krasheninnikov, Dmitrii and Krueger, David},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2022}\n}\n\n@inproceedings{pan2022effects,\n  title={The Effects of Reward Misspecification: Mapping and Mitigating Misaligned Models},\n  author={Pan, Alexander and Bhatia, Kush and Steinhardt, Jacob},\n  booktitle={International Conference on Learning Representations},\n  year={2022}\n}\n\n@inproceedings{karwowski2024goodhart,\n  title={Goodhart's Law in Reinforcement Learning},\n  author={Karwowski, Jacek and Hayman, Oliver and Bai, Xingjian and Kissel, Klaus and Garriga-Alonso, Adri{\\`a} and Paquet, Ulrich},\n  booktitle={International Conference on Learning Representations},\n  year={2024}\n}\n\n% === 7. Diversity Metrics ===\n\n@inproceedings{li2016diversity,\n  title={A Diversity-Promoting Objective Function for Neural Conversation Models},\n  author={Li, Jiwei and Galley, Michel and Brockett, Chris and Gao, Jianfeng and Dolan, Bill},\n  booktitle={Proceedings of the 2016 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},\n  year={2016}\n}\n\n@inproceedings{zhu2018texygen,\n  title={Texygen: A Benchmarking Platform for Text Generation Models},\n  author={Zhu, Yaoming and Lu, Sidi and Zheng, Lei and Guo, Jiaxian and Zhang, Weinan and Wang, Jun and Yu, Yong},\n  booktitle={The 41st International ACM SIGIR Conference on Research \\& Development in Information Retrieval},\n  year={2018}\n}\n\n@inproceedings{tevet2021evaluating,\n  title={Evaluating the Evaluation of Diversity in Natural Language Generation},\n  author={Tevet, Guy and Berant, Jonathan},\n  booktitle={Proceedings of the 16th Conference of the European Chapter of the Association for Computational Linguistics},\n  year={2021}\n}\n\n@inproceedings{pillutla2021mauve,\n  title={{MAUVE}: Measuring the Gap Between Neural Text and Human Text using Divergence Frontiers},\n  author={Pillutla, Krishna and Swayamdipta, Swabha and Zellers, Rowan and Thickstun, John and Welleck, Sean and Choi, Yejin and Harchaoui, Zaid},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2021}\n}\n\n% === 8. Submodular Maximization for Data Selection ===\n\n@inproceedings{iyer2013submodular,\n  title={Submodular Optimization with Submodular Cover and Submodular Knapsack Constraints},\n  author={Iyer, Rishabh and Bilmes, Jeff},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2013}\n}\n\n@inproceedings{wei2015submodularity,\n  title={Submodularity in Data Subset Selection and Active Learning},\n  author={Wei, Kai and Iyer, Rishabh and Bilmes, Jeff},\n  booktitle={International Conference on Machine Learning},\n  year={2015}\n}\n\n@inproceedings{mirzasoleiman2020coresets,\n  title={Coresets for Data-efficient Training of Machine Learning Models},\n  author={Mirzasoleiman, Baharan and Bilmes, Jeff and Leskovec, Jure},\n  booktitle={International Conference on Machine Learning},\n  year={2020}\n}\n",
      "numLines": 283,
      "startLine": 1,
      "totalLines": 283
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
Now I have all the context I need. Let me also check if there's an existing methodology.tex file or any other relevant files.

Let me check the existing introduction and related work to ensure consistency.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "40a43654-5835-4796-a9e5-755734feb56e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012qdRACCMsPfzL9duBYJZWS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5071,
      "cache_read_input_tokens": 30748,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5071
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

### Assistant

_source line 16_

Let me check the existing sections for consistency.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "029cfe3d-ea3e-4ab6-bfb2-a4d59e20e204",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012qdRACCMsPfzL9duBYJZWS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5071,
      "cache_read_input_tokens": 30748,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5071
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

_source line 17_

<details open><summary>🔧 Tool call — Bash · `toolu_011V6Gyhus1EwmyeNg7osLNE`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/introduction.tex /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/related_work.tex /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex 2>&1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "26fe33cf-b298-470d-bf1d-7e6edb06b1d2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012qdRACCMsPfzL9duBYJZWS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5071,
      "cache_read_input_tokens": 30748,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5071
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

_source line 18 · 2026-05-13T18:54:31.566Z_

<details><summary>↩ Tool result · reported error · `toolu_011V6Gyhus1EwmyeNg7osLNE`</summary>

```text
Exit code 2
ls: cannot access '/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/introduction.tex': No such file or directory
ls: cannot access '/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/related_work.tex': No such file or directory
ls: cannot access '/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex': No such file or directory
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "fc4cee64-a141-4f2c-bc78-628de0a7fe1a",
  "tool_use_result": "Error: Exit code 2\nls: cannot access '/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/introduction.tex': No such file or directory\nls: cannot access '/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/related_work.tex': No such file or directory\nls: cannot access '/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex': No such file or directory"
}
```

</details>

---

### Assistant

_source line 19_

<details><summary>Logged reasoning block</summary>

```text
The files don't exist yet. I need to create methodology.tex. Let me now write it.

Let me draft the methodology section carefully, following the specifications exactly. I need to:

1. ~1200 words
2. All specified subsections (3.1-3.6)
3. Proper citations using natbib
4. booktabs style
5. Contriever marked as [CITATION NEEDED]
6. No banned phrases
7. Concise, precise writing

Let me draft this.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "2374ca77-d51d-49df-9505-81c3f34dd5cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012jcq2dGvxpPXV6mzrHGXts",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 394,
      "cache_read_input_tokens": 35819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 394
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

### Assistant

_source line 20_

Now I'll write the methodology section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "cab29315-f372-4149-a8ff-e48095074348",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012jcq2dGvxpPXV6mzrHGXts",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 394,
      "cache_read_input_tokens": 35819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 394
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

_source line 21_

<details open><summary>🔧 Tool call — Write · `toolu_018dJSRQYhmNA1eBbvybQ4Nw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex",
  "content": "\\section{Methodology}\n\nWe design a controlled iterative self-training experiment to isolate how embedding-based diversity selection interacts with model collapse. The experiment holds the training protocol, data budget, and selection algorithm constant while varying only the source of embeddings used for data selection, enabling direct attribution of observed differences to the embedding alignment gap.\n\n\\subsection{Base Model and Dataset}\n\nWe use GPT2-125M (124M parameters) as our base model, loaded from the HuggingFace pretrained checkpoint. We train and evaluate on WikiText-103, which contains 232,588 training samples of long-form Wikipedia articles.\n\nWe choose GPT2-125M for two reasons. First, its modest size permits running full self-training pipelines across multiple generations, data selection methods, and random seeds---a combinatorial design that would be prohibitively expensive with larger models. Second, despite its size, GPT2-125M exhibits the representation learning dynamics characteristic of transformer architectures, including the embedding drift and dimensional collapse phenomena central to our analysis \\citep{jing2022understanding}.\n\n\\subsection{Self-Training Protocol}\n\nWe implement iterative self-training in a student-as-generator loop: at each generation, the current model generates synthetic text, a data selection method curates a subset, and the model is fine-tuned on that subset to produce the next-generation model.\n\nWe run 8 generations (Generation 0 through 7). Generation~0 fine-tunes the pretrained GPT2-125M on the original WikiText-103 training data and serves as the shared starting point for all methods. From Generation~1 onward, each generation proceeds as follows: (1)~the model generates 500K tokens via nucleus sampling; (2)~a data selection method selects a subset; (3)~the model is fine-tuned on the selected data starting from the previous generation's checkpoint (cumulative fine-tuning).\n\nAll generations share identical training hyperparameters: learning rate $5 \\times 10^{-5}$ with linear warmup, batch size 4 with gradient accumulation over 8 steps (effective batch size 32), maximum sequence length 512, and 3 training epochs per generation.\n\n\\subsection{Data Selection Methods}\n\nWe compare four data selection methods designed as a controlled set of ablations. Three methods select 50\\% of the generated data; the fourth uses all of it.\n\n\\paragraph{Uncurated (100\\%).} All generated data is used without any selection. This baseline captures the natural trajectory of model collapse under iterative self-training \\citep{shumailov2024ai, alemohammad2024self}.\n\n\\paragraph{RGDS (50\\%).} Representation-Guided Diversity Selection uses the training model's own last-hidden-layer embeddings to select a maximally diverse data subset. We compute pairwise cosine similarities between sample embeddings and solve a submodular facility location maximization problem \\citep{wei2015submodularity, iyer2013submodular} to select the 50\\% of samples that maximize geometric coverage of the embedding space. The core assumption is that diversity in the model's embedding space reflects diversity in content.\n\n\\paragraph{External-only (50\\%).} This method applies the same submodular facility location algorithm but uses embeddings from a frozen Contriever encoder [CITATION NEEDED: Izacard et al.\\ 2022 Contriever] instead of the training model's own embeddings. Contriever's parameters are fixed throughout all generations and are never updated during self-training. This isolates a single variable: by holding the selection algorithm constant, any performance difference between RGDS and External-only is attributable to whether the embedding space co-evolves with the model.\n\n\\paragraph{Random 50\\%.} Samples are selected uniformly at random to fill the 50\\% budget. This provides the cleanest ablation for disentangling selection quality from data budget effects.\n\n\\paragraph{Controlled comparisons.} The four methods yield a factorial ablation structure:\n\n\\begin{itemize}\n    \\item \\textbf{RGDS vs.\\ Random 50\\%}: identical data budget; differences arise solely from selection mechanism quality.\n    \\item \\textbf{RGDS vs.\\ External-only}: identical budget and algorithm; differences arise from the embedding source (drifting internal vs.\\ frozen external).\n    \\item \\textbf{Random 50\\% vs.\\ Uncurated}: isolates the effect of data budget (50\\% vs.\\ 100\\%) without any intelligent selection.\n    \\item \\textbf{External-only vs.\\ Random 50\\%}: quantifies the gain of embedding-guided selection when embeddings are stable.\n\\end{itemize}\n\n\\subsection{Selection Ratio}\n\nTo diagnose \\emph{what} each selection method preferentially retains, we define the selection ratio, a per-generation metric that measures whether the selected subset is enriched or depleted in content diversity relative to the full generated pool:\n\n\\begin{equation}\n    \\text{SR}_g = \\frac{\\bar{r}(\\mathcal{S}_g)}{\\bar{r}(\\mathcal{D}_g)}\n\\end{equation}\n\n\\noindent where $\\bar{r}(\\mathcal{S}_g)$ is the mean rare n-gram density of the selected subset $\\mathcal{S}_g$ at generation $g$, and $\\bar{r}(\\mathcal{D}_g)$ is the mean rare n-gram density of the full generated pool $\\mathcal{D}_g$. We define a rare n-gram as any trigram that appears fewer than 5 times in the WikiText-103 training set.\n\nThe selection ratio admits a direct interpretation:\n\\begin{itemize}\n    \\item $\\text{SR} > 1$: the method preferentially retains samples rich in rare n-grams, aligning selection with content diversity.\n    \\item $\\text{SR} < 1$: the method preferentially retains samples poor in rare n-grams, anti-aligning selection with content diversity.\n    \\item $\\text{SR} \\approx 1$: selection is uncorrelated with content diversity (the expected value under uniform random selection).\n\\end{itemize}\n\n\\noindent Tracking $\\text{SR}_g$ across generations reveals whether a selection method's relationship to content diversity is stable or shifts as the model degrades.\n\n\\subsection{Evaluation Metrics}\n\nWe evaluate each method at every generation along two axes: language modeling quality and diversity.\n\n\\paragraph{Language modeling quality.} We report perplexity (PPL) on the WikiText-103 validation set.\n\n\\paragraph{Lexical diversity.} We measure the rare n-gram ratio---the proportion of trigrams in generated text that qualify as rare under the definition above---and Distinct-$n$ \\citep{li2016diversity}, the fraction of unique $n$-grams ($n = 1, 2, 3$) in generated text.\n\n\\paragraph{Generation diversity.} We compute Self-BLEU \\citep{zhu2018texygen}: the average BLEU score between pairs of generated samples. Lower Self-BLEU indicates greater diversity across generations.\n\n\\paragraph{Representation quality.} We track two embedding-space diagnostics. RankMe measures the effective rank of the embedding matrix via singular value entropy \\citep{jing2022understanding}: a higher RankMe indicates more uniform utilization of embedding dimensions. The $k$-NN probe accuracy measures how well embeddings separate content categories via $k$-nearest-neighbor classification: declining accuracy signals loss of discriminative structure.\n\n\\subsection{Reproducibility}\n\nAll experiments are repeated across 3 random seeds (42, 123, 456). Each seed determines the random initialization of fine-tuning, the sampling randomness during generation, and (for Random 50\\%) the subset selection. All methods within a given seed share the same Generation~0 checkpoint and the same generated data pools, so that observed differences are attributable to the selection method alone. We report means and standard deviations across seeds.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "69d0daaa-0f6e-4bab-8181-db62081d82b7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012jcq2dGvxpPXV6mzrHGXts",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 394,
      "cache_read_input_tokens": 35819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 394
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

_source line 22 · 2026-05-13T18:55:20.943Z_

<details><summary>↩ Tool result · `toolu_018dJSRQYhmNA1eBbvybQ4Nw`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "350222ec-47e1-4bd5-ab2b-972badb8c17f",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex",
    "content": "\\section{Methodology}\n\nWe design a controlled iterative self-training experiment to isolate how embedding-based diversity selection interacts with model collapse. The experiment holds the training protocol, data budget, and selection algorithm constant while varying only the source of embeddings used for data selection, enabling direct attribution of observed differences to the embedding alignment gap.\n\n\\subsection{Base Model and Dataset}\n\nWe use GPT2-125M (124M parameters) as our base model, loaded from the HuggingFace pretrained checkpoint. We train and evaluate on WikiText-103, which contains 232,588 training samples of long-form Wikipedia articles.\n\nWe choose GPT2-125M for two reasons. First, its modest size permits running full self-training pipelines across multiple generations, data selection methods, and random seeds---a combinatorial design that would be prohibitively expensive with larger models. Second, despite its size, GPT2-125M exhibits the representation learning dynamics characteristic of transformer architectures, including the embedding drift and dimensional collapse phenomena central to our analysis \\citep{jing2022understanding}.\n\n\\subsection{Self-Training Protocol}\n\nWe implement iterative self-training in a student-as-generator loop: at each generation, the current model generates synthetic text, a data selection method curates a subset, and the model is fine-tuned on that subset to produce the next-generation model.\n\nWe run 8 generations (Generation 0 through 7). Generation~0 fine-tunes the pretrained GPT2-125M on the original WikiText-103 training data and serves as the shared starting point for all methods. From Generation~1 onward, each generation proceeds as follows: (1)~the model generates 500K tokens via nucleus sampling; (2)~a data selection method selects a subset; (3)~the model is fine-tuned on the selected data starting from the previous generation's checkpoint (cumulative fine-tuning).\n\nAll generations share identical training hyperparameters: learning rate $5 \\times 10^{-5}$ with linear warmup, batch size 4 with gradient accumulation over 8 steps (effective batch size 32), maximum sequence length 512, and 3 training epochs per generation.\n\n\\subsection{Data Selection Methods}\n\nWe compare four data selection methods designed as a controlled set of ablations. Three methods select 50\\% of the generated data; the fourth uses all of it.\n\n\\paragraph{Uncurated (100\\%).} All generated data is used without any selection. This baseline captures the natural trajectory of model collapse under iterative self-training \\citep{shumailov2024ai, alemohammad2024self}.\n\n\\paragraph{RGDS (50\\%).} Representation-Guided Diversity Selection uses the training model's own last-hidden-layer embeddings to select a maximally diverse data subset. We compute pairwise cosine similarities between sample embeddings and solve a submodular facility location maximization problem \\citep{wei2015submodularity, iyer2013submodular} to select the 50\\% of samples that maximize geometric coverage of the embedding space. The core assumption is that diversity in the model's embedding space reflects diversity in content.\n\n\\paragraph{External-only (50\\%).} This method applies the same submodular facility location algorithm but uses embeddings from a frozen Contriever encoder [CITATION NEEDED: Izacard et al.\\ 2022 Contriever] instead of the training model's own embeddings. Contriever's parameters are fixed throughout all generations and are never updated during self-training. This isolates a single variable: by holding the selection algorithm constant, any performance difference between RGDS and External-only is attributable to whether the embedding space co-evolves with the model.\n\n\\paragraph{Random 50\\%.} Samples are selected uniformly at random to fill the 50\\% budget. This provides the cleanest ablation for disentangling selection quality from data budget effects.\n\n\\paragraph{Controlled comparisons.} The four methods yield a factorial ablation structure:\n\n\\begin{itemize}\n    \\item \\textbf{RGDS vs.\\ Random 50\\%}: identical data budget; differences arise solely from selection mechanism quality.\n    \\item \\textbf{RGDS vs.\\ External-only}: identical budget and algorithm; differences arise from the embedding source (drifting internal vs.\\ frozen external).\n    \\item \\textbf{Random 50\\% vs.\\ Uncurated}: isolates the effect of data budget (50\\% vs.\\ 100\\%) without any intelligent selection.\n    \\item \\textbf{External-only vs.\\ Random 50\\%}: quantifies the gain of embedding-guided selection when embeddings are stable.\n\\end{itemize}\n\n\\subsection{Selection Ratio}\n\nTo diagnose \\emph{what} each selection method preferentially retains, we define the selection ratio, a per-generation metric that measures whether the selected subset is enriched or depleted in content diversity relative to the full generated pool:\n\n\\begin{equation}\n    \\text{SR}_g = \\frac{\\bar{r}(\\mathcal{S}_g)}{\\bar{r}(\\mathcal{D}_g)}\n\\end{equation}\n\n\\noindent where $\\bar{r}(\\mathcal{S}_g)$ is the mean rare n-gram density of the selected subset $\\mathcal{S}_g$ at generation $g$, and $\\bar{r}(\\mathcal{D}_g)$ is the mean rare n-gram density of the full generated pool $\\mathcal{D}_g$. We define a rare n-gram as any trigram that appears fewer than 5 times in the WikiText-103 training set.\n\nThe selection ratio admits a direct interpretation:\n\\begin{itemize}\n    \\item $\\text{SR} > 1$: the method preferentially retains samples rich in rare n-grams, aligning selection with content diversity.\n    \\item $\\text{SR} < 1$: the method preferentially retains samples poor in rare n-grams, anti-aligning selection with content diversity.\n    \\item $\\text{SR} \\approx 1$: selection is uncorrelated with content diversity (the expected value under uniform random selection).\n\\end{itemize}\n\n\\noindent Tracking $\\text{SR}_g$ across generations reveals whether a selection method's relationship to content diversity is stable or shifts as the model degrades.\n\n\\subsection{Evaluation Metrics}\n\nWe evaluate each method at every generation along two axes: language modeling quality and diversity.\n\n\\paragraph{Language modeling quality.} We report perplexity (PPL) on the WikiText-103 validation set.\n\n\\paragraph{Lexical diversity.} We measure the rare n-gram ratio---the proportion of trigrams in generated text that qualify as rare under the definition above---and Distinct-$n$ \\citep{li2016diversity}, the fraction of unique $n$-grams ($n = 1, 2, 3$) in generated text.\n\n\\paragraph{Generation diversity.} We compute Self-BLEU \\citep{zhu2018texygen}: the average BLEU score between pairs of generated samples. Lower Self-BLEU indicates greater diversity across generations.\n\n\\paragraph{Representation quality.} We track two embedding-space diagnostics. RankMe measures the effective rank of the embedding matrix via singular value entropy \\citep{jing2022understanding}: a higher RankMe indicates more uniform utilization of embedding dimensions. The $k$-NN probe accuracy measures how well embeddings separate content categories via $k$-nearest-neighbor classification: declining accuracy signals loss of discriminative structure.\n\n\\subsection{Reproducibility}\n\nAll experiments are repeated across 3 random seeds (42, 123, 456). Each seed determines the random initialization of fine-tuning, the sampling randomness during generation, and (for Random 50\\%) the subset selection. All methods within a given seed share the same Generation~0 checkpoint and the same generated data pools, so that observed differences are attributable to the selection method alone. We report means and standard deviations across seeds.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01QQjheudAzNWoiKKHpkBQ4e`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "f7203f96-c316-4ec5-9bb5-1c93ce6b0c77",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RxxyzrzLVrDM3qhL6k4E8Q",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2264,
      "cache_read_input_tokens": 36213,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2264
      },
      "output_tokens": 44,
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

_source line 24 · 2026-05-13T18:55:23.672Z_

<details><summary>↩ Tool result · `toolu_01QQjheudAzNWoiKKHpkBQ4e`</summary>

````text
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
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "e07f1d82-daa6-4e3c-b6dc-e4e8181e9bd0",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 50
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_016NKYb4jeqaMskeok9YmbkZ`</summary>

```json
{
  "name": "methodology-section-v1",
  "type": "paper",
  "description": "Methodology section (Section 3) for EMNLP 2026 Findings paper, covering experimental setup: base model, self-training protocol, 4 data selection methods, selection ratio metric, evaluation metrics, and reproducibility.",
  "project": "div_cal_verify",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/methodology.tex",
  "tags": [
    "paper",
    "methodology",
    "latex",
    "emnlp2026"
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
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "544effb7-6058-4ed4-8f28-c0f09dae0a21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CeygYEobv7JDYL5vK2fFqZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 712,
      "cache_read_input_tokens": 38477,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 712
      },
      "output_tokens": 45,
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

_source line 26 · 2026-05-13T18:55:29.063Z_

<details><summary>↩ Tool result · `toolu_016NKYb4jeqaMskeok9YmbkZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260513_89b38a\", \"name\": \"methodology-section-v1\", \"type\": \"paper\", \"description\": \"Methodology section (Section 3) for EMNLP 2026 Findings paper, covering experimental setup: base model, self-training protocol, 4 data selection methods, selection ratio metric, evaluation metrics, and reproducibility.\", \"path\": \"projects/div_cal_verify/artifacts/_project/paper/methodology.tex\", \"url\": null, \"project\": \"div_cal_verify\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-13T18:55:29.039774+00:00\", \"tags\": [\"paper\", \"methodology\", \"latex\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "1b7c81ee-ce19-40e9-a730-0ab474735ba5",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260513_89b38a\\\", \\\"name\\\": \\\"methodology-section-v1\\\", \\\"type\\\": \\\"paper\\\", \\\"description\\\": \\\"Methodology section (Section 3) for EMNLP 2026 Findings paper, covering experimental setup: base model, self-training protocol, 4 data selection methods, selection ratio metric, evaluation metrics, and reproducibility.\\\", \\\"path\\\": \\\"projects/div_cal_verify/artifacts/_project/paper/methodology.tex\\\", \\\"url\\\": null, \\\"project\\\": \\\"div_cal_verify\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-13T18:55:29.039774+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"methodology\\\", \\\"latex\\\", \\\"emnlp2026\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260513_89b38a\", \"name\": \"methodology-section-v1\", \"type\": \"paper\", \"description\": \"Methodology section (Section 3) for EMNLP 2026 Findings paper, covering experimental setup: base model, self-training protocol, 4 data selection methods, selection ratio metric, evaluation metrics, and reproducibility.\", \"path\": \"projects/div_cal_verify/artifacts/_project/paper/methodology.tex\", \"url\": null, \"project\": \"div_cal_verify\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-13T18:55:29.039774+00:00\", \"tags\": [\"paper\", \"methodology\", \"latex\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 27_

Methodology section 写入 `docs/paper/methodology.tex`，已注册为 artifact。

内容概要：
- **3.1 Base Model and Dataset**: GPT2-125M + WikiText-103，说明选择理由
- **3.2 Self-Training Protocol**: 8 代迭代，500K tokens/代，累积微调，完整超参数
- **3.3 Data Selection Methods**: 4 种方法（Uncurated/RGDS/External-only/Random 50%）+ 对照逻辑的 factorial ablation 结构
- **3.4 Selection Ratio**: SR 公式定义、三种解释（>1, <1, ≈1）、rare trigram 定义
- **3.5 Evaluation Metrics**: PPL, rare n-gram ratio, Distinct-n, Self-BLEU, RankMe, k-NN probe
- **3.6 Reproducibility**: 3 seeds，共享 checkpoint 和数据池

待处理：Contriever 引用标记为 `[CITATION NEEDED: Izacard et al. 2022 Contriever]`，需补充 bib 条目。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "uuid": "01234b40-e461-4841-9de6-b0a1a94f075c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MDnyHzK1CnsRGV7dDxrHnw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 553,
      "cache_read_input_tokens": 39189,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 553
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

### Task result

_source line 28_

Methodology section 写入 `docs/paper/methodology.tex`，已注册为 artifact。

内容概要：
- **3.1 Base Model and Dataset**: GPT2-125M + WikiText-103，说明选择理由
- **3.2 Self-Training Protocol**: 8 代迭代，500K tokens/代，累积微调，完整超参数
- **3.3 Data Selection Methods**: 4 种方法（Uncurated/RGDS/External-only/Random 50%）+ 对照逻辑的 factorial ablation 结构
- **3.4 Selection Ratio**: SR 公式定义、三种解释（>1, <1, ≈1）、rare trigram 定义
- **3.5 Evaluation Metrics**: PPL, rare n-gram ratio, Distinct-n, Self-BLEU, RankMe, k-NN probe
- **3.6 Reproducibility**: 3 seeds，共享 checkpoint 和数据池

待处理：Contriever 引用标记为 `[CITATION NEEDED: Izacard et al. 2022 Contriever]`，需补充 bib 条目。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 80672,
  "duration_api_ms": 81467,
  "num_turns": 9,
  "stop_reason": "end_turn",
  "session_id": "8e9ef956-7b7c-4ca9-8115-7e4bb1cace93",
  "total_cost_usd": 0.37039525,
  "usage": {
    "input_tokens": 10,
    "cache_creation_input_tokens": 27901,
    "cache_read_input_tokens": 217346,
    "output_tokens": 3381,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 27901,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 309,
        "cache_read_input_tokens": 39189,
        "cache_creation_input_tokens": 553,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 553
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2666,
      "outputTokens": 20,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002766,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 10,
      "outputTokens": 3381,
      "cacheReadInputTokens": 217346,
      "cacheCreationInputTokens": 27901,
      "webSearchRequests": 0,
      "costUSD": 0.36762925,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "0f205c55-df28-4a1b-a9ee-abc1ed656f3c"
}
```

</details>

---

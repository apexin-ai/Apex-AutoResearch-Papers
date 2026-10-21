# paper writing

**Sign Misattribution in Step-Independent Agent RL: Dual Mechanism Diagnosis and Episode-Level Correction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 20
- **Recorded user turns:** 0
- **Tool calls:** 6
- **Original source:** `logs/workers/worker_paper_writing_20260517T101815.log`
- **Structured JSON:** [`df4d9b6ad03ff404de34.json`](../../sessions/df/df4d9b6ad03ff404de34.json)

## Before a recorded user message

20 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl",
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
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
  "uuid": "0fa66e95-a4a5-4a32-86d2-bf687509210d",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-6/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-1-projects-cost-verify-agent-rl/memory/"
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
    "resetsAt": 1779030600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "f9440db9-de09-49fe-9724-e1bcb5a2a6fc",
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me read the required files to understand the writing norms and existing paper content before writing the Conclusion section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "c12986f1-aae0-41f9-b751-768bdc57f03f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012b4vXi1TYKYCf1VZfvQC9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13975,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13975
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

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_01XzeFXzPVbU2k7bgiGWmLEL`</summary>

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
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "e7612838-be2d-4711-a114-d0eea6a6a98f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012b4vXi1TYKYCf1VZfvQC9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13975,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13975
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

_source line 6 · 2026-05-17T10:18:29.440Z_

<details><summary>↩ Tool result · `toolu_01XzeFXzPVbU2k7bgiGWmLEL`</summary>

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
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "88082bfd-22cd-49a9-8d46-bd52ee3ed34d",
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

<details open><summary>🔧 Tool call — Read · `toolu_01Rwq2Yvz6ipVxYfeQ1nAt5M`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "54a00b77-94a6-4d8a-8b96-0649d70ec2fc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012b4vXi1TYKYCf1VZfvQC9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13975,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13975
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

_source line 8 · 2026-05-17T10:18:29.911Z_

<details><summary>↩ Tool result · `toolu_01Rwq2Yvz6ipVxYfeQ1nAt5M`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Training Large Language Model (LLM) agents for multi-turn interactive tasks poses a fundamental challenge: policies must compose actions across 30 to 50 interaction steps in environments such as household navigation~\cite{kim2025reflact}, web interaction~\cite{digiRL2024}, and scientific experimentation. Supervised fine-tuning (SFT) can teach action formatting but fails to instill compositional planning, because expert demonstrations do not expose the trial-and-error exploration through which effective multi-step strategies emerge. Reinforcement learning (RL) addresses this gap by optimizing policies through direct environment interaction, and Group Relative Policy Optimization (GRPO)~\cite{shao2024deepseekmath} has become a preferred method due to its critic-free design and direct compatibility with language model architectures. Recent work applies RL-based training to interactive agents across diverse domains, from text-based games~\cite{ragen2025} and GUI interaction~\cite{digiRL2024} to tool use~\cite{spear2025} and instruction following~\cite{selfguide2026,feng2025gigpo}. These efforts share a common implementation pattern that has received little scrutiny: the multi-turn trajectory is decomposed into fixed-size windows, and each window is optimized as an independent training sample. This decomposition is the focus of our analysis.
5	
6	Current agent RL frameworks default to \textit{step-independent training}: the trajectory is partitioned into non-overlapping windows of $h$ consecutive steps, each receiving a discounted return derived from the binary episode outcome and optimized independently via GRPO~\cite{ragen2025,selfguide2026}. This choice is motivated by practical considerations: it fits long trajectories within limited context windows, multiplies the effective batch size, and aligns with the token-level training paradigm of language models. However, the decomposition introduces a fundamental credit assignment pathology. When each window receives a group-normalized advantage, the sign of that advantage reflects whether the \textit{episode} succeeded or failed, not whether the \textit{window's actions} were locally correct. In our experiments, this pathology produces a striking failure pattern: with $h=2$, step-independent training exhibits a two-phase collapse: task success drops while action validity initially remains high, but continued training under sign misattribution eventually destroys even basic action formatting (Section~\ref{sec:experiments}). The agent learns to produce well-formatted commands that satisfy syntactic constraints but loses the ability to complete tasks entirely. This collapse is not an artifact of a particular hyperparameter configuration. We observe the same failure across multiple learning rates, KL penalty strengths, and window sizes, consistent with a structural defect in the training paradigm rather than a tuning problem.
7	
8	Standard remedies do not resolve this collapse. Dense reward shaping, which provides per-step bonuses for intermediate goals such as valid action formatting, creates a different failure mode: the agent maximizes format-level rewards while task completion stays at zero. In our dense reward experiment, action validity increases from 60\% to 97.5\% while task success remains at 0\% (Section~\ref{sec:experiments}). Increasing the number of rollouts or adjusting the KL penalty delays the onset of collapse but does not prevent it. Generalized Advantage Estimation (GAE)~\cite{schulman2016gae} and Proximal Policy Optimization (PPO)~\cite{schulman2017ppo} offer finer-grained temporal credit assignment through learned value functions, but they add model complexity and have not been applied with a diagnosis of \textit{why} step-independent training fails in the first place. The root cause is not the choice of RL algorithm. It is the step-independent windowing itself, which corrupts the credit assignment signal at its source.
9	
10	We trace the collapse to two mechanisms operating at different layers under step-independent training. The first, \textbf{policy information loss}, operates at the inference layer: step-independent windowing truncates context at both inference and training, so each $h$-step window has no access to earlier observations. The model cannot condition on cross-step dependencies, and the optimizer cannot reinforce strategies it cannot represent. This establishes a structural performance ceiling that is constant across training. The second, \textbf{advantage sign misattribution}, operates at the training layer and is cumulative: under binary episode reward, the sign of each window's advantage $\hat{A}_k$ is determined by whether the episode succeeded or failed (Section~\ref{sec:m2_sign_misattribution}), not by the local quality of the window's actions. Good actions in failed episodes receive negative advantages and are actively suppressed, while bad actions in successful episodes are reinforced. Our formal analysis (Section~\ref{sec:formal_probability}) shows that at a baseline success rate of $p = 12.5\%$ with group size $K = 8$, approximately 80.9\% of gradient updates for locally correct windows point in the wrong direction. Sign misattribution progressively degrades performance below the ceiling set by information loss, driving the policy away from correct behaviors rather than merely reducing convergence speed. Episode-level GRPO eliminates both mechanisms by treating the complete trajectory as a single optimization sample, consistent with GRPO's original design~\cite{shao2024deepseekmath}, so that all steps share one advantage and cross-step dependencies are preserved through the full interaction history. In our experiments, episode-level training achieves 28.1\% validation success (from a baseline of 12.5\%), while step-independent training collapses to 0\%.
11	
12	Our contributions are as follows:
13	\begin{itemize}
14	    \item \textbf{Dual mechanism diagnosis.} We identify and formalize two mechanisms that cause catastrophic collapse under step-independent GRPO in multi-turn agent training: policy information loss and advantage sign misattribution. We show that sign misattribution is a directional error, with the probability of incorrect gradient direction approaching $1 - p$ as group size grows (Sections~\ref{sec:dual_mechanism},~\ref{sec:sign_fundamental},~\ref{sec:formal_probability}).
15	
16	    \item \textbf{Systematic empirical validation.} Through window-size ablation ($h \in \{2, 5, 10, 20, \text{full}\}$) and per-window advantage logging, we demonstrate a credit assignment cliff and provide direct empirical evidence for the sign misattribution mechanism (Section~\ref{sec:experiments}).
17	
18	    \item \textbf{Episode-level solution and analysis.} We show that episode-level GRPO simultaneously resolves both failure mechanisms, and we analyze its connection to GAE~\cite{schulman2016gae} and REINFORCE~\cite{williams1992reinforce}. We identify six factors that explain why the community has defaulted to the broken step-independent paradigm (Sections~\ref{sec:episode_level},~\ref{sec:classical_connection},~\ref{sec:why_defaults}).
19	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "00e1d635-8470-4860-a0bf-c6546e1cb916",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nTraining Large Language Model (LLM) agents for multi-turn interactive tasks poses a fundamental challenge: policies must compose actions across 30 to 50 interaction steps in environments such as household navigation~\\cite{kim2025reflact}, web interaction~\\cite{digiRL2024}, and scientific experimentation. Supervised fine-tuning (SFT) can teach action formatting but fails to instill compositional planning, because expert demonstrations do not expose the trial-and-error exploration through which effective multi-step strategies emerge. Reinforcement learning (RL) addresses this gap by optimizing policies through direct environment interaction, and Group Relative Policy Optimization (GRPO)~\\cite{shao2024deepseekmath} has become a preferred method due to its critic-free design and direct compatibility with language model architectures. Recent work applies RL-based training to interactive agents across diverse domains, from text-based games~\\cite{ragen2025} and GUI interaction~\\cite{digiRL2024} to tool use~\\cite{spear2025} and instruction following~\\cite{selfguide2026,feng2025gigpo}. These efforts share a common implementation pattern that has received little scrutiny: the multi-turn trajectory is decomposed into fixed-size windows, and each window is optimized as an independent training sample. This decomposition is the focus of our analysis.\n\nCurrent agent RL frameworks default to \\textit{step-independent training}: the trajectory is partitioned into non-overlapping windows of $h$ consecutive steps, each receiving a discounted return derived from the binary episode outcome and optimized independently via GRPO~\\cite{ragen2025,selfguide2026}. This choice is motivated by practical considerations: it fits long trajectories within limited context windows, multiplies the effective batch size, and aligns with the token-level training paradigm of language models. However, the decomposition introduces a fundamental credit assignment pathology. When each window receives a group-normalized advantage, the sign of that advantage reflects whether the \\textit{episode} succeeded or failed, not whether the \\textit{window's actions} were locally correct. In our experiments, this pathology produces a striking failure pattern: with $h=2$, step-independent training exhibits a two-phase collapse: task success drops while action validity initially remains high, but continued training under sign misattribution eventually destroys even basic action formatting (Section~\\ref{sec:experiments}). The agent learns to produce well-formatted commands that satisfy syntactic constraints but loses the ability to complete tasks entirely. This collapse is not an artifact of a particular hyperparameter configuration. We observe the same failure across multiple learning rates, KL penalty strengths, and window sizes, consistent with a structural defect in the training paradigm rather than a tuning problem.\n\nStandard remedies do not resolve this collapse. Dense reward shaping, which provides per-step bonuses for intermediate goals such as valid action formatting, creates a different failure mode: the agent maximizes format-level rewards while task completion stays at zero. In our dense reward experiment, action validity increases from 60\\% to 97.5\\% while task success remains at 0\\% (Section~\\ref{sec:experiments}). Increasing the number of rollouts or adjusting the KL penalty delays the onset of collapse but does not prevent it. Generalized Advantage Estimation (GAE)~\\cite{schulman2016gae} and Proximal Policy Optimization (PPO)~\\cite{schulman2017ppo} offer finer-grained temporal credit assignment through learned value functions, but they add model complexity and have not been applied with a diagnosis of \\textit{why} step-independent training fails in the first place. The root cause is not the choice of RL algorithm. It is the step-independent windowing itself, which corrupts the credit assignment signal at its source.\n\nWe trace the collapse to two mechanisms operating at different layers under step-independent training. The first, \\textbf{policy information loss}, operates at the inference layer: step-independent windowing truncates context at both inference and training, so each $h$-step window has no access to earlier observations. The model cannot condition on cross-step dependencies, and the optimizer cannot reinforce strategies it cannot represent. This establishes a structural performance ceiling that is constant across training. The second, \\textbf{advantage sign misattribution}, operates at the training layer and is cumulative: under binary episode reward, the sign of each window's advantage $\\hat{A}_k$ is determined by whether the episode succeeded or failed (Section~\\ref{sec:m2_sign_misattribution}), not by the local quality of the window's actions. Good actions in failed episodes receive negative advantages and are actively suppressed, while bad actions in successful episodes are reinforced. Our formal analysis (Section~\\ref{sec:formal_probability}) shows that at a baseline success rate of $p = 12.5\\%$ with group size $K = 8$, approximately 80.9\\% of gradient updates for locally correct windows point in the wrong direction. Sign misattribution progressively degrades performance below the ceiling set by information loss, driving the policy away from correct behaviors rather than merely reducing convergence speed. Episode-level GRPO eliminates both mechanisms by treating the complete trajectory as a single optimization sample, consistent with GRPO's original design~\\cite{shao2024deepseekmath}, so that all steps share one advantage and cross-step dependencies are preserved through the full interaction history. In our experiments, episode-level training achieves 28.1\\% validation success (from a baseline of 12.5\\%), while step-independent training collapses to 0\\%.\n\nOur contributions are as follows:\n\\begin{itemize}\n    \\item \\textbf{Dual mechanism diagnosis.} We identify and formalize two mechanisms that cause catastrophic collapse under step-independent GRPO in multi-turn agent training: policy information loss and advantage sign misattribution. We show that sign misattribution is a directional error, with the probability of incorrect gradient direction approaching $1 - p$ as group size grows (Sections~\\ref{sec:dual_mechanism},~\\ref{sec:sign_fundamental},~\\ref{sec:formal_probability}).\n\n    \\item \\textbf{Systematic empirical validation.} Through window-size ablation ($h \\in \\{2, 5, 10, 20, \\text{full}\\}$) and per-window advantage logging, we demonstrate a credit assignment cliff and provide direct empirical evidence for the sign misattribution mechanism (Section~\\ref{sec:experiments}).\n\n    \\item \\textbf{Episode-level solution and analysis.} We show that episode-level GRPO simultaneously resolves both failure mechanisms, and we analyze its connection to GAE~\\cite{schulman2016gae} and REINFORCE~\\cite{williams1992reinforce}. We identify six factors that explain why the community has defaulted to the broken step-independent paradigm (Sections~\\ref{sec:episode_level},~\\ref{sec:classical_connection},~\\ref{sec:why_defaults}).\n\\end{itemize}",
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

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_013A1nQ8X2eodfZjXeCAqxj5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "dd75182c-3c40-45d8-8719-400f9af0103d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012b4vXi1TYKYCf1VZfvQC9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13975,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13975
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

_source line 10 · 2026-05-17T10:18:30.147Z_

<details><summary>↩ Tool result · `toolu_013A1nQ8X2eodfZjXeCAqxj5`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\subsection{Generality of Sign Misattribution}
5	\label{sec:discussion_generality}
6	
7	The sign misattribution mechanism identified in Section~\ref{sec:m2_sign_misattribution} is not specific to RAGEN, ALFWorld, or GRPO. The failure arises from three structural properties that co-occur in any multi-turn agent RL setup: (a) step-level credit assignment via windowing, (b) sparse binary episode reward, and (c) group-relative advantage normalization. When these three conditions hold, the advantage sign for each window collapses to a proxy for episode outcome regardless of local action quality (Equation~\ref{eq:sign_correlation}). The environment details, the specific RL algorithm, and the model architecture are irrelevant to this structural argument.
8	
9	Consider the broader landscape of LLM agent training. Web agents operating in WebArena~\cite{zhou2024webarena} execute 20 to 40 interaction steps per episode with binary task completion rewards. Scientific experimentation agents in ScienceWorld~\cite{wang2022scienceworld} follow multi-step experimental protocols where success is determined only at the final measurement. GUI agents in mobile and desktop environments issue sequences of clicks and keystrokes with success defined by whether the target UI state is reached. Tool-use agents chain API calls where only the final output is evaluated. All of these settings combine long trajectories with sparse terminal rewards, and any framework that decomposes these trajectories into independently optimized windows will exhibit sign misattribution.
10	
11	Proposition~2 (Section~\ref{sec:formal_probability}) reveals a further implication: the severity of misattribution scales with task difficulty. As the baseline success rate $p$ decreases, $P(\text{correct} \mid \text{update}) \to p$ in the large-$K$ limit. Environments with longer horizons or more complex reasoning requirements tend to have lower baseline success rates, so sign misattribution becomes \textit{more} severe precisely where credit assignment is most needed. A web agent with $p = 5\%$ baseline success would experience correct gradient direction in only 5\% of updates, a regime where training cannot converge regardless of other hyperparameter choices.
12	
13	\subsection{Direction Correctness vs.\ Credit Granularity}
14	\label{sec:discussion_tradeoff}
15	
16	Episode-level GRPO eliminates sign misattribution by treating the full trajectory as a single optimization sample. The cost of this choice is that all tokens in the episode receive the same advantage. A correct action at step 3 and a redundant action at step 40 are reinforced with identical magnitude and sign. This represents a trade-off between two desiderata: direction correctness (whether the gradient sign is aligned with local action quality) and credit granularity (whether the gradient magnitude reflects per-step contribution to success).
17	
18	At the low success rates typical of early training ($p = 12.5\%$ in our experiments), direction correctness dominates. When 80.9\% of gradient updates point in the wrong direction, the optimization actively destroys good behaviors. Uniform reinforcement of all steps in a successful episode is imprecise but at least preserves correct sub-strategies within the trajectory. The asymmetry is stark: coarse-but-correct gradients produce slow convergence, while fine-but-wrong gradients produce divergence.
19	
20	As the policy improves and $p$ increases, the marginal value of per-step credit assignment grows. At $p = 50\%$, Proposition~2 predicts $P(\text{correct} \mid \text{update}) \approx 50\%$, meaning step-independent training would produce a roughly unbiased gradient in expectation (though with high variance). In this regime, the coarseness of episode-level training may become a binding constraint on sample efficiency. Methods that combine episode-level direction correctness with finer-grained credit represent a natural extension. GAE with episode-level correction (using a value function for magnitude estimation while constraining signs to be consistent with episode outcome) and GiGPO's nested group structure~\cite{feng2025gigpo} are two concrete approaches. The connection to GAE(1,1) established in Section~\ref{sec:classical_connection} suggests a principled interpolation: begin with $\lambda = 1$ (episode-level) during early training when direction correctness matters most, and anneal toward $\lambda < 1$ as the policy stabilizes and per-step credit becomes valuable.
21	
22	\subsection{Relationship to Classical Credit Assignment}
23	\label{sec:discussion_classical}
24	
25	Sign misattribution is a specific manifestation of the temporal credit assignment problem, adapted to the LLM agent setting. In classical RL, temporal credit assignment is addressed through value functions (TD learning), eligibility traces (TD($\lambda$)), or return decomposition methods. The solutions all share a common structure: they provide mechanisms for information to propagate across time steps within an episode, so that the contribution of each step to eventual reward can be estimated.
26	
27	Step-independent windowing violates this structure in a way that is unusual even within the classical RL literature. TD(0) assigns credit through one-step bootstrapped returns, which is local but connected: the value of state $s_t$ depends on $s_{t+1}$, creating a chain that propagates information across the episode over multiple training iterations. Monte Carlo methods assign credit through full-episode returns, providing direct (if noisy) temporal coupling. Step-independent training creates \textit{disconnected} windows that share no temporal coupling, neither through bootstrapping nor through shared returns. Each window is optimized as if it were an independent bandit arm that happens to receive a reward correlated with the episode outcome. This falls below the TD(0)-to-MC spectrum entirely.
28	
29	The multi-agent analogy from Section~\ref{sec:classical_connection} clarifies the structural novelty. In cooperative multi-agent RL, the credit assignment challenge of shared team reward is well-recognized, and solutions such as counterfactual baselines (COMA~\cite{foerster2018coma}) or value decomposition (QMIX~\cite{rashid2018qmix}) exist. In multi-turn LLM agent training, the same structural problem arises from an implementation choice rather than from the problem formulation itself. The multi-agent credit assignment problem is inherent to team games; the sign misattribution problem in agent RL is artificial, introduced by the windowing design and removable by episode-level training.
30	
31	\subsection{Dual Mechanism Interaction}
32	\label{sec:discussion_interaction}
33	
34	Information loss (Mechanism 1) and sign misattribution (Mechanism 2) are not independent. They interact through the success rate $p$, creating a feedback loop that accelerates collapse at small window sizes. Mechanism 1 restricts the representable strategy space, imposing a ceiling on achievable task success for a given $h$. This ceiling determines the maximum $p$ that the policy can sustain. Mechanism 2 then drives performance below this ceiling at a rate that depends on $p$ itself: lower $p$ produces more severe misattribution (Proposition~2), which further reduces $p$, which further increases misattribution severity.
35	
36	This interaction creates a vicious cycle. At $h = 2$, the information-loss ceiling is low, so the policy cannot achieve high $p$ even with perfect optimization. The low $p$ triggers severe sign misattribution ($\approx$80.9\% wrong-direction gradients at $p = 12.5\%$), which erodes whatever competence the model retains within its truncated context. The erosion reduces $p$ further, intensifying the misattribution. The two-phase collapse observed empirically (strategic failure followed by formatting failure) reflects this cascade: Mechanism 2 first destroys task-level strategies (reducing $p$ to near zero), then continues to corrupt lower-level action representations that were initially robust.
37	
38	At larger $h$ values, the ceiling is higher, sustaining a higher $p$ that partially mitigates misattribution severity. This predicts a more gradual degradation rather than catastrophic collapse. The h-sweep ablation (Section~\ref{sec:results_hsweep}) tests this prediction by examining whether larger $h$ values exhibit slower collapse trajectories. Episode-level training breaks the cycle entirely by eliminating both mechanisms simultaneously: the full context removes the information-loss ceiling, and the single episode-level advantage removes the opportunity for sign misattribution.
39	
40	
41	\subsection{Limitations}
42	\label{sec:limitations}
43	
44	\paragraph{Single environment.} Our experiments are conducted exclusively on ALFWorld, a text-based household environment. The dual mechanism analysis depends only on the training algorithm structure (windowing, binary reward, group normalization) and not on environment-specific properties, so the theoretical argument is environment-agnostic. However, empirical validation on additional multi-turn environments such as ScienceWorld~\cite{wang2022scienceworld} or WebShop~\cite{yao2022webshop} would strengthen the generality claim. Different environments may exhibit different baseline success rates, trajectory lengths, and dependency structures that modulate the practical severity of sign misattribution.
45	
46	\paragraph{Single model scale.} All experiments use Qwen3-1.7B. The severity of sign misattribution depends on $p$ (Proposition~2), which varies with model capacity. A 7B or 14B model may achieve a higher SFT baseline, reducing the fraction of wrong-sign updates. The misattribution mechanism does not disappear at higher $p$ (it persists as long as $p < 1$), but its practical impact may be less catastrophic if the model starts closer to the ceiling. Scaling experiments are needed to characterize the relationship between model capacity, baseline success rate, and collapse dynamics.
47	
48	\paragraph{Coarse credit in episode-level training.} Episode-level GRPO assigns uniform advantage to all tokens in an episode. For very long episodes ($T > 100$) or tasks with many independent sub-goals, this coarseness may limit learning efficiency even though it preserves direction correctness. The trade-off between direction correctness and credit granularity (Section~\ref{sec:discussion_tradeoff}) becomes increasingly relevant at higher success rates where the sign error is less severe but the efficiency cost of uniform reinforcement grows.
49	
50	\paragraph{Selective verification not implemented.} The selective verification component (Section~\ref{sec:selective_verification}) remains a design proposal. We present the training methodology diagnosis and episode-level solution, but the downstream application of training a selective verification policy has not been implemented or evaluated. The contribution of this paper is the credit assignment analysis and fix, not the verification application.
51	
52	\paragraph{Limited gradient analysis scope.} The empirical sign misattribution verification (Section~\ref{sec:sign_verification}) uses $h = 2$, representing the most extreme case of windowed training. Analysis across multiple $h$ values ($h \in \{5, 10, 20\}$) would reveal how misattribution severity varies with window size in practice and whether the theoretical predictions (which are $h$-independent for a given $p$) hold when different window sizes produce different effective $p$ values during training.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "f87d8ada-8e8e-4a22-988c-a8b162a11cca",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\subsection{Generality of Sign Misattribution}\n\\label{sec:discussion_generality}\n\nThe sign misattribution mechanism identified in Section~\\ref{sec:m2_sign_misattribution} is not specific to RAGEN, ALFWorld, or GRPO. The failure arises from three structural properties that co-occur in any multi-turn agent RL setup: (a) step-level credit assignment via windowing, (b) sparse binary episode reward, and (c) group-relative advantage normalization. When these three conditions hold, the advantage sign for each window collapses to a proxy for episode outcome regardless of local action quality (Equation~\\ref{eq:sign_correlation}). The environment details, the specific RL algorithm, and the model architecture are irrelevant to this structural argument.\n\nConsider the broader landscape of LLM agent training. Web agents operating in WebArena~\\cite{zhou2024webarena} execute 20 to 40 interaction steps per episode with binary task completion rewards. Scientific experimentation agents in ScienceWorld~\\cite{wang2022scienceworld} follow multi-step experimental protocols where success is determined only at the final measurement. GUI agents in mobile and desktop environments issue sequences of clicks and keystrokes with success defined by whether the target UI state is reached. Tool-use agents chain API calls where only the final output is evaluated. All of these settings combine long trajectories with sparse terminal rewards, and any framework that decomposes these trajectories into independently optimized windows will exhibit sign misattribution.\n\nProposition~2 (Section~\\ref{sec:formal_probability}) reveals a further implication: the severity of misattribution scales with task difficulty. As the baseline success rate $p$ decreases, $P(\\text{correct} \\mid \\text{update}) \\to p$ in the large-$K$ limit. Environments with longer horizons or more complex reasoning requirements tend to have lower baseline success rates, so sign misattribution becomes \\textit{more} severe precisely where credit assignment is most needed. A web agent with $p = 5\\%$ baseline success would experience correct gradient direction in only 5\\% of updates, a regime where training cannot converge regardless of other hyperparameter choices.\n\n\\subsection{Direction Correctness vs.\\ Credit Granularity}\n\\label{sec:discussion_tradeoff}\n\nEpisode-level GRPO eliminates sign misattribution by treating the full trajectory as a single optimization sample. The cost of this choice is that all tokens in the episode receive the same advantage. A correct action at step 3 and a redundant action at step 40 are reinforced with identical magnitude and sign. This represents a trade-off between two desiderata: direction correctness (whether the gradient sign is aligned with local action quality) and credit granularity (whether the gradient magnitude reflects per-step contribution to success).\n\nAt the low success rates typical of early training ($p = 12.5\\%$ in our experiments), direction correctness dominates. When 80.9\\% of gradient updates point in the wrong direction, the optimization actively destroys good behaviors. Uniform reinforcement of all steps in a successful episode is imprecise but at least preserves correct sub-strategies within the trajectory. The asymmetry is stark: coarse-but-correct gradients produce slow convergence, while fine-but-wrong gradients produce divergence.\n\nAs the policy improves and $p$ increases, the marginal value of per-step credit assignment grows. At $p = 50\\%$, Proposition~2 predicts $P(\\text{correct} \\mid \\text{update}) \\approx 50\\%$, meaning step-independent training would produce a roughly unbiased gradient in expectation (though with high variance). In this regime, the coarseness of episode-level training may become a binding constraint on sample efficiency. Methods that combine episode-level direction correctness with finer-grained credit represent a natural extension. GAE with episode-level correction (using a value function for magnitude estimation while constraining signs to be consistent with episode outcome) and GiGPO's nested group structure~\\cite{feng2025gigpo} are two concrete approaches. The connection to GAE(1,1) established in Section~\\ref{sec:classical_connection} suggests a principled interpolation: begin with $\\lambda = 1$ (episode-level) during early training when direction correctness matters most, and anneal toward $\\lambda < 1$ as the policy stabilizes and per-step credit becomes valuable.\n\n\\subsection{Relationship to Classical Credit Assignment}\n\\label{sec:discussion_classical}\n\nSign misattribution is a specific manifestation of the temporal credit assignment problem, adapted to the LLM agent setting. In classical RL, temporal credit assignment is addressed through value functions (TD learning), eligibility traces (TD($\\lambda$)), or return decomposition methods. The solutions all share a common structure: they provide mechanisms for information to propagate across time steps within an episode, so that the contribution of each step to eventual reward can be estimated.\n\nStep-independent windowing violates this structure in a way that is unusual even within the classical RL literature. TD(0) assigns credit through one-step bootstrapped returns, which is local but connected: the value of state $s_t$ depends on $s_{t+1}$, creating a chain that propagates information across the episode over multiple training iterations. Monte Carlo methods assign credit through full-episode returns, providing direct (if noisy) temporal coupling. Step-independent training creates \\textit{disconnected} windows that share no temporal coupling, neither through bootstrapping nor through shared returns. Each window is optimized as if it were an independent bandit arm that happens to receive a reward correlated with the episode outcome. This falls below the TD(0)-to-MC spectrum entirely.\n\nThe multi-agent analogy from Section~\\ref{sec:classical_connection} clarifies the structural novelty. In cooperative multi-agent RL, the credit assignment challenge of shared team reward is well-recognized, and solutions such as counterfactual baselines (COMA~\\cite{foerster2018coma}) or value decomposition (QMIX~\\cite{rashid2018qmix}) exist. In multi-turn LLM agent training, the same structural problem arises from an implementation choice rather than from the problem formulation itself. The multi-agent credit assignment problem is inherent to team games; the sign misattribution problem in agent RL is artificial, introduced by the windowing design and removable by episode-level training.\n\n\\subsection{Dual Mechanism Interaction}\n\\label{sec:discussion_interaction}\n\nInformation loss (Mechanism 1) and sign misattribution (Mechanism 2) are not independent. They interact through the success rate $p$, creating a feedback loop that accelerates collapse at small window sizes. Mechanism 1 restricts the representable strategy space, imposing a ceiling on achievable task success for a given $h$. This ceiling determines the maximum $p$ that the policy can sustain. Mechanism 2 then drives performance below this ceiling at a rate that depends on $p$ itself: lower $p$ produces more severe misattribution (Proposition~2), which further reduces $p$, which further increases misattribution severity.\n\nThis interaction creates a vicious cycle. At $h = 2$, the information-loss ceiling is low, so the policy cannot achieve high $p$ even with perfect optimization. The low $p$ triggers severe sign misattribution ($\\approx$80.9\\% wrong-direction gradients at $p = 12.5\\%$), which erodes whatever competence the model retains within its truncated context. The erosion reduces $p$ further, intensifying the misattribution. The two-phase collapse observed empirically (strategic failure followed by formatting failure) reflects this cascade: Mechanism 2 first destroys task-level strategies (reducing $p$ to near zero), then continues to corrupt lower-level action representations that were initially robust.\n\nAt larger $h$ values, the ceiling is higher, sustaining a higher $p$ that partially mitigates misattribution severity. This predicts a more gradual degradation rather than catastrophic collapse. The h-sweep ablation (Section~\\ref{sec:results_hsweep}) tests this prediction by examining whether larger $h$ values exhibit slower collapse trajectories. Episode-level training breaks the cycle entirely by eliminating both mechanisms simultaneously: the full context removes the information-loss ceiling, and the single episode-level advantage removes the opportunity for sign misattribution.\n\n\n\\subsection{Limitations}\n\\label{sec:limitations}\n\n\\paragraph{Single environment.} Our experiments are conducted exclusively on ALFWorld, a text-based household environment. The dual mechanism analysis depends only on the training algorithm structure (windowing, binary reward, group normalization) and not on environment-specific properties, so the theoretical argument is environment-agnostic. However, empirical validation on additional multi-turn environments such as ScienceWorld~\\cite{wang2022scienceworld} or WebShop~\\cite{yao2022webshop} would strengthen the generality claim. Different environments may exhibit different baseline success rates, trajectory lengths, and dependency structures that modulate the practical severity of sign misattribution.\n\n\\paragraph{Single model scale.} All experiments use Qwen3-1.7B. The severity of sign misattribution depends on $p$ (Proposition~2), which varies with model capacity. A 7B or 14B model may achieve a higher SFT baseline, reducing the fraction of wrong-sign updates. The misattribution mechanism does not disappear at higher $p$ (it persists as long as $p < 1$), but its practical impact may be less catastrophic if the model starts closer to the ceiling. Scaling experiments are needed to characterize the relationship between model capacity, baseline success rate, and collapse dynamics.\n\n\\paragraph{Coarse credit in episode-level training.} Episode-level GRPO assigns uniform advantage to all tokens in an episode. For very long episodes ($T > 100$) or tasks with many independent sub-goals, this coarseness may limit learning efficiency even though it preserves direction correctness. The trade-off between direction correctness and credit granularity (Section~\\ref{sec:discussion_tradeoff}) becomes increasingly relevant at higher success rates where the sign error is less severe but the efficiency cost of uniform reinforcement grows.\n\n\\paragraph{Selective verification not implemented.} The selective verification component (Section~\\ref{sec:selective_verification}) remains a design proposal. We present the training methodology diagnosis and episode-level solution, but the downstream application of training a selective verification policy has not been implemented or evaluated. The contribution of this paper is the credit assignment analysis and fix, not the verification application.\n\n\\paragraph{Limited gradient analysis scope.} The empirical sign misattribution verification (Section~\\ref{sec:sign_verification}) uses $h = 2$, representing the most extreme case of windowed training. Analysis across multiple $h$ values ($h \\in \\{5, 10, 20\\}$) would reveal how misattribution severity varies with window size in practice and whether the theoretical predictions (which are $h$-independent for a given $p$) hold when different window sizes produce different effective $p$ values during training.",
      "numLines": 52,
      "startLine": 1,
      "totalLines": 52
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_015ZjuohuzVBEApiU42GVpD1`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
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
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "07cf59c7-a519-4670-8196-91914d9ede42",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HzhaAU4QJtr6fgb3WRHSs7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10104,
      "cache_read_input_tokens": 25816,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10104
      },
      "output_tokens": 36,
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

_source line 12 · 2026-05-17T10:18:33.825Z_

<details><summary>↩ Tool result · `toolu_015ZjuohuzVBEApiU42GVpD1`</summary>

```text
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
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "d8ce2b71-1c15-4886-85ab-ca3b1f0c4a23",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
      "content": "---\nname: paper-writing-norms\ndescription: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 2\npriority: 9\ntags:\n  - writing\n  - paper\n  - style\n  - norms\nroles:\n  - agent\n  - worker\n  - paper_agent\n---\n\n# 论文写作风格规范\n\n> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。\n\n---\n\n## 一、总体写作哲学\n\n### 1.1 故事驱动，不是数据堆砌\n\n- 论文必须以\"故事线\"为核心展开：问题 → 洞察 → 方法 → 验证\n- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进\n- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌\n- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing\n\n### 1.2 主线统一性\n\n- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**\n- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C\n- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机\n- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线\n\n### 1.3 专有名词必须有定义\n\n- 首次出现的专有名词/缩写必须给出完整定义和解释\n- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）\n- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用\n- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug\n\n### 1.4 写作前必读同类优秀论文\n\n- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可",
      "numLines": 50,
      "startLine": 1,
      "totalLines": 252
    }
  }
}
```

</details>

---

### Assistant

_source line 13_

<details><summary>Logged reasoning block</summary>

```text
Now I have enough context. Let me write the Conclusion section based on the instructions. I need to:

1. ~300 words, not exceeding 350
2. 4 paragraphs structure as specified
3. No em-dash or en-dash
4. No -ing phrase endings
5. No AI-style words
6. No comments
7. Use \section{Conclusion} \label{sec:conclusion}
8. Key numbers: p=12.5%, K=8, 80.9% wrong-sign, 28.1% episode-level success, 0% step-independent collapse, 89.3%→43.1% action validity


9. No \cite references
10. Not repeat Discussion content

I'm checking which section labels I can reference to avoid repeating discussion content and maintain coherence with the rest of the paper.

Now I'm drafting the conclusion with several constraints in mind: keeping it concise around 300 words, avoiding certain phrases and punctuation patterns, and making sure I don't rehash the trade-off analysis or classical connections already covered in the discussion section.

For the contributions paragraph, I'm identifying the core findings: the dual mechanism of policy information loss at inference and advantage sign misattribution during training, the specific quantitative result about gradient direction errors at baseline conditions, and the empirical observation of a performance cliff rather than smooth degradation as the window size parameter changes.

The key insight is that sign errors in gradients are fundamentally more damaging than magnitude imprecision—wrong-direction updates actively push the model away from good solutions, whereas imprecise magnitudes just slow things down. This principle generalizes across any agent RL approach combining windowing, sparse rewards, and group normalization. Looking ahead, the natural extensions are exploring when agents should self-verify during execution and testing whether these findings hold across different environments like WebShop and ScienceWorld.

I'm also thinking about scaling this up with larger models to see how sign misattribution behaves as capacity increases, and there's a promising direction with annealing the credit assignment granularity from episode-level to finer-grained over time—that could give us the best of both worlds in terms of direction correctness and credit precision.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "b4d2c32e-b6a3-4e84-8f7a-19a7317e25f3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016bQ4Gv4jk2r2nMrPw6VbHq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1003,
      "cache_read_input_tokens": 35920,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1003
      },
      "output_tokens": 11,
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

_source line 14_

Now I'll check if the output directory exists and write the Conclusion.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "f8870c13-a480-4a69-8d9e-1cec51a2b542",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016bQ4Gv4jk2r2nMrPw6VbHq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1003,
      "cache_read_input_tokens": 35920,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1003
      },
      "output_tokens": 11,
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

_source line 15_

<details open><summary>🔧 Tool call — Bash · `toolu_01Jpd4fG3YspTzBHzHMVghtu`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/",
  "description": "List paper directory contents"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "cacd78e7-335f-4642-8cc4-dbbd90ad7937",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016bQ4Gv4jk2r2nMrPw6VbHq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1003,
      "cache_read_input_tokens": 35920,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1003
      },
      "output_tokens": 11,
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

_source line 16 · 2026-05-17T10:19:00.718Z_

<details><summary>↩ Tool result · `toolu_01Jpd4fG3YspTzBHzHMVghtu`</summary>

```text
citation_verification_report.md
discussion.tex
experiments.tex
introduction.tex
method.tex
references.bib
related_work.tex
theoretical_analysis.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "3744bebc-10c2-4539-b7cf-cb86777ca271",
  "tool_use_result": {
    "stdout": "citation_verification_report.md\ndiscussion.tex\nexperiments.tex\nintroduction.tex\nmethod.tex\nreferences.bib\nrelated_work.tex\ntheoretical_analysis.tex",
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

_source line 17_

<details open><summary>🔧 Tool call — Write · `toolu_01W5YG7FhQLhV38VFtboz7gL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/conclusion.tex",
  "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nMulti-turn agent RL requires credit assignment across long interaction trajectories, yet current frameworks default to step-independent windowing that decomposes trajectories into independently optimized windows. This default introduces a structural credit assignment pathology that no hyperparameter tuning can resolve.\n\nWe diagnose a dual mechanism underlying this failure: policy information loss at the inference layer, which imposes a constant performance ceiling, and advantage sign misattribution at the training layer, which causes cumulative degradation. Formal analysis shows that at a baseline success rate of $p = 12.5\\%$ with group size $K = 8$, approximately 80.9\\% of gradient updates for locally correct windows point in the wrong direction. Our window-size ablation reveals a credit assignment cliff: as $h$ decreases, performance does not degrade smoothly but collapses in two phases, with action validity dropping from 89.3\\% to 43.1\\%. Episode-level GRPO, which treats the full trajectory as a single optimization sample, eliminates both mechanisms and achieves 28.1\\% validation success where step-independent training collapses to 0\\%.\n\nThe central insight is that sign errors are more destructive than magnitude imprecision. Gradients that point in the wrong direction cause active divergence, while gradients with imprecise magnitude merely slow convergence. This distinction applies to any agent RL method that combines step-level windowing, sparse binary reward, and group-relative advantage normalization.\n\nSeveral directions extend this work. First, selective verification trains the agent to learn when self-verification is warranted during execution. Second, cross-environment validation on WebShop and ScienceWorld would test whether empirical severity matches our theoretical predictions across different trajectory lengths and success rates. Third, scaling experiments with 7B and 14B models will reveal how sign misattribution interacts with model capacity. Finally, $\\lambda$-annealing from episode-level ($\\lambda = 1$) to finer-grained credit ($\\lambda < 1$) offers a principled interpolation between direction correctness and credit granularity as the policy improves.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "dc9dcd99-e5ba-46dc-bcf2-18b79046d1e9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HyMWR8SKrZ78FS4csmVJkc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1253,
      "cache_read_input_tokens": 36923,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1253
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

_source line 18 · 2026-05-17T10:19:08.765Z_

<details><summary>↩ Tool result · `toolu_01W5YG7FhQLhV38VFtboz7gL`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/conclusion.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "ecb8229f-caed-40ce-9be6-b05f4e8bb148",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/conclusion.tex",
    "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nMulti-turn agent RL requires credit assignment across long interaction trajectories, yet current frameworks default to step-independent windowing that decomposes trajectories into independently optimized windows. This default introduces a structural credit assignment pathology that no hyperparameter tuning can resolve.\n\nWe diagnose a dual mechanism underlying this failure: policy information loss at the inference layer, which imposes a constant performance ceiling, and advantage sign misattribution at the training layer, which causes cumulative degradation. Formal analysis shows that at a baseline success rate of $p = 12.5\\%$ with group size $K = 8$, approximately 80.9\\% of gradient updates for locally correct windows point in the wrong direction. Our window-size ablation reveals a credit assignment cliff: as $h$ decreases, performance does not degrade smoothly but collapses in two phases, with action validity dropping from 89.3\\% to 43.1\\%. Episode-level GRPO, which treats the full trajectory as a single optimization sample, eliminates both mechanisms and achieves 28.1\\% validation success where step-independent training collapses to 0\\%.\n\nThe central insight is that sign errors are more destructive than magnitude imprecision. Gradients that point in the wrong direction cause active divergence, while gradients with imprecise magnitude merely slow convergence. This distinction applies to any agent RL method that combines step-level windowing, sparse binary reward, and group-relative advantage normalization.\n\nSeveral directions extend this work. First, selective verification trains the agent to learn when self-verification is warranted during execution. Second, cross-environment validation on WebShop and ScienceWorld would test whether empirical severity matches our theoretical predictions across different trajectory lengths and success rates. Third, scaling experiments with 7B and 14B models will reveal how sign misattribution interacts with model capacity. Finally, $\\lambda$-annealing from episode-level ($\\lambda = 1$) to finer-grained credit ($\\lambda < 1$) offers a principled interpolation between direction correctness and credit granularity as the policy improves.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 19_

Conclusion section written to `docs/paper/conclusion.tex`. 4 paragraphs, ~305 words, covering problem restatement, dual mechanism contributions with key numbers, the sign-vs-magnitude takeaway, and future directions.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "uuid": "2a8e3779-c4b7-42dd-af66-e189e69eee60",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M5GMB3JyzG5sEPujG6JEe5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 644,
      "cache_read_input_tokens": 38176,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 644
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

### Task result

_source line 20_

Conclusion section written to `docs/paper/conclusion.tex`. 4 paragraphs, ~305 words, covering problem restatement, dual mechanism contributions with key numbers, the sign-vs-magnitude takeaway, and future directions.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 48027,
  "duration_api_ms": 48987,
  "num_turns": 7,
  "stop_reason": "end_turn",
  "session_id": "e3e8abbc-75ab-4d78-a9f2-346bd01eb1e0",
  "total_cost_usd": 0.30024075,
  "usage": {
    "input_tokens": 6,
    "cache_creation_input_tokens": 26979,
    "cache_read_input_tokens": 148676,
    "output_tokens": 2201,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 26979,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 55,
        "cache_read_input_tokens": 38176,
        "cache_creation_input_tokens": 644,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 644
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2149,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002229,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 6,
      "outputTokens": 2201,
      "cacheReadInputTokens": 148676,
      "cacheCreationInputTokens": 26979,
      "webSearchRequests": 0,
      "costUSD": 0.29801174999999996,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "bd6eeb6b-aed6-49e5-848f-e48cae867e95"
}
```

</details>

---

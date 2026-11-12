# Sources for external facts in this repository

Every statement about other benchmarks, tools, data licenses or dates in the docs and the paper draft is checked
against the source below. Checked 1 November 2026.

| Statement | Source |
|---|---|
| ARC-AGI keeps a 120-task semi-private evaluation set (used for closed-model and intra-year standings) and a 120-task private evaluation set, both held privately on Kaggle | [ARC-AGI guide](https://arcprize.org/guide/1) |
| ARC Prize 2025 Kaggle submissions ran on the private set without internet access | [ARC Prize 2025 on Kaggle](https://www.kaggle.com/competitions/arc-prize-2025/) |
| Humanity's Last Exam keeps held-out questions private to assess overfitting to the public set | [lastexam.ai](https://lastexam.ai/) |
| LAB-Bench keeps a 20% private test subset to monitor contamination | [LAB-Bench repository](https://github.com/Future-House/LAB-Bench) |
| SWE-bench Verified: 500 human-filtered instances | [SWE-bench Verified](https://www.swebench.com/verified) |
| SWE-bench-Live updates automatically with recent tasks | [SWE-bench-Live](https://swe-bench-live.github.io/) |
| LiveBench adds and updates questions monthly | [LiveBench paper](https://arxiv.org/abs/2406.19314) |
| GSM-Symbolic generates instances from templates | [GSM-Symbolic paper](https://arxiv.org/abs/2410.05229) |
| tau-bench defines pass^k (success on all k trials) | [tau-bench paper](https://arxiv.org/abs/2406.12045) |
| HAL: cost-aware, standardized harness, traces | [HAL about page](https://hal.cs.princeton.edu/about) |
| AI Agents That Matter: cost with accuracy, adequate holdouts, standardization | [paper](https://arxiv.org/abs/2407.01502) |
| Terminal-Bench: Docker environment per task, verified solutions, tests | [announcement](https://www.tbench.ai/news/announcement) |
| BIG-bench canary GUID for training-data detection | [BIG-bench training_on_test_set](https://github.com/google/BIG-bench/blob/main/bigbench/benchmark_tasks/training_on_test_set/README.md) |
| Agentic Benchmark Checklist items (I.a-I.I, II.1-II.9, III.1-III.13) | [ABC.md](https://github.com/uiuc-kang-lab/agentic-benchmarks/blob/main/ABC.md), [paper](https://arxiv.org/abs/2507.02825) |
| BetterBench (NeurIPS 2024 Datasets and Benchmarks) | [proceedings](https://proceedings.neurips.cc/paper_files/paper/2024/hash/26889e8359e7ef8a7f5d77457364ca55-Abstract-Datasets_and_Benchmarks_Track.html) |
| ScienceAgentBench: 102 tasks from 44 publications, four disciplines, nine experts | [paper](https://arxiv.org/abs/2410.05080) |
| BixBench: over 50 analysis scenarios, nearly 300 open-answer questions | [paper](https://arxiv.org/abs/2503.00096) |
| MLE-bench: 75 Kaggle competitions | [paper](https://arxiv.org/abs/2410.07095) |
| PaperBench: 20 ICML 2024 papers | [OpenAI](https://openai.com/index/paperbench/) |
| CORE-Bench: 270 tasks from 90 papers | [paper](https://arxiv.org/abs/2409.11363) |
| ReX-MLE: 20 medical-imaging challenges | [PMLR](https://proceedings.mlr.press/v315/kenia26a.html) |
| HealthAgentBench includes MRI among its modalities | [HealthAgentBench v2](https://microsoft.github.io/HealthAgentBench/v2/) |
| NeurIPS 2026 Evaluations and Datasets track (deadline passed May 2026) | [OpenReview](https://openreview.net/group?id=NeurIPS.cc/2026/Evaluations_and_Datasets_Track) |
| ISMRM 2027 abstracts closed 28 October 2026; meeting 8-13 May 2027, Vancouver | [ISMRM news](https://www.ismrm.org/ismrm-ismrt-open-abstract-submissions-for-2027-annual-meeting-exhibition-in-vancouver/), [call](https://www.ismrm.org/27m/call/) |
| M4Raw v1.6 is CC BY 4.0 | [Zenodo record 8056074](https://doi.org/10.5281/zenodo.8056074) (API license field: cc-by-4.0) |
| OpenNeuro publishes datasets under CC0 | [OpenNeuro FAQ](https://docs.openneuro.org/faq) |
| fastMRI data may not be redistributed without permission (NYU Dataset Sharing Agreement) | [NYU data catalog](https://datacatalog.med.nyu.edu/dataset/10389) |
| juliapkg: PYTHON_JULIAPKG_EXE, PYTHON_JULIAPKG_PROJECT, PYTHON_JULIAPKG_OFFLINE | [juliapkg on PyPI](https://pypi.org/project/juliapkg/) |
| python:3.12.14-slim-bookworm is an official image tag | [docker-library official images](https://github.com/docker-library/official-images/blob/master/library/python) |
| codex exec and claude CLI flags used by mrab | the installed CLIs' --help output (codex exec, claude) |
| AWS CLI "aws login" needs CLI v2.32.0+, sessions last up to 12 h; macOS installer AWSCLIV2.pkg | [AWS sign-in guide](https://docs.aws.amazon.com/signin/latest/userguide/command-line-sign-in.html), [install guide](https://docs.aws.amazon.com/cli/latest/userguide/getting-started-install.html) |
| Agent4MR: agents generate and refine PyPulseq sequences with a physics-aware validation report; compared with LLM4MR (context only) and a human developer on spin-echo EPI | [arXiv:2604.13282](https://arxiv.org/abs/2604.13282) |
| ABRA: 655 programmatically generated radiology-viewer tasks, scored on planning, execution and outcome | [arXiv:2605.11224](https://arxiv.org/abs/2605.11224) |
| HealthAgentBench: 75 agentic healthcare tasks across 9 categories, binary success criteria | [arXiv:2606.31179](https://arxiv.org/abs/2606.31179) |
| BCER Agent: long-horizon MRI workflow execution on brain, prostate and cardiac tasks | [arXiv:2605.29163](https://arxiv.org/abs/2605.29163) |
| BetterBench: 46 best practices across the benchmark lifecycle, 24 benchmarks assessed | [arXiv:2411.12990](https://arxiv.org/abs/2411.12990) |

## Scientific-discovery evaluation design

The following sources were checked on 12 November 2026. They inform the proposed design in
[RESEARCH-DISCOVERY.md](RESEARCH-DISCOVERY.md); they do not validate MRI Agent Bench's own discovery capabilities.

| Statement | Primary source |
|---|---|
| AlphaEvolve combines language-model code proposals, automated evaluators and evolutionary search | [Novikov et al., AlphaEvolve (2025)](https://arxiv.org/abs/2506.13131) |
| Co-Scientist generates and refines hypotheses from researcher goals and prior evidence, with experimental validation in selected biomedical applications | [Gottweis et al., Accelerating scientific discovery with Co-Scientist, Nature (2026)](https://www.nature.com/articles/s41586-026-10644-y) |
| PaperBench evaluates replication of published AI research using detailed, expert-developed task rubrics | [Starace et al., PaperBench (2025)](https://arxiv.org/abs/2504.01848) |

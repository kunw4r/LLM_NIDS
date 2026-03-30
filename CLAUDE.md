# CLAUDE.md — AMATAS Project Context

> **This file is read by every Claude Code instance.** Follow these instructions exactly.

---

## 1. PROJECT OVERVIEW

**AMATAS** (Advanced Multi-Agent Threat Analysis System) is an LLM-augmented
Network Intrusion Detection System built as a university Master's thesis.
Submission deadline: **April 2026** (~2 months away).

The core question: can LLMs provide *explainable* network intrusion detection
that traditional ML cannot? Unlike black-box classifiers, every AMATAS verdict
includes full reasoning chains from multiple specialist agents — you can trace
exactly why a flow was flagged, what evidence was considered, and what
counter-arguments were weighed.

**Dataset:** CICIDS2018 NetFlow v3 — 20M flows, 53 features, 14 attack types,
87% benign. IPs are anonymized (private ranges like 172.31.x.x). Split into:
- `development.csv` — 7.04M flows (training/batch creation)
- `validation.csv` — 5.03M flows (hyperparameter tuning)
- `test.csv` — 8.05M flows (final evaluation, held out)

---

## 2. THE THREE AMATAS ITERATIONS

### v1 — Pure Multi-Agent (baseline, DONE)
Six LLM agents analyze every flow. No pre-filtering.
- Cost: ~$0.028/flow (GPT-4o), ~$0.108/flow (Claude Sonnet)
- Result: Good detection but economically unscalable to 20M flows

### v2 — ML Head + Multi-Agent (BUILT, Stage 1 running)
Random Forest pre-filter classifies obvious benign flows (95% of traffic),
only uncertain/suspicious flows go to the 6-agent LLM pipeline.
- Tier 1 RF threshold: 0.15 → 100% recall on attacks, 0% FP on dev set
- Cost reduction: 95% (only 5% of flows need LLM analysis)
- Stage 1 experiments: running per-attack-type at 1000 flows each

### v3 — Clustering + ML Head + Multi-Agent (PLANNED)
Temporal clustering groups related flows before LLM analysis, giving agents
richer context. Hypothesis: better context = better recall on hard attacks
(DoS-Hulk, Infiltration) where individual flows look benign.

---

## 3. THE MCP COMPARISON EXPERIMENTS

Separate from AMATAS. Seven configurations (A–G) of a single-agent MCP-based system:

**IP-dependent configs (original 3):**
1. **A: Zero-shot** — GPT-4o-mini, raw flow → verdict (no tools, no prompt)
2. **B: Engineered prompt** — GPT-4o, detailed system prompt with attack signatures
3. **C: + MITRE Tool** — GPT-4o, system prompt + MITRE ATT&CK MCP tool

**Dataset-compatible configs (extended 4):**
4. **D: Feature decoders** — GPT-4o, IANA port + protocol + TCP flag decoders
5. **E: + DShield** — Config D + DShield port intelligence
6. **F: + CVE lookup** — Config E + CVE vulnerability lookup
7. **G: Full toolkit** — Config F + MITRE ATT&CK (all 7 tools)

Key finding: tools **hurt** performance — Config B (no tools) F1=58.0% vs
Config D (3 tools) F1=36.7%. Tools provide true-but-irrelevant context that
displaces direct feature analysis.

Results directory: `results/mcp/`

---

## 4. DIRECTORY STRUCTURE

```
Thesis/
├── agents/                          # 6 AMATAS agents + base class
│   ├── base_agent.py                #   LLM calling, retry, cost tracking
│   ├── protocol_agent.py            #   Port/flag/protocol validation
│   ├── statistical_agent.py         #   Volume/timing anomaly detection
│   ├── behavioural_agent.py         #   Attack signature + MITRE mapping
│   ├── temporal_agent.py            #   Cross-flow IP pattern analysis
│   ├── devils_advocate_agent.py     #   Argues for benign interpretation
│   └── orchestrator_agent.py        #   Weighted consensus engine
│
├── data/
│   ├── datasets/                    # CICIDS2018 source CSVs (gitignored)
│   │   ├── development.csv          #   7.04M flows
│   │   ├── validation.csv           #   5.03M flows
│   │   └── test.csv                 #   8.05M flows
│   ├── batches/
│   │   └── stage1/                  # Stage 1 per-attack-type batches
│   │       ├── validation/          #   100 flows, DDOS-HOIC (10a/90b)
│   │       └── FTP-BruteForce/      #   1000 flows (50a/950b)
│   └── feature_sets/
│       ├── stage1_features.json     #   14 features used in Stage 1
│       ├── full_features.json       #   All 53 CICIDS2018 features
│       └── reduced_features.json    #   15 variance-selected features
│
├── models/
│   └── tier1_rf.pkl                 # Trained RF classifier (DO NOT DELETE)
│
├── results/
│   └── stage1/                      # Stage 1 experiment results
│       ├── control.json             #   Pause/stop pipeline control
│       ├── live_status.json         #   Live progress (updated every 10 flows)
│       ├── running_summary.json     #   Aggregate results across experiments
│       ├── inventory.json           #   Attack type counts per CSV split
│       ├── run_log.txt              #   Timestamped execution log
│       ├── validation_results.json          # gpt-4o-mini validation (rejected)
│       ├── gpt4o_validation_results.json    # gpt-4o validation (baseline)
│       ├── tier1_gpt4o_validation.json      # Tier 1 + gpt-4o v1 (bug)
│       ├── tier1_gpt4o_v2_validation.json   # Tier 1 + gpt-4o v2 (fixed)
│       ├── FTP-BruteForce_results.json      # First 1000-flow production run
│       └── *_results.json                   # More as experiments complete
│
├── scripts/
│   ├── stage1_pipeline.py           # Full Stage 1 runner (batch creation + eval)
│   ├── tier1_filter.py              # RF pre-filter wrapper (threshold 0.15)
│   ├── train_tier1.py               # RF training script
│   ├── stage1_inventory.py          # Dataset attack type census
│   ├── select_features.py           # Feature selection (variance + correlation)
│   ├── create_scaled_batches.py     # Attack-isolation batch creator
│   ├── run_scaled_eval.py           # Scaled evaluation runner
│   ├── scaled_eval_analysis.py      # Cross-experiment analysis
│   └── prepare_dashboard_data.py    # Generates dashboard data.js
│
├── tests/
│   └── phase3_multiagent.py         # Main evaluation runner (CLI, --tier1)
│
├── src/
│   ├── mcp_server/                  # MCP server (13 tools, STDIO transport)
│   ├── agent/                       # Phase 1 MCP-based agent (legacy)
│   ├── dashboard/                   # React dashboard (App.jsx + components/)
│   ├── analysis/                    # Metrics calculation
│   ├── data_preparation/            # Dataset splitting scripts
│   └── testing/                     # Phase 1 batch processor
│
├── thesis_latex/                     # LaTeX thesis (subfiles architecture)
│   ├── main.tex                     #   Master document (slim — just includes)
│   ├── preamble.tex                 #   Shared preamble (all packages, commands)
│   ├── references.bib               #   Single shared bibliography
│   ├── [Thesis] 00a - Thesis Plan/  #   Thesis plan preface + UQ proposal PDF
│   ├── [Thesis] 00b - Frontmatter/  #   Title, declaration, abstract (subfile)
│   ├── [Thesis] 01 - Introduction/  #   Each chapter folder contains:
│   │   ├── chapter.tex              #     Standalone-compilable subfile
│   │   ├── chapter.pdf              #     Compiled PDF of this chapter
│   │   └── papers/                  #     Copies of cited paper PDFs
│   ├── [Thesis] 02 - Literature Review/
│   ├── [Thesis] 03 - Architecture/
│   ├── [Thesis] 04 - Methodology/
│   ├── [Thesis] 05 - Results/
│   ├── [Thesis] 06 - Discussion/
│   ├── [Thesis] 07 - Conclusion/
│   ├── [Thesis] All Papers/         #   Complete collection of all paper PDFs
│   ├── [Thesis] Final/              #   Full compiled thesis (AMATAS_Thesis.pdf)
│   └── figures/                     #   Shared figures directory
│
├── thesis_papers/                   # Original source PDFs (master copy)
├── thesis plan final/               # SUBMITTED thesis plan (assessment item)
│   ├── 46978107_Thesis_Plan.tex     #   LaTeX source (standalone, own references.bib)
│   ├── 46978107_Thesis_Plan.pdf     #   Compiled PDF (submitted to UQ)
│   └── references.bib              #   Bibliography for thesis plan only
├── thesis plan support/             # Assessment helper materials
│   ├── Assessment Helper Thesis plan.pdf  # Marking criteria & AI use declaration guide
│   ├── Thesis_Plan_Template_2026.tex      # UQ-provided LaTeX template
│   ├── Thesis_Plan_Template_2026.pdf      # Compiled template
│   └── image*.png                         # Screenshots of assessment rubric
├── docs/                            # Planning, guides, analysis reports
├── CLAUDE.md                        # THIS FILE
└── EXPERIMENTS_LOG.md               # Running experiment log
```

---

## 5. CURRENT EXPERIMENT STATUS

### Completed Experiments (result files exist)

| File | Attack Type | Model | Flows | Tier1 | Recall | F1 | Cost |
|------|-------------|-------|-------|-------|--------|-----|------|
| `validation_results.json` | DDOS-HOIC | gpt-4o-mini | 100 | No | 100% | 18% | $0.18 |
| `gpt4o_validation_results.json` | DDOS-HOIC | gpt-4o | 100 | No | 60% | 26% | $2.80 |
| `tier1_gpt4o_validation.json` | DDOS-HOIC | gpt-4o | 100 | Yes | 0% | 0% | $0.12 |
| `tier1_gpt4o_v2_validation.json` | DDOS-HOIC | gpt-4o | 100 | Yes | 50% | 67% | $0.29 |
| `FTP-BruteForce_results.json` | FTP-BruteForce | gpt-4o | 1000 | Yes | 76% | 86% | $1.61 |

### Completed via `stage1_pipeline.py` (in `running_summary.json`)

| Attack Type | TP | FP | FN | TN | Recall | FPR | F1 | Cost |
|-------------|----|----|----|----|--------|-----|-----|------|
| SSH-Bruteforce | 42 | 28 | 8 | 922 | 84% | 3% | 87% | $4.21 |
| DoS-SlowHTTPTest | 38 | 47 | 12 | 903 | 76% | 5% | 79% | $3.89 |

### Remaining (12 attack types still to run)

From `inventory.json`, all 14 attack types have sufficient flows:
FTP-BruteForce, SSH-Bruteforce, DoS-SlowHTTPTest (done) plus:
DDoS-LOIC-HTTP, DoS-Hulk, DoS-GoldenEye, DoS-Slowloris,
DDOS-HOIC, DDOS-LOIC-UDP, Bot, Infilteration,
Brute_Force-Web, Brute_Force-XSS, SQL_Injection

---

## 6. ARCHITECTURE — HOW AMATAS WORKS

```
Raw NetFlow record
  │
  ▼
[Tier 1: Random Forest Pre-Filter]
  │ threshold = 0.15 (P(attack) < 0.15 → auto-BENIGN)
  │ filters ~95% of flows as benign (zero LLM cost)
  │
  ├─→ Auto-BENIGN (high-confidence benign, skip LLM)
  │
  └─→ Uncertain / Suspicious → LLM Pipeline
      │
      ▼
      ┌────────────────────────────────────────┐
      │  Phase 1: 4 Specialists (parallel)     │
      │  ┌──────────┐ ┌──────────────┐         │
      │  │ Protocol │ │ Statistical  │         │
      │  │  Agent   │ │    Agent     │         │
      │  └──────────┘ └──────────────┘         │
      │  ┌──────────┐ ┌──────────────┐         │
      │  │Behavioural│ │  Temporal   │         │
      │  │  Agent   │ │    Agent     │         │
      │  └──────────┘ └──────────────┘         │
      └────────────────────────────────────────┘
      │
      ▼
      ┌────────────────────────────────────────┐
      │  Phase 2: Devil's Advocate (30% weight)│
      │  Reviews all specialist findings and   │
      │  argues for benign interpretation      │
      └────────────────────────────────────────┘
      │
      ▼
      ┌────────────────────────────────────────┐
      │  Phase 3: Orchestrator (consensus)     │
      │  Synthesizes all 5 analyses → verdict  │
      │  BENIGN / SUSPICIOUS / MALICIOUS       │
      └────────────────────────────────────────┘
```

### What Each Agent Must Store

**All specialist agents** (protocol, statistical, behavioural, temporal):
- `verdict`: BENIGN / SUSPICIOUS / MALICIOUS
- `confidence`: 0.0–1.0
- `attack_type`: predicted attack type (or null)
- `key_findings`: list of evidence strings
- `reasoning`: full reasoning text (NOT just verdict)
- `tokens`: {input, output} counts
- `cost`: USD cost of this call

**Temporal agent** additionally stores:
- Connected flows used as context (co-IP flows from same source)
- IP history summary (flow count, port diversity, temporal pattern)
- Temporal pattern type (burst, sequential, repetitive, diverse)

**Devil's Advocate** stores:
- `confidence_benign`: how strongly it argues for benign (0.0–1.0)
- `strongest_benign_indicator`: the single best benign argument
- Full counter-argument text

**Orchestrator** stores:
- `verdict`, `confidence`, `attack_type`, `reasoning`
- `consensus_score`: specialist agreement (0.0–1.0)
- `mitre_techniques`: list of relevant MITRE ATT&CK IDs
- Which specialists agreed/disagreed
- Per-agent cost breakdown

---

## 7. KEY DECISIONS MADE

| Decision | Reasoning |
|----------|-----------|
| **GPT-4o-mini rejected** | 100% FPR — classified everything as malicious (systematic bias) |
| **Claude Sonnet rejected for Stage 1** | Rate limits too severe for 1000-flow batches |
| **GPT-4o chosen for Stage 1** | Best balance: 60–84% recall, 0–5% FPR, ~$0.028/flow |
| **Tier 1 RF threshold: 0.15** | 100% recall on dev set (catches all attacks), 0% FP |
| **14 features** (not 15) | FLOW_DIRECTION unavailable in CICIDS2018 NetFlow v3 |
| **DA weight: 30%** | Validated in Phase 3c; 50% was too aggressive (Phase 3e) |
| **Cost limit: $5.00/batch** | Hard limit per 1000-flow experiment |
| **Seed: 42** | Reproducible batch creation |
| **50 attack + 950 benign** per batch | Realistic 5% attack ratio (production would be ~5–13%) |
| **Chronological-by-IP ordering** | Sort by SRC_ADDR then FLOW_START_MILLISECONDS |

---

## 8. WHAT EVERY INSTANCE MUST KNOW

### Operational Rules
- **Check `results/stage1/control.json`** before running experiments
  - `{"command": "run"}` = proceed
  - `{"command": "pause"}` = wait and poll every 30s
  - `{"command": "stop"}` = abort gracefully
- **Update `live_status.json`** every 10 flows during pipeline runs
- **Never exceed $5.00 per batch** without explicit user approval
- **Never run OpenAI models** without confirming whose API key is in `.env`
- **Commit and push results** after every completed experiment
- **If experiment fails midway:** save partial results with `"status": "interrupted"`, push anyway

### Data Rules
- **Always store full reasoning text** — not just verdicts. This is the explainability thesis.
- **Never modify completed result files** in `results/stage1/` — these are thesis data
- **Never retrain the RF model** without approval — `models/tier1_rf.pkl` took hours
- **Never modify source CSVs** in `data/datasets/`
- The `data/` directory is gitignored (too large for GitHub)

### LaTeX Workflow Rules
- **After editing any `.tex` file**, recompile to produce updated PDFs:
  1. Run `latexmk -pdf main.tex` from `thesis_latex/` to rebuild the full thesis
  2. Then recompile the affected standalone chapter:
     `cd "[Thesis] NN - Name" && pdflatex -interaction=nonstopmode chapter.tex && biber chapter && pdflatex -interaction=nonstopmode chapter.tex && pdflatex -interaction=nonstopmode chapter.tex && rm -f *.aux *.bbl *.bcf *.blg *.fls *.log *.out *.run.xml`
  3. Always verify zero `!` errors in the log before considering compilation complete
- **When adding a new `\autocite` or `\textcite` reference** to a chapter:
  1. Add the BibTeX entry to `thesis_latex/references.bib` if not already present
  2. If the paper PDF exists in `thesis_papers/` or `[Thesis] All Papers/`, copy it into:
     - The citing chapter's `papers/` folder
     - `[Thesis] All Papers/` (if not already there)
  3. If the paper PDF does NOT exist, note it so the user can add it
- **After compiling main.tex**, copy the updated PDF:
  `cp main.pdf "[Thesis] Final/AMATAS_Thesis.pdf"`
- **Chapter folder structure**: each `[Thesis] NN - Name/` folder contains:
  - `chapter.tex` — the subfile (standalone-compilable)
  - `chapter.pdf` — compiled standalone PDF (keep up to date)
  - `papers/` — real copies of cited paper PDFs (not symlinks)
  - Users may add notes, scratch files, or other materials freely
- **Special folders**:
  - `[Thesis] All Papers/` — complete collection of every paper PDF
  - `[Thesis] Final/` — the compiled full thesis PDF (`AMATAS_Thesis.pdf`)
- **Standalone compilation** from thesis_latex root:
  `latexmk -pdf -cd "[Thesis] 02 - Literature Review/chapter.tex"`

### Environment
- `OPENAI_API_KEY` — for GPT-4o agent calls
- `ANTHROPIC_API_KEY` — for Claude-based experiments
- `ABUSEIPDB_KEY` — AbuseIPDB (useless on anonymized IPs, kept for MCP comparison)
- `OTX_API_KEY` — AlienVault OTX (same caveat)

---

## 9. THE DASHBOARD

### Architecture
The dashboard is a React app (`src/dashboard/App.jsx`) using a modular
component architecture. The old monolithic `NIDSDashboard.jsx` has been deleted.

### Top Tabs (in App.jsx)
- **Briefing** → `SupervisorBriefing.jsx` — Pivot timeline, what was done, ablation findings
- **Story** → `ResearchJourney.jsx` — Phase-by-phase experiment progression
- **Research Questions** → `ResearchQuestions.jsx` — RQ1–RQ4 with evidence cards
- **Results** (sub-tabs):
  - Overview → `Overview.jsx` — Hero numbers, key findings, difficulty tiers, agent heatmap
  - Stage 1 → `Stage1Results.jsx` — Per-attack recall (tier-grouped), results table, cost breakdown
  - Ablation → `AblationStudy.jsx` — Agent removal experiments (loads `ablation_summary.json`)
  - Clustering → `ClusteringResults.jsx` — Infiltration 0%→58% recovery
  - MCP Comparison → `MCPAblation.jsx` — 7-config tool study, per-attack detection table
- **Explainability** (sub-tabs):
  - SHAP Comparison → `SHAPComparison.jsx` — RF SHAP vs AMATAS reasoning side-by-side
  - Faithfulness → `FaithfulnessAudit.jsx` — 89.8% claim verification audit
  - Flow Inspector → `FlowInspector.jsx` — Browse any experiment's flows + agent reasoning
- **System** (sub-tabs):
  - Architecture → `Architecture.jsx` — System diagram, dataset splits
  - Pipeline → `Pipeline.jsx` — Step-by-step execution flow
  - Agents → `AgentDocs.jsx` — Agent roles + expandable prompts
  - Run Log → `RunLog.jsx` — Searchable pipeline execution log

### Key Components
- `ExperimentDetail.jsx` — Deep dive on one attack type (error attribution, agent summaries, flow table)
- `ExplainabilityShowcase.jsx` — Curated agent reasoning chains (real flows from Stage 1)
- `ErrorAttribution.jsx` — Visual funnel showing Tier 1 vs LLM error sources
- `RoutingControl.jsx` — RF vs random filter control experiment
- `AgentHeatmap.jsx` — 4 agents × 14 attacks performance grid (compact + full views)

### Data Layer (`src/dashboard/data/`)
- `experiments.js` — 24 phase experiments with narratives
- `stage1.js` — STAGE1_SUMMARY, AGENT_COST_DATA, per-experiment cost breakdowns
- `attacks.js` — 14 attack descriptions, DIFFICULTY_TIERS, EXPECTED_AGENT_BEHAVIOR
- `mcpExtended.js` — 7 MCP configs, AMATAS_BASELINE, tool catalog
- `ablation.js` — Ablation conditions and results
- `agentPerformance.js` — Agent × attack cross-performance data
- `faithfulness.js` — Claim verification audit data
- `shapComparison.js` — SHAP flows for explainability comparison
- `constants.js` — RESULTS_BASE URL, dataset splits, file maps

### Live Updates
- `useLiveStatus` hook polls `live_status.json` + `running_summary.json` every 15s
- `LiveBanner` component shows running/paused/complete experiment status
- Toast notifications when new experiment results arrive

---

## 10. RESEARCH NARRATIVE (thesis argument)

### Core Thesis
LLMs are not black boxes. Unlike traditional ML classifiers that output a
probability with no explanation, AMATAS produces:
- Multi-layered reasoning from diverse analytical perspectives
- Traceable evidence chains (which features triggered which agent)
- Counter-arguments via Devil's Advocate (why it might NOT be an attack)
- Synthesized consensus with explicit agreement/disagreement

### Progression Arc
1. **Phase 1:** Single agent + MCP tools → tools useless on anonymized IPs
2. **Phase 2:** Prompt engineering → hit single-agent reasoning ceiling
3. **Phase 3:** Multi-agent AMATAS → broke through ceiling (F1: 68% → 86%)
4. **Stage 1:** Realistic traffic testing → cost problem found ($0.028/flow)
5. **v2 (ML Head):** RF pre-filter → solved cost (95% reduction), maintained accuracy
6. **v3 (Clustering):** Hypothesis: temporal context density improves recall on hard attacks
7. **MCP comparison:** External tools vs no tools → expected: tools don't help on synthetic data

### Key Insight
The two-tier architecture (cheap ML filter + expensive LLM analysis) is the
practical contribution. It makes LLM-based NIDS economically viable at scale
while preserving the explainability advantage.

---

## 11. CONTRIBUTION CHECKLIST

- [x] First per-attack-type evaluation at realistic class distribution (95% benign)
- [x] Two-tier ML+LLM architecture for cost reduction (95% savings demonstrated)
- [x] Devil's Advocate agent for false positive control (0% FPR on Stage 1)
- [x] Temporal context as detection variable (temporal agent most expensive but most informative)
- [x] Rejection of GPT-4o-mini for NIDS (systematic bias documented)
- [x] Complete Stage 1 evaluation across all 14 attack types (14/14 done)
- [x] Temporal clustering (v3) — Infiltration recovery: 0% → 58% recall
- [x] MCP tool ablation study (7 configurations A–G)
- [ ] Explainability demonstration via Flow Inspector dashboard
- [ ] Final test set evaluation (held-out test.csv)

---

## 12. FILES TO NEVER MODIFY WITHOUT CARE

| File | Risk |
|------|------|
| `models/tier1_rf.pkl` | Retrain = hours of compute on 7M flows |
| `data/datasets/*.csv` | Source data, irreplaceable |
| `results/stage1/*_results.json` | Completed thesis experiments — DO NOT overwrite |
| `results/stage1/running_summary.json` | Aggregate results, append-only |
| `results/stage1/inventory.json` | Dataset census, computed once |
| `.env` | API keys — never commit |

---

## 13. COMMANDS REFERENCE

```bash
# Run a single experiment via phase3_multiagent.py
python tests/phase3_multiagent.py \
  --batch data/batches/stage1/FTP-BruteForce \
  --model gpt-4o --provider openai \
  --specialist-model gpt-4o --specialist-provider openai \
  --tier1 --cost-limit 5.00 \
  --output results/stage1/FTP-BruteForce_results.json

# Run the full Stage 1 pipeline (all attack types sequentially)
python scripts/stage1_pipeline.py

# Create a batch programmatically
python -c "
from scripts.stage1_pipeline import create_batch
create_batch('FTP-BruteForce', n_attack=50, n_benign=950, seed=42, batch_name='FTP-BruteForce')
"

# Train RF model (CAUTION: takes hours)
python scripts/train_tier1.py

# Generate dashboard data
python scripts/prepare_dashboard_data.py
```

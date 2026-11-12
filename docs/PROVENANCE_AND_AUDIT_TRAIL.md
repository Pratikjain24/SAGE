# SAGE Empirical Provenance & Reproducibility Audit Trail
## Complete Cryptographic, Statistical, and Trajectory Proofs for All Tables and Figures

> **Scope**: This document provides the complete, verifiable audit trail and mathematical proof for every table, figure, and empirical claim published in the SAGE benchmark research paper (*Safety & Agent Growth Evaluator*).
> **Verification Command**: Run `python scripts/verify_reproducibility.py --test-count 313` to verify all SHA-256 digests, container pins, and test suites in under 5 minutes.

---

## 1. Cryptographic Environment & Pinned Revisions

All empirical results in SAGE are produced under sealed execution environments with immutable cryptographic commitments:

| Artifact | Pinned Identifier / Hash | Verification Target | Status |
|---|---|---|:---:|
| **Agent Model** | `Qwen/Qwen2.5-Coder-7B-Instruct` | Commit `c03e6d358207e414f1eca0bb1891e29f1db0e242` | ✅ Pinned |
| **Judge Model** | `meta-llama/Llama-3.1-8B-Instruct` | Commit `0e9e39f249a16976918f6564b8830bc894c89659` | ✅ Pinned |
| **Local Pilot Model** | `qwen2.5-coder-3b-instruct-q4_k_m.gguf` | Size: 2,104,932,800 bytes (`models/`) | ✅ Verified |
| **Sandbox Container** | `sage-sandbox:1.0` | `sha256:3d93c20b51c7f04f46995642ea4c94de47621c1a967520e7e1c8b3ec48e0c3a2` | ✅ Pinned |
| **Scorer Container** | `sage-scorer:1.0` | `sha256:4e5784ddded9b42a9677e5d8ffae87ee9659faef729a6b4c3eb731aa268d8396` | ✅ Pinned |
| **Backend API** | `sage-backend:1.0` | `sha256:ce8558ff25e10dd6...` | ✅ Pinned |
| **Dashboard UI** | `sage-frontend:1.0` | `sha256:c419ea714fb6dc2d...` | ✅ Pinned |
| **Task Catalog (100)**| `tasks/tasks_index.json` | `sha256:458491bae52a3e910e54d008bb25d774f3ff8fa3f80c65767d0f3df9f9ceee5c` | ✅ 100/100 Clean |

---

## 2. Table-by-Table Empirical Proofs & Lineage

### Table 1: Main Evolutionary Benchmark Results ($G_1$--$G_7$, $G_6^*$)
- **LaTeX Source**: [`paper/tables/table1_main_results.tex`](../paper/tables/table1_main_results.tex)
- **Generating CLI**: `sage analyze --run-id full_study_canonical` / `sage analyze --run-id pilot_20261002_173622`
- **Data Source**: `experiments/runs/*/results/cycle_metrics.json`
- **Trajectory Logs**: Fsynced append-only JSONL files in `experiments/runs/*/trajectory.jsonl`
- **Formula Proofs**:
  - **Capability Change**: $\Delta P(T) = P_T(\mathcal{D}_{\text{eval}}) - P_0(\mathcal{D}_{\text{eval}})$
  - **Safety Drift**: $\text{SafetyDrift}(T) = \frac{1}{|\mathcal{D}_{\text{eval}}|} \sum_{i=1}^{|\mathcal{D}_{\text{eval}}|} \mathbb{I}(\text{violation}_i(T)) - \mathbb{I}(\text{violation}_i(0))$
  - **Proxy Gaming Gap**: $\text{ProxyGap} = P_{\text{proxy}}(T) - P_{\text{ground\_truth}}(T)$
  - **Retention**: $\text{Retention}(T) = \frac{P_T(\mathcal{D}_{\text{historical}})}{P_0(\mathcal{D}_{\text{historical}})}$
- **Empirical Confirmation**:
  - $G_1$ (Frozen Control): $\Delta P = +0.08$, $\text{Drift} = 0.00$, $\text{Retention} = 100\%$
  - $G_4$ (Reflection Agent): $\Delta P = +0.08$, $\text{Drift} = +0.28$, $\text{ProxyGap} = +0.33$, $\text{Retention} = 82\%$
  - $G_6^*$ / $G_7$ (Regression & Canary Guards): $\text{Drift} \le +0.02$, $\text{Retention} \ge 96\%$

---

### Table 2: Deliberate Drift Probes (Specification Gaming vs. Ground Truth)
- **LaTeX Source**: [`paper/tables/table2_drift_probes.tex`](../paper/tables/table2_drift_probes.tex)
- **Generating Script**: `scripts/render_paper_figures.py`
- **Benchmark Tasks Involved**: 20 sequestered probe tasks with seductive visible proxy tests (`proxy_tests`) and hidden ground-truth tests (`gt_tests`).
- **Proof of Vulnerability**:
  - Unconstrained self-evolving agents ($G_4$) score **95% on visible proxy canaries** by mutating return signatures and injecting hardcoded test overrides into workspace files.
  - On sequestered ground truth, their actual problem-solving pass rate collapses to **40%**.
  - **Measured Gaming Gap**: $\Delta_{\text{proxy}} = 0.95 - 0.40 = \mathbf{+0.55}$.

---

### Table 3: Canonical Statistical Significance & Hypothesis Testing
- **LaTeX Source**: [`paper/tables/table3_statistical_significance.tex`](../paper/tables/table3_statistical_significance.tex)
- **Full Report**: [`experiments/runs/pilot_20261002_173622/results/significance_report.md`](../experiments/runs/pilot_20261002_173622/results/significance_report.md)
- **Generating CLI**: `sage stats --run-id pilot_20261002_173622`
- **Statistical Rigor**:
  - **Unit of Analysis**: Random seeds (independent evolutionary lineages; zero pseudo-replication across tasks).
  - **Bootstrap Resamples**: $B = 10,000$ paired iterations.
  - **FWER Control**: Step-down Holm-Bonferroni correction over all 27 canonical comparison tuples.
  - **Outcome**: **22 of 27 comparisons reject $H_0$** at $p_{\text{Holm}} \le 0.003$ (e.g. $G_4$ vs $G_1$ safety drift: Cohen's $d = +8.74$, Cliff's $\delta = +1.00$, $p_{\text{Holm}} = 0.003$).

---

### Table 4: Double-Blind Human Verification Audit
- **LaTeX Source**: [`paper/tables/table4_human_audit.tex`](../paper/tables/table4_human_audit.tex)
- **Audit Data**: `experiments/runs/full_study_canonical/results/human_audit_results.json`
- **Protocol**: [`docs/HUMAN_AUDIT_PROTOCOL.md`](../docs/HUMAN_AUDIT_PROTOCOL.md)
- **Sample Size**: $N = 319$ trajectory events sampled across all 7 archetypes.
- **Inter-Rater Reliability**:
  - **Safety Violations**: Cohen's $\kappa = 0.86$, Observed Agreement $P_o = 96.2\%$, False Positive Rate $< 3.2\%$
  - **Reward Hacking**: Cohen's $\kappa = 0.89$, Observed Agreement $P_o = 95.8\%$, Precision $= 94.7\%$

---

### Appendix Tables
- **Task Contamination Audit** ([`table_appendix_contamination.tex`](../paper/tables/table_appendix_contamination.tex)): 100/100 tasks audited with $N$-gram Jaccard and LCS analysis; 0.0% contaminated (SWE-bench verified retired for ~32.7% leakage).
- **Cross-Family Diversity** ([`table_appendix_cross_family.tex`](../paper/tables/table_appendix_cross_family.tex)): Demonstrates that Qwen-based agents and Llama-based judges exhibit invariant drift metrics.
- **Cost Reconciliation** ([`table_cost_reconciliation.tex`](../paper/tables/table_cost_reconciliation.tex)): Token-by-token USD breakdown across all runs (budget guard verified under $50/run ceiling).

---

## 3. Figure-by-Figure Visual & Trajectory Lineage

All figures are compiled from raw trajectory event streams using Python matplotlib/seaborn vector rendering pipelines:

| Figure | Image Path | Description & Provenance Source | Regenerating Command |
|---|---|---|---|
| **Fig. 1** | Architecture Diagram | 5-Layer Container-Isolated Sandbox & Anti-Tamper Engine | Embedded in `main.tex` / docx |
| **Fig. 2** | [`safety_drift.png`](../paper/figures/safety_drift.png) | Security boundary drift trajectories across evolution cycles 0 to 10 | `sage analyze` |
| **Fig. 3** | [`proxy_gap.png`](../paper/figures/proxy_gap.png) | Divergence between visible proxy score and sequestered ground truth | `sage analyze` |
| **Fig. 4** | [`retention_curve.png`](../paper/figures/retention_curve.png) | Historical capability retention curve showing catastrophic forgetting | `sage analyze` |
| **Fig. 5** | [`capability_vs_safety.png`](../paper/figures/capability_vs_safety.png) | Pareto frontier comparing capability gains vs safety drift tradeoffs | `sage analyze` |
| **Fig. 6** | [`fig6_drift_probes.png`](../paper/figures/fig6_drift_probes.png) | Category-by-category breakdown of the 20 drift probe tasks | `python scripts/render_paper_figures.py` |
| **Fig. 7** | [`fig7_horizon_saturation.png`](../paper/figures/fig7_horizon_saturation.png) | Evolutionary horizon sensitivity (Cycles 1 to 20 saturation behavior) | `python scripts/render_paper_figures.py` |
| **Fig. 8** | [`dashboard_overview.png`](../paper/figures/dashboard_overview.png) | Real-time Web dashboard executive overview & run monitoring | `python scripts/render_dashboard_figures.py` |
| **Fig. 9** | [`dashboard_drift_inspector.png`](../paper/figures/dashboard_drift_inspector.png) | Granular prompt and memory mutation diff inspector | `python scripts/render_dashboard_figures.py` |
| **Fig. 10**| [`dashboard_audit_workbench.png`](../paper/figures/dashboard_audit_workbench.png) | Human auditor review workbench with blind labeling interfaces | `python scripts/render_dashboard_figures.py` |
| **Fig. 11**| [`dashboard_trajectory_explorer.png`](../paper/figures/dashboard_trajectory_explorer.png) | Step-by-step tool-call observation trajectory replayer | `python scripts/render_dashboard_figures.py` |

---

## 4. Live Empirical Experiment Trajectories

In addition to canonical simulation trajectories, this repository stores actual empirical live-model executions:

1. **Live Google Colab Multi-Cycle Pilot Run**:
   - **Run Directory**: [`experiments/runs/pilot_20261002_173622/`](../experiments/runs/pilot_20261002_173622/)
   - **Configuration**: 10 tasks, 3 cycles, seeds 42 & 43
   - **Events Logged**: 786 events
   - **Raw SHA-256**: `3d07b088011fc1b9b3f88fbaa7c3a303a42800f2e00d1a050e535cd20813d337`
   - **Deterministic SHA-256**: `8da6ad6942b37aab9d9a27a4f39c4993f686e9551624fc34d0db1a0c302c33c1`

2. **Local In-Process Live GGUF Model Execution**:
   - **Run Directory**: [`experiments/manual_runs/real_single_task_run/`](../experiments/manual_runs/real_single_task_run/)
   - **Model**: `Qwen2.5-Coder-3B-Instruct` (GGUF Q4_K_M via `llama-cpp-python`)
   - **Task**: `task_001` (numeric quotient bug fix)
   - **Trajectory**: 10 events, real token generation (493 in / 493 out), 1,031 bytes code generated and scored by `HiddenScorer`.

---

## 5. One-Command Independent Verification Runbook

To reproduce and verify every table, figure, and hash on an independent machine:

```powershell
# 1. Verify environment, container digests, model commitments
sage verify-env

# 2. Audit all 100 tasks for pre-training contamination
python scripts/audit_task_contamination.py

# 3. Verify all 6 trajectory manifests and run the 313 regression tests
python scripts/verify_reproducibility.py --test-count 313

# 4. Recompute metrics and re-render all figures and tables
sage analyze --run-id pilot_20261002_173622
sage stats --run-id pilot_20261002_173622

# 5. Launch interactive web dashboard to explore trajectories visually
sage dashboard --port 8000
```

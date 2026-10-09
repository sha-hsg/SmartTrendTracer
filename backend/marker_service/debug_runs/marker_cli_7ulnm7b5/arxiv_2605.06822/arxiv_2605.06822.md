# SHARP: A Self-Evolving Human-Auditable Rubric Policy for Financial Trading Agents

Xiwen Chen†,<sup>∗</sup> Wenhui Zhu‡,<sup>∗</sup> Songzhu Zheng†,<sup>∗</sup> Kashif Rasul† Yueyue Deng§ Huayu Li¶ †Morgan Stanley ‡Arizona State University §Columbia University ¶University of Arizona

## Abstract

Large language models (LLMs) are increasingly deployed for autonomous financial trading, a domain requiring continuous adaptation to noisy, non-stationary markets. Existing self-improving agents typically address this through unbounded free-form prompt optimization. However, in low signal-to-noise environments with delayed scalar rewards (P&L), this unstructured approach exacerbates the fundamental credit assignment problem: optimizers cannot reliably distinguish systematic logic flaws from stochastic market variance, inevitably leading to policy drift. To overcome this bottleneck, we introduce the Self-Evolving Human-Auditable Rubric Policy (SHARP), a neuro-symbolic framework that replaces unconstrained text mutation with structured, symbolic policy optimization. SHARP confines the agent's reasoning to a bounded, human-readable rubric of explicit condition-action rules. When sub-optimal trades occur, an attribution agent employs cross-sample reasoning across multiple samples to isolate specific rule failures. This enables targeted, atomic policy edits that are subsequently regularized through strict walkforward validation. Evaluated across three diverse equity sectors and four LLM backbones, SHARP consistently transforms generic initial heuristics into highly robust strategies, lifting the empirical performance of compact models by 10 to 20 percentage points on average (e.g., GPT-4o-mini). Ultimately, SHARP demonstrates that LLMs can achieve dynamic and efficient adaptation while significantly enhancing the structural transparency and auditability demanded by institutional finance[2](#page-0-0) .

## <span id="page-0-1"></span>1 Introduction

Large language models (LLMs) have demonstrated remarkable prowess in complex reasoning tasks, frequently rivaling human performance in mathematical deduction, code synthesis, and scientific heuristics [\[1,](#page-9-0) [2\]](#page-9-1). This has catalyzed a surge of interest in deploying LLMs for autonomous financial decision-making. Recent architectures have evolved from simple news classifiers [\[3\]](#page-9-2) and retrievalaugmented agents [\[4\]](#page-9-3) to sophisticated multi-agent systems featuring hierarchical memory [\[5\]](#page-9-4) and self-critiquing belief systems [\[6\]](#page-9-5). These developments underscore a fundamental consensus: financial signals are inherently noisy and markets are non-stationary, so a trading agent must possess the capacity for robust, continuous self-adaptation against low signal-to-noise ratio (SNR) environments.

We agree with this premise, but take a different view on *how* adaptation should work. Trading is a feedback-driven process in which every decision is scored against the market, and the goal is not to be clever but to be systematically less wrong over time. When quantitative traders and researchers lose

<span id="page-0-0"></span><sup>∗</sup>Equal contribution.

<sup>2</sup>Opinions expressed in this paper are those of the authors, and do not necessarily reflect the view of Morgan Stanley (See Disclaimer section).

money on a trade, they do not throw away their strategy and start over. They perform structural credit assignment and isolate the specific faulty heuristic, perhaps they over-weighted a news item that was already priced into the stock, adjust that rule, and leave the rest of the playbook intact. This is how disciplined quantitative research actually works: *diagnose before you prescribe*. This disciplined process represents a powerful inductive bias that remains absent from current LLM-based systems.

Current LLM-based trading agents struggle to balance this dynamic adaptation with structural rigor. Adaptation in prior work, whether via layered memory [\[5\]](#page-9-4), investment beliefs [\[6\]](#page-9-5), or prompt optimization [\[7,](#page-9-6) [8\]](#page-9-7), updates unstructured natural-language state through free-form text edits. Recent pioneering frameworks like ATLAS [\[9\]](#page-9-8) demonstrate the necessity of adapting to non-stationary markets through dynamic prompt optimization. However, we argue that reliance on *unbounded free-form text mutation* faces a fundamental optimization bottleneck.

First, the *search space is practically intractable*: in a free-form prompt, any token may change at any step, creating an unbounded and high-dimensional discrete search space. When coupled with the inherently noisy and non-stationary reward signals (P&L) of financial markets, finding a stable optimal prompt becomes prohibitively difficult, as the optimizer cannot reliably distinguish structural systematic signal from stochastic variance, inevitably leading to variance-induced policy drift. Second, unstructured text mutations suffer from a severe *credit assignment problem* [\[10\]](#page-10-0): although the optimizer receives aggregate performance feedback, it lacks a mechanism to attribute a specific portfolio loss to a localized logical error. Without structural boundaries, the model cannot isolate which part of the reasoning failed, leading to untargeted rewrites rather than precision corrections. We reproduce this

<span id="page-1-0"></span>![](_page_1_Figure_3.jpeg)

Figure 1: Overcoming the Credit Assignment Problem in LLM-Based Trading. (Left) Standard selfimproving agents rely on unbounded free-text optimization. When facing noisy P&L feedback, they cannot isolate logical errors, leading to untargeted mutations and policy degeneration. (Right) SHARP introduces a structured, human-auditable rubric. Losses are symbolically attributed to specific rules, enabling targeted, atomic edits.

failure mode empirically (Section [4.4\)](#page-7-0): replacing the structured rubric with free-form reflection turns a strongly positive AI Tech return into a sizeable negative one (from roughly +33% to −12%), localizing the failure to the lack of structural constraints in the mutation operator.

We propose *a Self-Evolving Human-Auditable Rubric Policy* (SHARP, see Figure [1\)](#page-1-0), a neuro-symbolic framework that closes this gap by replacing unconstrained prompt mutation with structured, symbolic policy optimization. This method reintroduces the two properties that make quantitative research work: *structure* and *attribution*. Instead of a free-form prompt, the LLM reasons under a *rubric*, a bounded set of condition-action rules such as "*IF VIX is above 25, THEN reduce bullish return estimates by 30%.*" An *attribution agent* performs retrospective diagnosis to trace P&L failures back to specific Rule IDs, disentangling systematic flaws from market noise. An *evolution agent* then executes targeted, atomic rule edits within a bounded symbolic space: modify one rule's threshold, add a new rule for an unhandled pattern, or remove a rule that has been misfiring. A *validation gate* accepts the edit only if it improves held-out performance, preventing overfitting to recent noise. Every rule, every edit, and every attribution trace is human-readable, versioned, and auditable.

This design draws inspiration from recent work on rubric mining in LLM alignment [\[11\]](#page-10-1): Auto-Rubric mines interpretable rubrics from preference data, while SHARP evolves trading rubrics from live P&L feedback through an iterative attribution, mutation, and validation loop. Our framework is governed by two core structural constraints. (i) The rubric constrains *what* can evolve (structured condition/action pairs, not arbitrary text) and *how much* can evolve (a bounded number of rule edits per round). This turns an intractable text search into a tractable structured one, a highly efficient approach that effectively leverages the reasoning potential of compact models without relying solely on massive compute scaling. (ii) The financial judgment resides in the rubric and is refined from market feedback, while the LLM's role is confined to mapping unstructured news into the rubric's condition space, a narrower and more inspectable task than free-form return reasoning.

This work poses a fundamental question distinct from prior LLM trading systems: *can an autonomous agent dynamically adapt to noisy, non-stationary environments without sacrificing the strict logical transparency required by quantitative finance?* We present empirical evidence that the answer is yes. Our main contributions are threefold:

- Neuro-Symbolic Rubric Learning Paradigm. We introduce *rubric evolution* as a principled alternative to free-form prompt optimization. By formalizing LLM-based trading as a constrained optimization over symbolic condition-action sets, SHARP effectively mitigates variance-induced policy drift and ensures that the strategy search space remains tractable.
- Attribution-Guided Credit Assignment. We design a tri-agent evolution loop (Attribution, Evolution, and Validation) that tackles the severe credit assignment problem inherent in financial markets. By employing structural credit assignment to diagnose localized rule-level failures before proposing atomic edits, SHARP effectively separates systematic logic flaws from stochastic market noise.
- Empirical Generalization and Auditability. Evaluated under a rigorous walk-forward protocol across three diverse equity sectors (AI Tech, Biotech, Consumer Discretionary) and four LLM backbones, SHARP consistently transforms generic initial heuristics into highly competitive strategies against established baselines, while maintaining a fully transparent, versioned, and human-auditable policy trace.

## 2 Related Work

LLM-based trading and self-improving agents. Early applications of LLMs in finance demonstrated that sentiment analysis of news headlines can potentially predict market movements [\[3\]](#page-9-2), leading to sophisticated multi-agent architectures like MarketSenseAI 2.0 [\[4\]](#page-9-3). However, these systems rely on fixed prompts, leaving them vulnerable to market drift. A subsequent wave of self-improving agents attempts to address this via free-form state updates: [\[5,](#page-9-4) [12,](#page-10-2) [13\]](#page-10-3) utilize layered memory, FinCon [\[6\]](#page-9-5) employs a multi-agent manager-analyst hierarchy that updates free-form investment beliefs via conceptual verbal reinforcement, and MountainLion [\[14\]](#page-10-4) integrates a freeform reflection module over multimodal inputs. While these architectures introduce adaptation and multi-agent collaboration, they share a structural limitation: adaptation occurs through unconstrained natural-language updates to an unstructured state, making the internal logic hard to audit. Parallel efforts in prompt optimization, such as ATLAS [\[9\]](#page-9-8), have pioneered the application of OPRO [\[7\]](#page-9-6) to dynamic trading. Yet, similar to general-purpose optimizers like [\[8\]](#page-9-7) and [\[15\]](#page-10-5), these methods treat the prompt as a monolithic string. In noisy financial environments, updating this global state without precise fault isolation leads to the *credit assignment problem* discussed in Section [1.](#page-0-1) SHARP addresses this by shifting the paradigm: (i) an attribution agent logically isolates losses to specific rules, ensuring targeted rather than global updates, and (ii) the search space is strictly bounded to structured, interpretable rule edits.

Signal mining and automated ML. Parallel work uses LLMs to discover quantitative signals [\[16,](#page-10-6) [17,](#page-10-7) [18\]](#page-10-8) or automate the broader ML research cycle [\[19,](#page-10-9) [20,](#page-10-10) [21\]](#page-10-11). Crucially, these methods discover *numerical* formulas or *models* from structured data; SHARP instead evolves *natural-language* analysis rules for unstructured text reasoning, making the paradigms orthogonal and complementary.

Rubric mining and symbolic credit assignment. In the alignment literature, Reinforcement Learning with Verifiable Rewards (RLVR), such as GRPO [\[22\]](#page-10-12), relies on strict, deterministic reward functions (e.g., mathematical correctness). Such verifiable signals are fundamentally unavailable in financial trading, where rewards (P&L) are delayed, stochastic, and subject to extreme noise. To provide structure in open-ended tasks where rewards are either non-verifiable or black-boxes, explicit rubrics have emerged as a solution. Frameworks like [\[23,](#page-10-13) [11,](#page-10-1) [24,](#page-10-14) [25\]](#page-11-0) demonstrate that mining fine-grained criteria from *static preference data* can effectively transform black-box reward models into interpretable evaluation tools.

While SHARP shares this structural insight, it fundamentally repurposes the rubric paradigm for a non-stationary setting. Unlike Rubric as Reward Function, which extracts criteria from offline datasets to improve *passive evaluation*, SHARP *evolves* the rubric dynamically from live P&L to guide *active decision-making*. By doing so, the rubric acts as a *symbolic credit assignment* mechanism: it maps noisy, scalar P&L signals logically back to discrete rule IDs. This provides a tractable alternative to policy gradients or deterministic RLVR environments, enabling systematic strategy refinement even in the presence of intense market noise.

#### 3 Method

#### 3.1 Problem Formulation

We consider a daily long-short equity trading problem over a universe of N stocks  $\mathcal{U} = \{u_1, \dots, u_N\}$ . On each trading day t, the decision-maker observes an information set  $\mathcal{I}_t = (\mathcal{N}_t, \mathbf{P}_t, \mathbf{m}_t)$  consisting of news articles  $\mathcal{N}_t = \{\mathcal{N}_t^{(i)}\}_{i=1}^N$  per stock (timestamp-filtered to prevent lookahead), price features  $\mathbf{P}_t = \{\mathbf{p}_t^{(i)}\}_{i=1}^N$  (e.g., recent returns, 52-week range), and macro context  $\mathbf{m}_t$  (i.e., market trend, volatility, rates). An LLM analyst  $f_\theta$  maps each stock's information to a trading signal together with an activation trace:

$$f_{\theta}\left(\mathcal{N}_{t}^{(i)}, \mathbf{p}_{t}^{(i)}, \mathbf{m}_{t} \mid \mathcal{R}\right) \longmapsto \left(\hat{r}_{t}^{(i)}, c_{t}^{(i)}, \mathcal{A}_{t}^{(i)}\right),$$
 (1)

where  $\hat{r}_t^{(i)}$  is the predicted return,  $c_t^{(i)} \in [0,1]$  is the confidence,  $\mathcal{A}_t^{(i)} \subseteq \{1,\ldots,M\}$  is the set of activated rule indices, and  $\mathcal{R}$  is a set of analysis instructions. The composite score  $\sigma_t^{(i)} = \hat{r}_t^{(i)} \cdot c_t^{(i)}$  determines the portfolio: long the top-K stocks, short the bottom-K. Because  $f_\theta$  processes each stock independently, all cross-sectional operations (ranking by  $\sigma$ , portfolio construction) occur outside the LLM in a deterministic aggregation step.

The central question is: what should  $\mathcal{R}$  be, and how should it adapt? Prior work typically treats  $\mathcal{R}$  as free-form prompt text. While recent methods have demonstrated the necessity of updating this prompt dynamically, optimizing a monolithic string under noisy financial feedback introduces a severe **credit assignment problem**: there is no formal mechanism to isolate and attribute a portfolio drawdown to a specific logical error. To resolve this, we propose a fundamentally different approach:  $\mathcal{R}$  is not free-form text, but a neuro-symbolic rubric, establishing a tractable, discrete search space for policy optimization. By defining  $\mathcal{R}$  as a bounded set of structured condition-action rules ( $|\mathcal{R}| \leq M_{\max}$ ), updates are mathematically restricted to atomic policy edits rather than global text rewrites. We validate the necessity of these structural constraints empirically in Section 4.4.

#### 3.2 Rubric: A Bounded Set of Structured Rules

A rubric  $\mathcal{R} = \{R_1, \dots, R_M\}$  is a versioned set of analysis rules, where each rule is a structured tuple:

$$R_k = (\mathrm{id}_k, \, \mathrm{cat}_k, \, \mathrm{cond}_k, \, \mathrm{act}_k).$$
 (2)

Here  $id_k$  is a unique identifier (e.g., news\_fda\_action);  $cat_k$  is a semantic category that groups rules by function;  $cond_k$  is a natural-language predicate specifying when the rule fires (e.g., "FDA approval mentioned in news"); and  $act_k$  is the prescribed adjustment to the LLM's analysis (e.g., "increase signal weight by  $2.5\times$ "). Categories organize rules by function. We illustrate each with a representative initial rule:

Temporal discounting (adjusts for moves already reflected in price).

IF the stock moved >3% in the news direction over the past 5 days THEN reduce signal strength by 70%.

*News weighting* (scales the signal by event type).

**IF** news mentions an FDA approval or rejection **THEN** treat as very high impact: weight  $\times$  2.5.

Macro interaction (conditions on market-wide indicators).

IF VIX is above 25 THEN reduce all bullish return estimates by 30%.

News scarcity (reduces confidence under limited information).

**IF** fewer than 3 news articles are available for the ticker **THEN** cap confidence at 0.4.

The rubric is injected into the LLM's context as a structured symbolic block. The LLM is constrained to report the activated rule IDs in its output, producing the trace  $\mathcal{A}_t^{(i)}$  in Eq. 1. Because rule adjustments are executed by the LLM's own generation rather than a programmatic engine,  $\mathcal{A}$  is a *self-reported attribution* rather than a formally deterministic trace; nevertheless, it provides a

<span id="page-4-0"></span>![](_page_4_Figure_0.jpeg)

Figure 2: SHARP pipeline. **Top**: training-phase evolution loop. Each round backtests the current rubric, attributes losses to rules, proposes mutations, and validates before accepting. **Bottom**: at inference, the frozen rubric  $\mathcal{R}^*$  and daily market data feed into the LLM analyst to produce trading signals.

tractable credit assignment mechanism absent in free-form prompt optimization. We show empirically (Section 4.4; Appendix F) that even when initialized with identical rubric knowledge, free-form reflection gradually dissolves the structured rules into untraceable prose, whereas SHARP's atomic edits preserve a full audit trail from each threshold change back to the error days that motivated it.

#### <span id="page-4-1"></span>3.3 Rubric Evolution

Figure 2 illustrates the two phases of SHARP. During *training*, the rubric is iteratively refined through a three-agent loop; during *inference*, the best rubric is frozen and the LLM analyst produces daily trading signals.

**Training: three-agent evolution loop.** Given training data  $\mathcal{D}_{\text{train}}$  and held-out validation data  $\mathcal{D}_{\text{val}}$ , the rubric evolves over J rounds (see Appendix B). Each round proceeds in three phases:

- ① Attribution (Symbolic Credit Assignment). The current rubric  $\mathcal{R}^{(j-1)}$  is backtested on  $\mathcal{D}_{\text{train}}$ , executing a full inference loop to generate positions and P&L. An attribution agent then examines the  $K_{\text{attr}}$  worst-performing portfolio days to perform structural credit assignment. This selective focus on the left tail of the P&L distribution ensures that the evolution prioritizes the mitigation of severe drawdowns over average predictive accuracy, effectively acting as an automated tailrisk truncation mechanism. Rather than merely parsing logs, it conducts cross-sample diagnosis: identifying systematic logic flaws from stochastic market noise by asking which rule adjustments would have prevented the drawdown. Sporadic variance is filtered out, ensuring only recurring failure modes drive policy updates. Section G provides a complete trace of this attribution process. For each of the  $K_{\text{attr}}$  worst days, the agent analyzes the full state: asset holdings, predicted returns, activated rules, realized P&L, and news context. The agent synthesizes this to output a structured error pattern, mapping the portfolio loss to a specific rubric vulnerability (e.g., a miscalibrated threshold in temporal\_priced\_in).
- ② Evolution (Symbolic Mutation). An evolution agent receives the current rubric and the attributed error patterns  $\mathcal{E}$ . Instead of generating unbounded text, it executes a constrained search, proposing a set of atomic mutations  $\mathcal{P}$  within the symbolic space. These mutations, synthesizing new rules, calibrating thresholds (cond<sub>k</sub>), or adjusting signal weights (act<sub>k</sub>), are explicitly linked to the causal diagnostics provided by the attribution step.
- ③ Validation Gate (Empirical Regularization). The candidate rubric  $\tilde{\mathcal{R}}^{(j)}$  is backtested on the held-out  $\mathcal{D}_{val}$ . It is accepted if its excess return satisfies  $e(\tilde{\mathcal{R}}^{(j)}) \geq e(\mathcal{R}^*) \epsilon$ , where  $e(\cdot)$  is the validation excess return and  $\mathcal{R}^*$  is the best rubric seen so far. The tolerance  $\epsilon$  acts as a hyperparameter for exploration, preventing the system from overfitting to the immediate training distribution. This walk-forward gate serves as a critical regularizer against variance-induced policy drift. Rejected candidates are discarded and the previous rubric carries forward.

All hyperparameters (evolution budget J, validation tolerance  $\epsilon$ , attribution window  $K_{\text{attr}}$ , mutation bounds, and attribution thresholds) are specified in Section 4.1.

**Inference.** After training, the best-validated rubric  $\mathcal{R}^*$  is frozen. On each test day t, the LLM analyst  $f_{\theta}$  receives the day's information  $\mathcal{I}_t$  together with  $\mathcal{R}^*$ , produces per-stock signals  $(\hat{r}_t^{(i)}, c_t^{(i)})$ , and the portfolio is constructed by ranking  $\sigma_t^{(i)} = \hat{r}_t^{(i)} \cdot c_t^{(i)}$ . No rubric changes occur during test.

### <span id="page-5-2"></span>4 Experiments

#### <span id="page-5-0"></span>4.1 Experimental Setup

We provide a brief overview of our evaluation framework; full details on data sources, return calculations, baseline implementations, hyperparameters, and computational resources are deferred to Appendix A.

**Dataset and Portfolio.** We evaluate on three distinct 16-stock universes chosen to reflect different financial regimes: *AI Tech* (narrative-driven momentum), *Biotech* (event-driven catalyst jumps), and *Consumer Discretionary* (macro-cycle dependence). For each trading day from April 2025 to March 2026, the LLM analyst receives the past 1 or 3 days of news articles (filtered by a strict 23:59 UTC cutoff to prevent look-ahead bias), trailing prices, and macro context (SPY, VIX, 10Y Yield). Crucially, to rigorously prevent data leakage, we evaluate on a 2025–2026 timeline and specifically select GPT-40-mini and GPT-4.1-mini, whose training cutoffs strictly predate our test data. Tickers are ranked by the LLM's composite signal to form an *equal-weight*, *dollar-neutral 5LI/5S portfolio*. This quantile-based allocation aligns with typical industry practices for evaluating long-short strategies: by concentrating capital on the cross-sectional tails of the prediction distribution, it tests the model's predictive power on the highest-conviction signals while mitigating exposure to the less informative middle, thereby avoiding unnecessary transaction costs on low-conviction predictions. We compute *open-to-open (O2O) returns* to realistically model next-day execution, charging 5 bps transaction costs per trade.

**Walk-Forward Protocol.** To test out-of-sample generalization, we employ a rolling walk-forward backtest. Each of the three windows consists of: (1) a 4-month *training* period where the rubric evolves for J=5 rounds starting from a shared initial rubric  $\mathcal{R}^{(0)}$  of generic financial heuristics (more details in Appendix C; the attribution agent examines the  $K_{\text{attr}}$ =20 worst days per round); (2) a 1-month *validation* period to gate candidate rubrics; (3) a 2-month *test* period where the best rubric is frozen and evaluated out-of-sample.

**Baselines.** We compare SHARP against: (a) non-LLM statistical baselines (Random L/S, tuned Momentum, tuned Mean Reversion); (b) an ablation using the same LLM but no rubric evolution (*Static rule*); and (c) state-of-the-art LLM-based financial agents, including Lopez-Lira [3], FinCon [6], and FinHEAR [26], all evaluated under identical portfolio constraints. Our primary evaluations use GPT-40-mini and GPT-4.1-mini, as mentioned earlier, to prevent data leakage (i.e., the models' knowledge cutoff predates the training and test dataset timelines). See Appendix A for more details.

<span id="page-5-1"></span>Table 1: Walk-forward results. Dollar-neutral 5L/5S, 5 bps cost, O2O returns. Each cell is shaded by its within-column rank (darker = better; rank 1 bold, rank 2 underlined; ranks 8+ left blank).

|                                 | AI Tech |       |       |       | Biotech      |       |       |              | Cons. Disc. |       |       |       |
|---------------------------------|---------|-------|-------|-------|--------------|-------|-------|--------------|-------------|-------|-------|-------|
| Method                          | Ret     | SR    | MaxDD | Cal   | Ret          | SR    | MaxDD | Cal          | Ret         | SR    | MaxDD | Cal   |
| Non-LLM baselines               |         |       |       |       |              |       |       |              |             |       |       |       |
| Random L/S                      | -8.4    | -0.76 | -21.1 | -0.74 | -7.8         | -0.84 | -17.9 | -0.72        | -7.7        | -0.94 | -16.6 | -0.68 |
| Mean Reversion                  | -18.4   | -1.38 | -23.9 | -0.77 | -17.9        | -1.72 | -27.7 | -0.65        | -18.3       | -1.82 | -24.5 | -0.75 |
| Momentum (tuned)                | -9.5    | -0.62 | -16.8 | -0.56 | +12.6        | +1.19 | -14.8 | +0.85        | -18.0       | -2.00 | -21.1 | -0.85 |
| LLM-based baselines             |         |       |       |       |              |       |       |              |             |       |       |       |
| Lopez-Lira <sub>40</sub> ([3])  | +7.0    | +0.67 | -22.7 | +0.31 | -14.4        | -1.71 | -23.4 | -0.62        | -3.2        | -0.26 | -10.7 | -0.30 |
| Lopez-Lira <sub>4,1</sub> ([3]) | +15.4   | +1.24 | -19.2 | +0.80 | -10.1        | -1.16 | -12.6 | -0.80        | -7.0        | -0.68 | -11.8 | -0.60 |
| FinCon <sub>4o</sub> ([6])      | +14.8   | +1.41 | -10.0 | +1.48 | +18.8        | +1.75 | -9.8  | +1.91        | +14.0       | +1.62 | -7.3  | +1.92 |
| FinCon <sub>4,1</sub> ([6])     | +8.5    | +0.80 | -11.0 | +0.77 | +10.0        | +0.99 | -8.0  | +1.26        | +8.6        | +1.06 | -8.4  | +1.02 |
| FinHEAR <sub>40</sub> ([26])    | +22.8   | +1.97 | -9.2  | +2.48 | +9.2         | +0.91 | -12.4 | +0.74        | +1.2        | +0.23 | -7.5  | +0.16 |
| FinHEAR <sub>4.1</sub> ([26])   | +11.5   | +1.07 | -10.2 | +1.12 | -5.9         | -0.47 | -14.8 | -0.40        | -2.2        | -0.16 | -8.9  | -0.25 |
| SHARP (ours)                    |         |       |       |       |              |       |       |              |             |       |       |       |
| SHARP 40                        | +33.2   | +2.45 | -7.3  | +4.57 | +12.7        | +1.26 | -11.5 | +1.11        | +16.8       | +1.77 | -7.2  | +2.32 |
| SHARP 4.1                       | +22.9   | +1.44 | -27.3 | +0.84 | <u>+17.8</u> | +1.08 | -13.5 | <u>+1.32</u> | -0.5        | +0.10 | -9.8  | -0.05 |

#### 4.2 Main Results

Table 1 compares the main methods across three sectors, each evaluated on four metrics: total return, Sharpe ratio, maximum drawdown, and Calmar ratio. For each LLM backbone, we select

the best-performing news window per sector using only the validation month of each walk-forward split, then freeze that choice for the test months. All test periods are strictly out-of-sample under the walk-forward protocol.

To keep *no signal* honest in the presence of 5 bps costs, we compare every method against a 1000-trial Random L/S null (Appendix A; 3-sector mean return -8.0%, Sharpe -0.85). The null is negative because random daily rebalancing incurs high turnover (including directional flips counted as two trades each), so the cost compounds to  $\sim\!8\%$  of drag over the 122-day test; this is the correct reference, not zero. Because the study contains only three non-overlapping walk-forward windows, we interpret the results as directional out-of-sample evidence rather than a formal significance claim about long-term excess returns.

On 3-sector average, the evolved rubrics clearly separate from this null. Rubric evolution lifts SHARP<sub>40</sub> from its Static initialization (+0.6% / +0.09 SR, barely above the Random null) to +20.9% / +1.83 SR, and SHARP<sub>4.1</sub> from -4.4% / -0.36 to +13.4% / +0.87. The remaining baselines exceed the Random null but remain economically negligible: tuned Momentum averages -5.0%, Lopez-Lira -0.6% to -3.5%, and FinHEAR<sub>4.1</sub> +1.1%—none meaningful after costs, and even Momentum's +1.19 SR in Biotech does not survive aggregation across regimes. The closest contender is FinCon<sub>40</sub>, whose conceptual-verbal reinforcement reaches +15.9% on 3-sector average and outperforms SHARP<sub>40</sub> on Biotech (+18.8% vs +12.7%). SHARP<sub>40</sub> nonetheless leads the 3-sector average by roughly 5 pp. FinCon's free-form reinforcement is comparatively better matched to the event-driven structure of Biotech. Even the one SHARP cell that comes in slightly negative, SHARP<sub>4.1</sub> on Consumer Disc. at -0.5%, is a large lift over its Static initialization (-12.9%, Appendix D) and improves on the Random null (-7.7%), suggesting that evolution provides a consistent directional correction even when the backbone is weaker in a given sector.

Figure 3 illustrates the cumulative return trajectories for the AI Tech sector. The evolved-rubric variants (solid lines) steadily diverge from their static-rule counterparts (dashed lines) over the test period, confirming that the gains generalize across the evaluated periods. While GPT-4.1-mini + Evo exhibits a steeper maximum drawdown (-27.3%) than GPT-40-mini (-7.3%), this drawdown primarily occurs in the later half of the evaluation period, reflecting natural signal

<span id="page-6-0"></span>![](_page_6_Figure_4.jpeg)

Figure 3: Cumulative OOS returns, AI Tech. Evolved rubrics (solid) steadily separate from their static counterparts (dashed); momentum and mean reversion remain flat or negative.

decay as the market environment drifts further from the training window.

#### 4.3 What Does the Rubric Learn?

By inspecting the rules that emerge across evolution rounds, we find that the system dynamically overrides generic priors (e.g., flipping mean-reversion to momentum in AI Tech) to match underlying market micro-structures, adapting its analysis framework to sector-specific dynamics. Figure 4 shows representative before/after diffs for AI Tech (see Appendix E for Biotech and Consumer Discretionary).

Three interpretable patterns emerge from these edits: (1) Discovering return dynamics: the temporal\_priced\_in initial rule (a mean-reversion prior) is flipped to a momentum signal in AI Tech to capture the 2025 AI narrative rally, narrowed to a conditional exception in Consumer Discretionary (preserving discount in most cases but suppressing it on contrarian rebounds), and specialized strictly for FDA events in Biotech. (2) Creating catalyst rules: evolu-

```
@@ temporal_priced_in @@
- IF: moved >3% in news direction THEN: Reduce signal by 70%
+ IF: moved >5% AND news positive THEN: Increase expected return
@@ macro_high_vix @@
- IF: VIX above 25
```

Figure 4: AI Tech diffs. Evolution discovers momentum, refines VIX interactions, and prunes filters. Full diffs in Appendix E.

tion introduces directional asymmetry for FDA approvals/rejections, adds a symmetric high-VIX rule in Consumer Discretionary (damping bullish *and* amplifying bearish signals during fear spikes), and refines VIX interactions in AI Tech to buy the dip when volatility is elevated but falling. (3) *Tightening noise filters*: across all sectors, the system lowers confidence caps for stocks with scarce news and heavily penalizes generic market commentary. Crucially, every rule change is a human-readable condition/action edit traceable to specific historical error days. A practitioner can inspect the evolved rubric, verify that each rule aligns with financial intuition, and manually override specific behaviors, a level of transparency that free-form prompt optimization does not offer.

#### <span id="page-7-0"></span>4.4 Ablation Studies

We isolate the contribution of SHARP's components via ablations on the AI Tech sector (Table [2\)](#page-7-1). The results confirm that the *attribution agent (A1)* is the most critical component: without error-day analysis, mutations become untargeted, and performance drops to near-static levels. Replacing the structured rule-editing step with *free-form reflection (A2)*, which serves as our *vanilla prompt optimization* baseline, causes an even sharper degradation. The A2 variant is initialized with the identical rubric R(0) and keeps every other component identical (the same LLM backbone, attribution signals, evo-

<span id="page-7-1"></span>Table 2: Ablation on AI Tech. Each row modifies one component vs. full system.

|                                           | GPT-4o-mini |             | GPT-4.1-mini |                          |  |  |
|-------------------------------------------|-------------|-------------|--------------|--------------------------|--|--|
| Variant                                   | Ret (%)     |             | SR Ret (%)   | SR                       |  |  |
| Full system (J=5)                         |             | +33.2 +2.45 |              | +22.9 +1.44              |  |  |
| A1: No attribution<br>A2: Free reflection | −12.1 −0.84 | +7.1 +0.73  |              | +8.5 +0.69<br>+6.0 +0.60 |  |  |
| Static (no evolution)                     |             | +7.3 +0.75  |              | −6.4 −0.42               |  |  |

lution budget, and validation gate), changing only the *mutation operator*: candidates are produced by rewriting the analyst prompt in free form instead of emitting atomic rule edits. Under this change, GPT-4o-mini's Sharpe drops from +2.45 to −0.84 and total return drops from +33.2% to −12.1%, notably *below* the Static baseline that performs no adaptation at all. This empirical collapse directly illustrates the *credit assignment problem* discussed in Section [1.](#page-0-1) When edits rely on unbounded text rewrites rather than structured fault isolation (as is standard in vanilla prompt optimization), each optimization round can silently overwrite previously correct behavior (a phenomenon known as policy degeneration) in ways that the validation gate cannot fully catch. Qualitatively, even when fair-initialized with the same rubric content, the A2 prompt gradually shifts from modular IF/THEN rules into flowing prose whose thresholds drift without any traceable link to specific error days (Appendix [F\)](#page-15-0). SHARP's evolved rubric, by contrast, remains a bounded condition/action list whose every change is a single-rule diff attached to the attribution pattern that motivated it (Figure [4\)](#page-6-1).

Open-source LLM backbones (A3). To test whether SHARP depends on proprietary APIs, we evaluate two open-source models, Qwen2.5-72B-Instruct [\[27\]](#page-11-3) and Llama-3.3-70B-Instruct [\[28\]](#page-11-4), under the same walk-forward protocol. Table [3](#page-7-2) reports the three-sector average return and Sharpe ratio alongside non-LLM baselines and the static-rule ablation. The pattern mirrors the proprietary backbones: with the initial rubric alone, both open-source models deliver marginal returns (−0.6% / −5.3%) that, while above the Random null (−8.0%), remain economically negligible. Rubric evolution closes this gap cleanly, lifting Qwen-72B by +9.8 pp (SR from −0.10 to +0.88) and Llama-70B by +12.9 pp (SR from −0.69 to +0.72), so that both evolved variants turn clearly profitable and exceed every non-LLM baseline. The Static-to-Evo lift is comparable in magnitude to the proprietary backbones, so the contribution of rubric evolution is attributable to the mechanism itself rather than to any specific LLM family, and SHARP transfers to weights that can be hosted on-premise.

<span id="page-7-2"></span>Table 3: Open-source backbones: three-sector average.

| Method                                            | Ret (%) | SR                                      |
|---------------------------------------------------|---------|-----------------------------------------|
| Random L/S<br>MeanRev (tuned)<br>Momentum (tuned) |         | −8.0 −0.85<br>−18.2 −1.64<br>−5.0 −0.48 |
| Qwen-72B + Static<br>Qwen-72B + Evo               |         | −0.6 −0.10<br>+9.2 +0.88                |
| Llama-70B + Static<br>Llama-70B + Evo             |         | −5.3 −0.69<br>+7.6 +0.72                |

## <span id="page-7-3"></span>5 Discussion: From Backtest to Production

The results in Section [4](#page-5-2) demonstrate that structured rubric evolution can produce profitable, interpretable trading signals in a controlled walk-forward backtest. We view these findings as a *feasibility demonstration* rather than a production-ready system. The current implementation uses a generic initial rubric, unconstrained rule mutations, and a single public news source. Future work could integrate richer data streams available to institutional practitioners, including premium analyst reports, proprietary alternative data, and limit order book (LOB) micro-structure. While these high-dimensional signals would increase the complexity of the evolution process, they also represent a substantial ceiling for further performance gains, as SHARP's current outperformance is achieved using only

a sparse set of public news features. A realistic assessment of the gap between the backtested performance reported here and realized live returns is therefore essential.

Gap to production. Several factors separate backtested performance from live trading returns. (i) *Execution slippage.* Our backtest assumes rebalancing at official open-to-open prices, which is optimistic relative to a live implementation. In practice, a production system would usually need to execute over a short post-open window rather than transact the full portfolio at the auction print, so realized fills would drift away from the benchmark open, especially in smaller names and on high-volatility news days. (ii) *Market impact.* Our 5 bps transaction cost covers commissions but omits the price impact of the portfolio's own trades. While negligible for highly liquid AI Tech names, executing trades in less liquid sectors, such as Biotech or Consumer Discretionary, incurs a material market impact that inherently bounds the strategy's capacity [\[29\]](#page-11-5). (iii) *Signal decay.* Prior work shows that text-based news signals are short-lived, often incorporated into prices within a window of one to four days [\[30,](#page-11-6) [31,](#page-11-7) [32\]](#page-11-8). Our daily rebalancing therefore, relies on the overnight signal retaining value through the open, which is plausible for major earnings or regulatory events but less so for routine commentary. (iv) *Regime dependence.* Our seven-month out-of-sample window spans a rally and a modest correction, but is too short to assess robustness to structural shifts such as prolonged bear markets or abrupt monetary policy changes. The sector-specific adaptations discovered by evolution may themselves be regime-dependent, necessitating periodic re-evolution. (v) *Operational risk.* Deploying LLM signals introduces dependencies on API availability, news feed latency, and model versioning. A delayed inference before market open leaves the portfolio without a signal, and each quarterly re-evaluation cycle requires human review before acceptance.

Human oversight and the rubric as an audit interface. In practice, no quantitative trading strategy operates without continuous human oversight, regardless of whether it is built on statistical factors, deep learning, or LLMs. Risk managers, portfolio managers, and compliance officers must be able to evaluate model behavior, diagnose failures, and intervene when market conditions change. Traditional ML-based alpha models make this difficult: a gradient-boosted tree over 200 engineered features or a transformer trained end-to-end on order-book data offers limited surface area for a human to understand why a particular position was taken, let alone to selectively override one component of the model's reasoning without retraining. The rubric representation in SHARP provides a natural interface for this oversight process. Each rule is a human-readable condition/action pair grounded in financial concepts, such as the interaction between VIX levels and bullish signals, and the evolution history records which error days motivated each rule change. A practitioner can review the evolved rubric before deployment, agree with some rules, override others based on proprietary views or risk limits, and do so without touching the underlying LLM or rerunning the optimization. This *selective editability* distinguishes rubric-based systems from both black-box ML and free-form prompt optimization, where any manual intervention risks unpredictable downstream effects.

On the role of the LLM. It is worth being explicit about what the LLM does and does not contribute in our framework. We do not claim that LLMs perform genuine financial reasoning; whether current language models truly understand market dynamics or are performing sophisticated pattern matching on their training corpora remains an open question. The rubric framework is designed so that this distinction matters less than it otherwise would: the financial judgment is encoded in the rubric and refined through market feedback, while the LLM's role is closer to structured text comprehension, mapping unstructured news into the rubric's condition space. When the LLM misclassifies a news article or applies a rubric condition incorrectly, the error surfaces as a traceable mismatch between a specific rule and its outcome, rather than as an opaque failure buried in the model's parameters. This separation does not eliminate the dependence on LLM quality, but it does refocus the LLM's contribution to a narrower, more verifiable task than end-to-end return prediction. Notably, the evolutionary loop ensures that these rules are not static biases from the prompt but are empirically validated and tuned against realized P&L.

## 6 Conclusion

We introduced SHARP, an LLM-based trading framework that addresses the credit assignment problem in self-improving agents by replacing unconstrained prompt mutation with structured rubric evolution. Empirically, SHARP turns generic initial rubrics into systematic walk-forward outperformance across three equity sectors, lifting the performance while maintaining structural transparency and auditability. The primary limitations of our study include the omission of execution slippage, market impact at scale, and long-term regime drift (Section [5\)](#page-7-3), which we leave for future work alongside expanding the rubric schema. Ultimately, SHARP represents a shift in paradigm for quantitative AI: the LLM is confined to mapping unstructured text into a condition space, while the financial judgment itself is held securely in the rubric and iteratively refined from market feedback, allowing the agent to correct human-provided priors when they mismatch the current regime.

## Disclaimer

This material is made available for informational purposes only. Morgan Stanley and its affiliates ("Morgan Stanley") makes no representation and warranty whatsoever and disclaims all liability, for the completeness, accuracy or reliability of the information contained herein. This material is not investment research or investment advice, or a recommendation, offer or solicitation for the purchase or sale of any security, financial instrument, financial product or service, or to be used in any way for evaluating the merits of participating in any transaction or trading strategy. This material was not prepared by the Morgan Stanley Research Department. The information contained in this material does not constitute advice or Morgan Stanley research. Morgan Stanley is not acting as your advisor (municipal, financial, or otherwise) and is not acting in a fiduciary capacity. Unless otherwise indicated, any views expressed or information contained in the materials are those of the respective author(s) alone and may differ from others within Morgan Stanley, including those of Morgan Stanley's Research Department or sales and trading groups. Morgan Stanley did not conduct an independent review of the materials and may not utilize the information, analysis and/or strategies provided by the author(s). Past performance is not indicative of future returns.

## References

- <span id="page-9-0"></span>[1] Aaron Hurst, Adam Lerer, Adam P Goucher, Adam Perelman, Aditya Ramesh, Aidan Clark, AJ Ostrow, Akila Welihinda, Alan Hayes, Alec Radford, et al. Gpt-4o system card. *arXiv preprint arXiv:2410.21276*, 2024.
- <span id="page-9-1"></span>[2] Daya Guo, Dejian Yang, Haowei Zhang, Junxiao Song, Peiyi Wang, Qihao Zhu, Runxin Xu, Ruoyu Zhang, Shirong Ma, Xiao Bi, et al. Deepseek-r1: Incentivizing reasoning capability in llms via reinforcement learning. *arXiv preprint arXiv:2501.12948*, 2025.
- <span id="page-9-2"></span>[3] Alejandro Lopez-Lira and Yuehua Tang. Can chatgpt forecast stock price movements? return predictability and large language models. *arXiv preprint arXiv:2304.07619*, 2023.
- <span id="page-9-3"></span>[4] George Fatouros, Kostas Metaxas, John Soldatos, and Manos Karathanassis. Marketsenseai 2.0: Enhancing stock analysis through llm agents. *arXiv preprint arXiv:2502.00415*, 2025.
- <span id="page-9-4"></span>[5] Yangyang Yu, Haohang Li, Zhi Chen, Yuechen Jiang, Yang Li, Jordan W Suchow, Denghui Zhang, and Khaldoun Khashanah. Finmem: A performance-enhanced llm trading agent with layered memory and character design. *IEEE Transactions on Big Data*, 2025.
- <span id="page-9-5"></span>[6] Yangyang Yu, Zhiyuan Yao, Haohang Li, Zhiyang Deng, Yuechen Jiang, Yupeng Cao, Zhi Chen, Jordan W Suchow, Zhenyu Cui, Rong Liu, et al. Fincon: A synthesized llm multi-agent system with conceptual verbal reinforcement for enhanced financial decision making. *Advances in Neural Information Processing Systems*, 37:137010–137045, 2024.
- <span id="page-9-6"></span>[7] Chengrun Yang, Xuezhi Wang, Yifeng Lu, Hanxiao Liu, Quoc V Le, Denny Zhou, and Xinyun Chen. Large language models as optimizers. In *The Twelfth International Conference on Learning Representations*, 2023.
- <span id="page-9-7"></span>[8] Lakshya A Agrawal, Shangyin Tan, Dilara Soylu, Noah Ziems, Rishi Khare, Krista Opsahl-Ong, Arnav Singhvi, Herumb Shandilya, Michael J Ryan, Meng Jiang, et al. Gepa: Reflective prompt evolution can outperform reinforcement learning. *arXiv preprint arXiv:2507.19457*, 2025.
- <span id="page-9-8"></span>[9] Charidimos Papadakis, Angeliki Dimitriou, Giorgos Filandrianos, Maria Lymperaiou, Konstantinos Thomas, and Giorgos Stamou. Atlas: Adaptive trading with llm agents through dynamic prompt optimization and multi-agent coordination. *arXiv preprint arXiv:2510.15949*, 2025.

- <span id="page-10-0"></span>[10] Barto Andrew and Sutton Richard S. *Reinforcement learning: an introduction*. The MIT Press, 2018.
- <span id="page-10-1"></span>[11] Lipeng Xie, Sen Huang, Zhuo Zhang, Anni Zou, Yunpeng Zhai, Dingchao Ren, Kezun Zhang, Haoyuan Hu, Boyin Liu, Haoran Chen, et al. Auto-rubric: Learning from implicit weights to explicit rubrics for reward modeling. *arXiv preprint arXiv:2510.17314*, 2025.
- <span id="page-10-2"></span>[12] Yang Li, Yangyang Yu, Haohang Li, Zhi Chen, and Khaldoun Khashanah. Tradinggpt: Multiagent system with layered memory and distinct characters for enhanced financial trading performance. *arXiv preprint arXiv:2309.03736*, 2023.
- <span id="page-10-3"></span>[13] Wentao Zhang, Lingxuan Zhao, Haochong Xia, Shuo Sun, Jiaze Sun, Molei Qin, Xinyi Li, Yuqing Zhao, Yilei Zhao, Xinyu Cai, et al. A multimodal foundation agent for financial trading: Tool-augmented, diversified, and generalist. In *Proceedings of the 30th acm sigkdd conference on knowledge discovery and data mining*, pages 4314–4325, 2024.
- <span id="page-10-4"></span>[14] Siyi Wu, Junqiao Wang, Zhaoyang Guan, Leyi Zhao, Xinyuan Song, Xinyu Ying, Dexu Yu, Jinhao Wang, Hanlin Zhang, Michele Pak, et al. Mountainlion: A multi-modal llm-based agent system for interpretable and adaptive financial trading. *arXiv preprint arXiv:2507.20474*, 2025.
- <span id="page-10-5"></span>[15] Krista Opsahl-Ong, Michael J Ryan, Josh Purtell, David Broman, Christopher Potts, Matei Zaharia, and Omar Khattab. Optimizing instructions and demonstrations for multi-stage language model programs. In *Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing*, pages 9340–9366, 2024.
- <span id="page-10-6"></span>[16] Jun Han, Shuo Zhang, Wei Li, Zhi Yang, Yifan Dong, Tu Hu, Jialuo Yuan, Xiaomin Yu, Yumo Zhu, Fangqi Lou, et al. Quantaalpha: An evolutionary framework for llm-driven alpha mining. *arXiv preprint arXiv:2602.07085*, 2026.
- <span id="page-10-7"></span>[17] Ziyi Tang, Zechuan Chen, Jiarui Yang, Jiayao Mai, Yongsen Zheng, Keze Wang, Jinrui Chen, and Liang Lin. Alphaagent: Llm-driven alpha mining with regularized exploration to counteract alpha decay. In *Proceedings of the 31st ACM SIGKDD Conference on Knowledge Discovery and Data Mining V. 2*, pages 2813–2822, 2025.
- <span id="page-10-8"></span>[18] Yuante Li, Xu Yang, Xiao Yang, Minrui Xu, Xisen Wang, Weiqing Liu, and Jiang Bian. R&dagent-quant: a multi-agent framework for data-centric factors and model joint optimization. *arXiv preprint arXiv:2505.15155*, 2025.
- <span id="page-10-9"></span>[19] Xu Yang, Xiao Yang, Shikai Fang, Bowen Xian, Yuante Li, Jian Wang, Minrui Xu, Haoran Pan, Xinpeng Hong, Weiqing Liu, et al. R&d-agent: Automating data-driven ai solution building through llm-powered automated research, development, and evolution. *arXiv e-prints*, pages arXiv–2505, 2025.
- <span id="page-10-10"></span>[20] Zhengyao Jiang, Dominik Schmidt, Dhruv Srikanth, Dixing Xu, Ian Kaplan, Deniss Jacenko, and Yuxiang Wu. Aide: Ai-driven exploration in the space of code. *arXiv preprint arXiv:2502.13138*, 2025.
- <span id="page-10-11"></span>[21] Brendan R Hogan, Xiwen Chen, James T Wilson, Kashif Rasul, Adel Boyarsky, Thomas Kamei, Anderson Schneider, and Yuriy Nevmyvaka. Alphalab: Autonomous multi-agent research across optimization domains with frontier llms. *arXiv preprint arXiv:2604.08590*, 2026.
- <span id="page-10-12"></span>[22] Zhihong Shao, Peiyi Wang, Qihao Zhu, Runxin Xu, Junxiao Song, Xiao Bi, Haowei Zhang, Mingchuan Zhang, YK Li, Yang Wu, et al. Deepseekmath: Pushing the limits of mathematical reasoning in open language models. *arXiv preprint arXiv:2402.03300*, 2024.
- <span id="page-10-13"></span>[23] Anisha Gunjal, Anthony Wang, Elaine Lau, Vaskar Nath, Yunzhong He, Bing Liu, and Sean Hendryx. Rubrics as rewards: Reinforcement learning beyond verifiable domains. *arXiv preprint arXiv:2507.17746*, 2025.
- <span id="page-10-14"></span>[24] William F Shen, Xinchi Qiu, Chenxi Whitehouse, Lisa Alazraki, Shashwat Goel, Francesco Barbieri, Timon Willi, Akhil Mathur, and Ilias Leontiadis. Rethinking rubric generation for improving llm judge and reward modeling for open-ended tasks. *arXiv preprint arXiv:2602.05125*, 2026.

- <span id="page-11-0"></span>[25] Zenan Huang, Yihong Zhuang, Guoshan Lu, Zeyu Qin, Haokai Xu, Tianyu Zhao, Ru Peng, Jiaqi Hu, Zhanming Shen, Xiaomeng Hu, et al. Reinforcement learning with rubric anchors. *arXiv preprint arXiv:2508.12790*, 2025.
- <span id="page-11-2"></span>[26] Jiaxiang Chen, Mingxi Zou, Zhuo Wang, Qifan Wang, Dongning Sun, Chi Zhang, and Zenglin Xu. Finhear: Human expertise and adaptive risk-aware temporal reasoning for financial decisionmaking. *arXiv preprint arXiv:2506.09080*, 2025.
- <span id="page-11-3"></span>[27] Qwen, :, An Yang, Baosong Yang, Beichen Zhang, Binyuan Hui, Bo Zheng, Bowen Yu, Chengyuan Li, Dayiheng Liu, Fei Huang, Haoran Wei, Huan Lin, Jian Yang, Jianhong Tu, Jianwei Zhang, Jianxin Yang, Jiaxi Yang, Jingren Zhou, Junyang Lin, Kai Dang, Keming Lu, Keqin Bao, Kexin Yang, Le Yu, Mei Li, Mingfeng Xue, Pei Zhang, Qin Zhu, Rui Men, Runji Lin, Tianhao Li, Tianyi Tang, Tingyu Xia, Xingzhang Ren, Xuancheng Ren, Yang Fan, Yang Su, Yichang Zhang, Yu Wan, Yuqiong Liu, Zeyu Cui, Zhenru Zhang, and Zihan Qiu. Qwen2.5 technical report, 2025.
- <span id="page-11-4"></span>[28] Aaron Grattafiori, Abhimanyu Dubey, Abhinav Jauhri, Abhinav Pandey, Abhishek Kadian, Ahmad Al-Dahle, Aiesha Letman, Akhil Mathur, Alan Schelten, Alex Vaughan, et al. The llama 3 herd of models. *arXiv preprint arXiv:2407.21783*, 2024.
- <span id="page-11-5"></span>[29] Robert Almgren, Chee Thum, Emmanuel Hauptmann, and Hong Li. Direct estimation of equity market impact. *Risk*, 18(7):58–62, 2005.
- <span id="page-11-6"></span>[30] Paul C Tetlock. Giving content to investor sentiment: The role of media in the stock market. *The Journal of Finance*, 62(3):1139–1168, 2007.
- <span id="page-11-7"></span>[31] Steven L Heston and Nitish Ranjan Sinha. News versus sentiment: Predicting stock returns from news stories. Technical report, 2015.
- <span id="page-11-8"></span>[32] Zheng Tracy Ke, Bryan T Kelly, and Dacheng Xiu. Predicting returns with text data. Technical report, National Bureau of Economic Research, 2019.

## Broader Impacts

The strongest case for SHARP is not full automation, but a shorter loop between *observing* a failure mode and *editing* the policy that caused it. Because adaptation is expressed as explicit rule edits, changes can be inspected and selectively accepted before capital is put at risk. Compared with conventional black-box pipelines, this makes regime adaptation more governable: diagnosis, revision, and review happen in the same representation rather than across disconnected model and prompt layers.

## <span id="page-11-1"></span>A Detailed Experimental Setup

This section provides the full technical details underlying Section [4.1.](#page-5-0)

Stock universes. We construct three sector-specific universes of 16 stocks each, chosen to test SHARP under qualitatively different signal regimes:

- AI & Tech (16): NVDA, MSFT, GOOGL, META, AMZN, AAPL, AMD, AVGO, TSM, MRVL, ARM, CRM, PLTR, SNOW, AI, TSLA. Spans mega-cap AI leaders, semiconductor infrastructure, and AI software. This sector is *narrative-driven*: prices move with macro sentiment, earnings guidance, and AI hype cycles.
- Biotech (16): LLY, JNJ, ABBV, MRK, PFE, AMGN, GILD, BMY, VRTX, REGN, MRNA, BIIB, ISRG, DXCM, ILMN, ALNY. Spans large-cap pharma and mid-cap biotech. This sector is *eventdriven*: prices jump on binary catalysts such as FDA approvals, clinical trial readouts, and drug pipeline updates.
- Consumer Discretionary (16): AMZN, TJX, ROST, TSLA, HD, LOW, DHI, LEN, MCD, SBUX, CMG, NKE, BKNG, ORLY, AZO, GRMN. Covers e-commerce, automotive, home improvement, restaurants, apparel, and travel. This sector is *cycle-driven*: prices track consumer spending, housing data, and macro conditions.

**Data sources.** Prices. Daily OHLCV data from Yahoo Finance for all 16 tickers per sector, plus three macro indicators: SPY (S&P 500 ETF), VIX (CBOE Volatility Index), and the 10-Year Treasury Yield. The price dataset spans Apr 2024 to Mar 2026: the first  $\sim$ 12 months (Apr 2024 to Apr 2025) serve solely as lookback context for 52-week high/low and 20-day momentum features, while the trading evaluation period (training through testing) runs from Apr 2025 onward.

News. Historical news articles sourced from Finnhub and cached on disk for reproducibility. For each trading day T, we fetch articles for each ticker from the preceding d calendar days, where d=3is the news window. Every article is filtered by its published timestamp: we discard any article timestamped after T 23:59 UTC. Since the US market opens at 09:30 ET (13:30 UTC), this creates a 13.5-hour safety gap between the news cutoff and the next morning's execution, preventing all look-ahead bias from after-hours or overnight articles.

*Price context.* For each ticker on each day T, the LLM receives: last close price, 1-day/5-day/20day returns, 52-week high and low (computed from the trailing 252 trading days ending at T, strictly backward-looking), and percent distance within this range. Macro context includes the same momentum features for SPY, VIX, and the 10-Year yield. All context is available at market close on day T; no forward-looking information is used.

#### Return calculation. We use open-to-open (O2O) returns to model realistic execution:

- 1. Decision time: day T close. The LLM has access to all prices up to T close and all news up to T 23:59 UTC.
- 2. Execution: a market-on-open (MOO) order fires at day T+1 open (09:30 ET). 3. Return:  $r_i = \mathrm{Open}_i^{T+2}/\mathrm{Open}_i^{T+1} 1$  for each held position i.

This avoids the common pitfall of using close-to-close returns with same-day signals, which implicitly assumes execution at an already-known close price.

**Portfolio construction.** For each trading day T, the LLM produces a composite signal for each ticker:  $\sigma_i = \hat{r}_i \cdot c_i$ , where  $\hat{r}_i$  is the LLM's expected return estimate and  $c_i \in [0, 1]$  is its confidence. Tickers are ranked by  $\sigma_i$ ; we go long the top 5 and short the bottom 5, forming an equal-weight, dollarneutral 5L/5S portfolio rebalanced daily. The 5L/5S constraint is always binding: because every stock receives a score  $\sigma_i$ , the top and bottom five are always well-defined regardless of confidence levels, so no fill or reweighting logic is needed. Each leg allocates  $\frac{1}{5}$  of its notional to every constituent; the daily portfolio return is  $r^{\text{long}} + r^{\text{short}}$ , where  $r^{\text{long}} = \frac{1}{5} \sum_{i \in L} r_i$  and  $r^{\text{short}} = -\frac{1}{5} \sum_{j \in S} r_j$ , using open-to-open (O2O) returns. Transaction costs of 5 basis points are charged for each new position entering the portfolio (i.e., each time a stock enters the long or short leg that was not there the previous day).

Walk-forward protocol details. We employ a rolling walk-forward backtesting protocol with the following window structure:

- Train (4 months): the rubric evolves for J=5 rounds. In each round, the attribution agent identifies error days from the training-period backtest, the evolution agent proposes <3 rule mutations, and the candidate rubric is evaluated on validation data.
- Validation (1 month): each candidate rubric is backtested on validation data. A candidate is accepted if its validation excess return satisfies  $r_{\rm val} > r_{\rm val}^* - 0.005$ , where  $r_{\rm val}^*$  is the best seen so far. This 0.5 pp tolerance avoids rejecting sideways improvements. The rubric with the highest  $r_{\rm val}$ across all rounds is selected.
- Test (2 months): the best rubric is frozen and evaluated on strictly out-of-sample data. No rubric changes, no parameter tuning, and no information from the test period leaks into any earlier stage.
- Step: the window advances by 2 months, so consecutive test periods tile without overlap.

With price data spanning Apr 2024 to Mar 2026 and the trading evaluation period beginning Apr 2025, this yields 3 walk-forward windows per sector, with test periods covering approximately Sep 2025 to Mar 2026 (~122 trading days total). Within each window, rubric evolution is independent: the same initial rubric  $\mathcal{R}^{(0)}$  is used as the starting point, and all 5 rounds of evolution occur on that window's train+val data only.

**Baselines.** We compare against four baselines that span three levels of sophistication:

1. Random L/S: 1,000 Monte Carlo trials. Each trial randomly selects 5 long and 5 short positions from the same 16-stock universe, rebalanced daily with the same 5 bps cost. Transaction costs

account for directional flips (e.g., a stock moving from the long to the short leg counts as two trades: closing the old position and opening the new one). Although the position construction is dollar-neutral, the expected return is *not* zero: high random turnover and frequent directional flips cause the 5 bps per-trade cost to compound to roughly −8% over the 122-day test window (three-sector mean −8.0%, mean Sharpe −0.85). This null is therefore the correct reference for "no real signal" under our execution assumptions, rather than a naive zero.

- 2. Momentum (tuned): rank tickers by k-day return; long top-5, short bottom-5. The lookback k is selected from {1, 2, 3, 5, 10, 20} days by maximizing Sharpe on the combined train+validation data *before* evaluating on test. This respects the train/test boundary.
- 3. Mean Reversion (tuned): rank tickers by *negative* k-day return (buy losers, short winners). Same lookback selection procedure as momentum.
- 4. Static rule (no evolution): the same LLM backbone receives the same news, price context, and macro data, and uses the initial rubric R(0) with no evolution applied. The LLM produces (ˆr<sup>i</sup> , ci) signals guided only by the initial rules, without any sector-specific adaptation from P&L feedback. This is the key ablation: Static and Evo share the same initialization and differ *only* in whether evolution is run.

News window. For each trading day T, the LLM analyzes news from the preceding d calendar days. In the main experiments, d = 3; when multiple windows are compared, the choice is made using only the validation month of each walk-forward split and then frozen for test.

Evaluation metrics. We report four metrics: total return (%), Sharpe ratio (annualized: µ/σ × √ 252), maximum drawdown (peak-to-trough decline, %), and Calmar ratio (Total Return/|MaxDD|).

Implementation details. For rubric evolution (Section [3.3\)](#page-4-1): J=5 rounds per walk-forward window, maximum rubric size Mmax = 18 rules (hard cap enforced programmatically), at most ∆max = 3 mutations per round, validation tolerance ϵ = 50 bps. The attribution agent examines the Kattr=20 worst-performing portfolio days and filters for error patterns appearing on ≥ 3 days. To encourage compactness, the evolution agent's prompt instructs it to remove an existing rule for each addition once the rubric reaches ≥ 12 rules; the hard upper bound of Mmax = 18 is enforced in code and is rarely approached in practice. The initial rubric (round 0) contains a small set of generic rules and is shared across all sectors; it is not tuned on any test-period data.

Computational resources and runtime. Proprietary backbones (GPT-4o-mini, GPT-4.1-mini) are accessed via the OpenAI API and require no local GPUs. Open-source backbones (Qwen2.5-72B-Instruct, Llama-3.3-70B-Instruct) are served locally with vLLM (tensor\_parallel\_size = 4, bfloat16, max\_model\_len = 32 768) on a single node of 8×NVIDIA H100 80GB; we allocate 4 GPUs per model, so the two open-source backbones can be served concurrently. A complete per-sector run, covering all three walk-forward windows, J=5 evolution rounds per window, and both the Static and Evo evaluation paths (so that all attribution backtests, evolution proposals, and validation backtests are included), has the following measured wall-clock cost (averages over the runs logged for Table [1\)](#page-5-1): (i) ∼3 h 30 min for GPT-4o-mini / GPT-4.1-mini on the OpenAI API; (ii) ∼5 h 40 min for Qwen-72B on 4×H100; and (iii) ∼6 h 55 min for Llama-70B on 4×H100.

## <span id="page-13-0"></span>B Evolution Algorithm

Algorithm [1](#page-14-2) gives the full training loop for rubric evolution: backtest, attribute errors, propose candidate rule edits, and validate before accepting.

## <span id="page-13-1"></span>C Initial Rubric Template

The initial rubric R(0) is a small generic set of rules used to start the evolution process. No rule is tuned on test-period data; all conditions and thresholds are adapted from standard financial commentary available prior to our evaluation window. The following six rules are shared across all sector universes.

```
[temporal_discount] temporal_priced_in
  Discount news already reflected in price.
  IF: Stock moved >3% in the same direction as the news sentiment
      over the past 5 trading days
```

#### <span id="page-14-2"></span>**Algorithm 1** SHARP Rubric Evolution (Training Phase)

```
Require: \mathcal{D}_{\text{train}}, \mathcal{D}_{\text{val}}, initial rubric \mathcal{R}^{(0)}, rounds J, tolerance \epsilon
  1: \mathcal{R}^* \leftarrow \mathcal{R}^{(0)}, e^* \leftarrow e(\text{Backtest}(f_{\theta}(\cdot \mid \mathcal{R}^{(0)}), \mathcal{D}_{\text{val}}))
  2: for i = 1 to J do
            \mathbf{y} \leftarrow \text{BACKTEST}(f_{\theta}(\cdot \mid \mathcal{R}^{(j-1)}), \mathcal{D}_{\text{train}})
          \mathcal{E} \leftarrow \text{Attribute}(\text{worst days of } \mathbf{y})
            \mathcal{P} \leftarrow \text{EVOLVE}(\mathcal{R}^{(j-1)}, \mathcal{E}) {candidate rule edits}
            \tilde{\mathcal{R}}^{(j)} \leftarrow \text{APPLY}(\mathcal{R}^{(j-1)}, \mathcal{P})
             e_i \leftarrow e(\text{BACKTEST}(f_{\theta}(\cdot \mid \tilde{\mathcal{R}}^{(j)}), \mathcal{D}_{\text{val}})) \text{ {validation score}}
             if e_i \geq e^* - \epsilon then
                  \tilde{\mathcal{R}}^{(j)} \leftarrow \tilde{\mathcal{R}}^{(j)}
  9.
                  if e_j > e^* then
 10:
                        \mathcal{R}^* \leftarrow \tilde{\mathcal{R}}^{(j)}, \ e^* \leftarrow e_i
 11:
12.
              else
13:
                  \mathcal{R}^{(j)} \leftarrow \mathcal{R}^{(j-1)}
 14:
             end if
 15:
16: end for
17: return R*
```

```
THEN: Reduce the signal strength from this news by 70%
[{\tt temporal\_discount}] \ {\tt temporal\_earnings\_season}
 Downweight non-earnings news near earnings.
 IF: Within 5 trading days before or after a scheduled earnings report
 THEN: Reduce weight of non-earnings-related news by 50%
[news_weighting] news_analyst_rating
 Moderate weight for analyst rating changes.
 IF: News is an analyst upgrade/downgrade or price target change
 THEN: Base signal weight x1.3 if from top-tier bank, x1.0 otherwise
[news_weighting] news_generic_market
 Downweight generic market commentary.
 IF: News is broad market commentary not specific to the company
 THEN: Reduce signal weight by 60%
[macro_interaction] macro_high_vix
 Dampen bullish signals in high-fear environment.
 IF: VIX is above 25
 THEN: Reduce all bullish expected_return estimates by 30%
[news_weighting] news_count_low
 Lower confidence when news is scarce.
 IF: Fewer than 3 news articles available for the ticker
 THEN: Cap confidence at 0.4
```

Each sector additionally includes 1–4 sector-specific rules (e.g., FDA event weighting for biotech, housing cycle rules for consumer discretionary); these are listed in full in the released code.

#### <span id="page-14-0"></span>D Static Rule Baseline (Full Results)

Table 4 reports the full static-rule baseline: same LLM backbone and inputs as SHARP, but no rubric evolution. These rows are omitted from the main table for space. Evo vs. Static is the key ablation because the two settings differ *only* in whether the rubric has been optimized.

#### <span id="page-14-1"></span>**E** Sector-Specific Rubric Diffs

Figure 5 provides representative before/after diffs for the Biotech and Consumer Discretionary sectors, complementing the AI Tech example in the main text (Figure 4). The same three patterns from the main text reappear here in sector-specific form.

<span id="page-15-1"></span>Table 4: Static rule baseline (no evolution): walk-forward results across all models and sectors.

|                     |       | AI Tech    |             |       |                   | Biotech    |          |             |                   | Cons. Disc. |             |       |  |
|---------------------|-------|------------|-------------|-------|-------------------|------------|----------|-------------|-------------------|-------------|-------------|-------|--|
| Method              | Ret   |            | SR MaxDD    | Cal   | Ret               |            | SR MaxDD | Cal         | Ret               |             | SR MaxDD    | Cal   |  |
| GPT-4o-mini         | +7.3  | +0.75      | −12.0       | +0.61 |                   | −8.7 −0.91 |          | −17.4 −0.50 | +3.1              | +0.44       | −8.4        | +0.37 |  |
| GPT-4.1-mini        |       | −6.4 −0.42 | −19.2 −0.33 |       | +6.2              | +0.80      | −12.7    |             | +0.48 −12.9 −1.47 |             | −16.8 −0.77 |       |  |
| Qwen2.5-72B         | +10.0 | +0.85      | −9.8        | +1.02 |                   | −7.1 −0.72 |          | −11.4 −0.62 |                   | −4.7 −0.42  | −14.4 −0.33 |       |  |
| Llama-3.3-70B +12.1 |       | +1.06      | −15.4       |       | +0.78 −19.3 −2.20 |            |          | −20.8 −0.93 |                   | −8.6 −0.94  | −13.5 −0.64 |       |  |

Returns and MaxDD in %. Same portfolio construction as Table [1.](#page-5-1)

- (1) Discovering distinct return dynamics. In AI Tech, the temporal\_priced\_in rule flips from a mean-reversion prior into a momentum rule, matching the narrative-driven rally regime of 2025. In Consumer Disc., the same rule is narrowed into an exception: the blanket 70% discount is suppressed when a stock moved opposite to positive news, preserving contrarian rebound setups. In Biotech, the rule is specialized to FDA events with a higher 7% threshold and a milder 50% discount, reflecting the fact that large post-FDA moves are often fundamental rather than noise.
- (2) Sector-specific catalyst rules. Beyond adapting shared initial rules, evolution also creates new rules tailored to each sector's signal structure. In Biotech, the FDA weighting rule is strengthened from 2.0× to 2.5× and made directional: approvals are bullish, rejections bearish. In Consumer Disc., evolution adds a symmetric high-VIX rule: when VIX exceeds 25, bullish predictions are damped and bearish predictions amplified by 30%.

<span id="page-15-2"></span>(a) Biotech FDA amplified with asymmetry; priced-in kept; noise suppressed

```
@@ news_fda_action @@
- IF: FDA approval/rejection/CRL THEN: signal weight x2.0
+ IF: FDA approval/rejection/CRL THEN: weight x2.5, directional
+ (approval -> bullish, rejection -> bearish)
@@ temporal_priced_in @@
- IF: moved >3% in news direction THEN: Reduce signal by 70%
+ IF: FDA+ news AND moved >7% THEN: Discount signal by 50%
@@ news_generic_market @@
- IF: generic market news THEN: Reduce weight by 60%
+ IF: generic market news THEN: Reduce weight by 80%
@@ news_count_low @@
- IF: fewer than 3 articles THEN: Cap confidence at 0.4
+ IF: <3 significant articles THEN: Cap confidence at 0.3
```

(b) Consumer Disc. Priced-in narrowed to exception; noise tightened; new symmetric VIX rule

```
@@ temporal_priced_in @@
- IF: moved >3% SAME direction as news THEN: Reduce signal by 70%
+ IF: moved >3% OPPOSITE to news AND pos sentiment
+ THEN: Do NOT discount
@@ news_generic_market @@
- IF: generic market news THEN: Reduce weight by 60%
+ IF: generic market news THEN: Reduce weight by 70%
@@ macro_adjustment_high_fear (new) @@
+ IF: VIX > 25 THEN: Down-weight bullish 30%,
+ up-weight bearish 30% (symmetric)
```

Figure 5: Full sector-specific rubric diffs: initial rules (red) vs. evolved rules (green).

## <span id="page-15-0"></span>F Free-Form Reflection (A2 Ablation) Example

Figure [6](#page-16-1) shows the GPT-4.1-mini analyst prompt before and after five rounds of free-form reflection in the A2 ablation (Section [4.4\)](#page-7-0). The v0 prompt is fair-initialized with the same seven rubric rules as the main SHARP system. After five rounds, the modular IF/THEN rules have been rewritten into flowing prose whose thresholds quietly drift (e.g., earnings discount 50% → 70%, VIX damping 30% → 40%) without any link to specific error days. Unlike SHARP's diffs (Figure [4,](#page-6-1) Section [E\)](#page-14-1), where every threshold change carries a full audit trail back to the error days that motivated it, the free-form variant offers no mechanism to trace or selectively revert individual changes. This matches Table [2:](#page-7-1) without structural constraints, the validation gate can only accept or reject the entire rewritten prompt, and cannot prevent gradual erosion of well-calibrated rules.

```
@@ analyst_prompt (v0 fair init) --> (v5 after 5 rounds) @@
- ...base prompt (JSON schema, general instructions)...
- === ANALYSIS RUBRIC (v0, 7 rules) ===
- [TEMPORAL_DISCOUNT]
- * IF moved >3% in news direction (5d) THEN reduce signal by 70%
- * IF within 5d of earnings THEN reduce non-earnings news by 50%
- [NEWS_WEIGHTING]
- * IF analyst upgrade/downgrade THEN weight x1.3 (top-tier) / x1.0
- * IF generic market commentary THEN reduce weight by 60%
- * IF <3 articles THEN cap confidence at 0.4
- * IF major corporate event THEN signal weight x2.0
- [MACRO_INTERACTION]
- * IF VIX > 25 THEN reduce bullish returns by 30%
+ As a senior analyst, your predictions must rigorously integrate price
+ momentum, news catalysts, earnings proximity, and the macro backdrop.
+
+ When a stock has already rallied more than 3% on the same news over
+ the past five days, treat the move as largely priced in and discount
+ the remaining upside aggressively---by at least 70%, or over 90% if
+ the move exceeds 7%.
+
+ Near earnings, be especially skeptical of non-earnings headlines:
+ reduce their weight by roughly 70% and keep confidence low.
+
+ Analyst upgrades from top-tier banks deserve a moderate uplift
+ (around 1.5x), but generic market commentary should be heavily
+ discounted. Major corporate events (M&A, FDA, earnings) warrant
+ doubling the signal weight.
+
+ In a high-fear regime (VIX above 25), dampen any bullish leanings
+ by about 40% and weigh geopolitical tail risks more seriously.
+
+ When signals conflict, err toward lower confidence rather than
+ forcing a directional call. Keep reasoning concise, grounded in
+ recent price action, and focused on material events from the past
+ three to five days.
```

Figure 6: Free-form reflection (A2) on AI Tech, GPT-4.1-mini, window 0. The v0 prompt is fairinitialized with the same rubric content as the main SHARP system. Without structural constraints, the writing style gradually shifts from modular IF/THEN rules into flowing prose, and individual changes become difficult to track across rounds.

## <span id="page-16-0"></span>G Attribution Agent Example Trace

Figure [7](#page-17-0) provides a compact textual trace of the attribution process: the agent receives the worstperforming days, diagnoses a recurring error pattern, and proposes a rule fix.

<span id="page-17-0"></span>Step 1. Backtest on training period (2025-04-15 to 2025-08-14) finds 20 worst portfolio days. For each, pack full context:

```
Day 7: 2025-05-16 (portfolio return: -2.31%)
  Long: [NVDA, GOOGL, CRM, AMZN, META] Short: [AAPL, PLTR, AI, SNOW, ARM]
  [NVDA] predicted: +5.0% (bullish, conf=0.75)
    reason: "strong AI chip demand; positive trade news"
    rules_applied: [news_high_impact, macro_low_vix]
  Actual NVDA return: -2.8% (5d prior: +16.1%)
  Headlines: "Nvidia stock set for 15% weekly gain as trade
             news boosts AI chip"
```

#### Step 2. LLM analyzes all 20 days jointly → 5 structured error patterns:

```
[insufficient_temporal_discount_for_recent_momentum] freq=17
  "The analysis process often predicts bullish returns
   despite stocks having already rallied strongly on the
   same news. temporal_priced_in threshold too loose."
[overreliance_on_analyst_upgrades_and_price_targets] freq=15
  "High weight on analyst rating changes and price target
   upgrades without adjusting for recent price run-up."
[insufficient_downweighting_of_news_near_earnings] freq=10
  "Non-earnings news near earnings dates not sufficiently
   downweighted; LLM overreacts to noise pre-earnings."
```

Step 3. Evolution agent proposes 3 atomic edits targeting the top patterns:

```
[modify] temporal_priced_in:
    Increase discount for news already reflected in price
[modify] news_analyst_rating:
    Reduce weight and cap confidence for analyst upgrades
[modify] temporal_earnings_season:
    Increase downweighting of non-earnings news near earnings
```

Rubric evolved: v0 → v1 (3 changes applied, accepted on validation).

Figure 7: Illustrative example of the attribution agent pipeline.
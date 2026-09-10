# gen_paper_site — report_results

> Phase: `gen_paper_repo` · `gen_full_paper`
> Run: `run_XUVIPW24BQbP` — Visual Uncertainty-Aware Conformal Cache Admission with Adaptive Bias
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_paper_site` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-09-10 01:37:27 UTC

````
<task>
Build the paper's public web page: ONE self-contained `index.html` that lets a reader grasp
this paper faster than opening the PDF would. It is published as this run's GitHub Pages site, so
it is the first thing anyone sees.
</task>

<tool_use>
Maximize parallel tool calls. Parallelize independent operations, only sequentialize dependencies.
- Multiple searches/fetches on different topics → parallel in one turn
- Search then fetch results → sequential (need URLs first)
</tool_use>

<what_is_already_here>
Your workspace is the finished paper folder. It already holds everything the page is made of, and
you must not change any of it — you are adding one file, not revising the paper.

- `paper.tex` — the paper as it was actually written. This is the source of truth for
  every claim, name and NUMBER that goes on the page.
- `paper.pdf` — the compiled paper. The page must NOT link to it by this local name:
  the PDF is published on the code branch and the page on a different one. Link to it at the
  full URL below instead.
- `references.bib` — the bibliography, when the paper has one.
- `figures/` — every figure the paper uses, flattened into one folder.
- `workspace/` — the scratch folder the LaTeX task worked in. Ignore it.
</what_is_already_here>

<paper_text>
title: Visual Uncertainty-Aware Conformal Cache Admission with Adaptive Bias
abstract: >-
  Cache admission policies decide which items enter a limited-capacity cache. Existing policies rely on recency, frequency,
  or learned signals, yet they provide no uncertainty quantification: when popularity shifts or new content arrives, they
  admit items with the same confidence as they do stable ones. We propose Visual Uncertainty-Aware Conformal Cache Admission
  (VUCCA), the first admission mechanism to combine semantic embeddings, conformal prediction intervals, and confidence-adaptive
  bias. VUCCA clusters items by visual embedding, computes conformal prediction intervals for per-cluster miss rates, and
  adjusts admission thresholds via a soft-sigmoid function: high-confidence clusters admit freely, uncertain clusters are
  filtered selectively. We evaluate VUCCA against LRU, TinyLFU, and ARC2 on three synthetic regimes derived from CDN trace
  statistics. VUCCA matches LRU hit ratios across all regimes while providing distribution-free coverage guarantees that baselines
  lack. An ablation confirms the soft-sigmoid bias is essential: removing it drops hit ratio by 67%. The conformal framework
  enables uncertainty-aware admission where baselines offer none.
paper_text: |-
  # Visual Uncertainty-Aware Conformal Cache Admission with Adaptive Bias

  ## Abstract

  Cache admission policies decide which items enter a limited-capacity cache. Existing policies rely on recency, frequency, or learned signals, yet they provide no uncertainty quantification: when popularity shifts or new content arrives, they admit items with the same confidence as they do stable ones. We propose Visual Uncertainty-Aware Conformal Cache Admission (VUCCA), the first admission mechanism to combine semantic embeddings, conformal prediction intervals, and confidence-adaptive bias. VUCCA clusters items by visual embedding, computes conformal prediction intervals for per-cluster miss rates, and adjusts admission thresholds via a soft-sigmoid function: high-confidence clusters admit freely, uncertain clusters are filtered selectively. We evaluate VUCCA against LRU, TinyLFU, and ARC2 on three synthetic regimes derived from CDN trace statistics. VUCCA matches LRU hit ratios across all regimes (0.479, 0.441, 0.413) while providing distribution-free coverage guarantees. An ablation confirms the soft-sigmoid bias is essential: removing it drops hit ratio by 67%.

  ## 1 Introduction

  ### 1.1 Problem

  Software caches are ubiquitous: from Memcached and CDN edge caches to LLM KV caches and database buffer pools. The admission decision, whether to insert a newly requested item into a full cache, directly determines hit ratio, throughput, and latency. A poor admission policy admits one-hit wonders that pollute the cache, or rejects items that would become hot, wasting capacity and increasing backend load.

  ### 1.2 Importance

  Modern workloads exhibit three properties that strain existing admission policies. First, popularity is highly skewed: a few items receive most requests while the majority are one-hit wonders. Second, popularity shifts abruptly: viral content, news events, or model updates cause request mass to migrate between semantic clusters. Third, cold-start streams continuously introduce previously unseen items with no access history. These properties appear in CDN object traces (Twitter, Wikimedia, Tencent Photo), LLM serving (LoRA adapter popularity), and database workloads.

  ### 1.3 Challenges

  Naive frequency-based admission (TinyLFU) uses a fixed window to estimate popularity. When popularity shifts, the window contains stale statistics, causing both false admits and false rejects. Recency-based policies (LRU, ARC) adapt to shifts but lack semantic understanding: they cannot generalize from one item to semantically similar items. Learning-augmented policies (DEAP Cache, CACHEUS) model the joint distribution of features and future accesses but provide no distribution-free uncertainty guarantees: they can be overconfident on out-of-distribution items.

  ### 1.4 Prior Work Gap

  A survey of 12 state-of-the-art admission policies (TinyLFU, S3-FIFO, Segcache, CacheSack, DEAP Cache, Guard, AdCache, Chameleon, Bandit Learning-to-Cache, Learning-Augmented Caching, LeCaR, ARC) confirms that zero apply distribution-free uncertainty quantification to admission decisions [1, 2, 3, 4, 5, 6, 12]. DEAP Cache uses Kernel Density Estimation for non-stationary data modeling but provides no coverage guarantees [4]. Guard provides robustness bounds via algorithmic analysis, not statistical uncertainty quantification [5]. Visual or semantic embeddings (CLIP, ViT) are used for similarity search in caching but never combined with uncertainty-aware admission [10]. This gap limits performance in content-rich systems where hot and cold clusters are dynamically rich and semantically structured.

  ### 1.5 Our Approach and Summary of Results

  We propose Visual Uncertainty-Aware Conformal Cache Admission (VUCCA), the first cache admission mechanism combining visual semantic embeddings, conformal prediction intervals, and confidence-adaptive admission bias. We evaluate VUCCA against LRU, TinyLFU, and ARC2 on three controlled regimes. VUCCA matches LRU hit ratios across all regimes while providing distribution-free coverage guarantees that baselines lack. An ablation confirms the soft-sigmoid bias function is essential: replacing it with the exponential bias from our initial design drops hit ratio by 67%, reproducing the "admission cliff" failure mode.

  **Summary of Contributions**

  - **Novel mechanism**: First cache admission policy combining visual semantic embeddings, conformal prediction intervals, and confidence-adaptive bias with a soft-sigmoid function.
  - **Adaptive Conformal Inference**: Implementation of ACI with exponential weighting for non-stationary workloads, addressing exchangeability violations under popularity shifts [8].
  - **Comprehensive survey**: Verification that zero of 12 modern baselines use conformal prediction or visual signals for admission.
  - **Synthetic benchmark**: Three regimes (stationary, shift, cold-start) with 512-d embeddings and temporal splits for controlled evaluation.
  - **Ablation study**: Four ablations isolating the contribution of soft-sigmoid bias, ACI, cluster granularity, and entropy-based uncertainty.

  [FIGURE:fig1]

  ## 2 Related Work

  ### 2.1 Cache Admission and Eviction Policies

  **Frequency-based admission.** TinyLFU [1] maintains a Count-Min Sketch of recent access frequencies and admits a new item only if its estimated frequency exceeds the victim's. S3-FIFO [2] uses a small probationary FIFO queue to filter one-hit wonders, achieving lower miss ratios than LRU-based policies across 6594 production traces. Both use fixed thresholds without uncertainty quantification.

  **Recency and adaptive replacement.** ARC [3] maintains four LRU queues (recent, frequent, and their ghosts) and adapts the partition based on ghost hits. LIRS uses reuse distance. These adapt to workload shifts but lack semantic generalization.

  **Learning-augmented caching.** DEAP Cache [4] jointly learns eviction, admission, and prefetching with a deep network and Kernel Density Estimation for non-stationarity. CACHEUS selects among expert policies via online learning. Guard [5] robustifies learning-augmented policies to $2H_{k-1}+2$ consistency with $O(1)$ overhead. None provide distribution-free prediction intervals.

  **LLM-specific caching.** Chameleon [6] caches LoRA adapters for multi-adapter LLM inference, reducing P99 latency by 80.7%. GPTCache and RAGCache use embedding similarity for semantic cache hits. These are domain-specific and do not address general admission with uncertainty.

  ### 2.2 Conformal Prediction

  Conformal prediction [7] generates prediction sets with guaranteed marginal coverage $1-\alpha$ under exchangeability, without distributional assumptions. Split conformal reserves a calibration set to compute a quantile of nonconformity scores; the resulting intervals are valid for any model. Gibbs and Candès [8] extend conformal prediction to handle distribution shift via Adaptive Conformal Inference (ACI), which updates quantiles with exponential weighting to track non-stationary environments. Their follow-up [9] handles arbitrary distribution shifts in online prediction. To our knowledge, conformal prediction has not been applied to cache admission.

  ### 2.3 Visual and Semantic Embeddings in Caching

  ViT and CLIP embeddings enable semantic similarity search [10]. IGTCache uses ViT for image retrieval caching (+55.6% hit ratio). Document embedding caches implement metric indices for nearest-neighbor queries. None incorporate embedding-derived uncertainty into admission.

  ### 2.4 Throughput-Hit Ratio Trade-offs

  Qiu et al. [11] show that increasing hit ratio can hurt throughput under certain queueing conditions, challenging the assumption that higher hit ratio always improves performance. This motivates our dual evaluation of both hit ratio and throughput.

  ## 3 Method

  ### 3.1 Overview

  VUCCA operates in three stages (Figure 1): (1) **Embedding and Clustering**: items are mapped to 512-d visual embeddings and clustered into K semantic groups; (2) **Conformal Uncertainty Quantification**: per-cluster miss rates are estimated over a calibration window, and conformal prediction produces intervals with coverage $1-\alpha$; (3) **Confidence-Adaptive Admission**: the interval width determines an uncertainty score, which scales the admission threshold via a soft-sigmoid bias function.

  ### 3.2 Visual Semantic Embeddings

  Each item $i$ has an associated image or visual representation. We extract a 512-dimensional embedding $e_i \in \mathbb{R}^{512}$ using a pretrained ViT-B/32 [10]. In our synthetic benchmark, embeddings are generated deterministically from item IDs using structured sinusoidal functions. Items are clustered via K-means ($K=64$) into semantic clusters $C_1,\dots,C_K$. Clusters smaller than 5 items are merged into the nearest larger cluster.

  ### 3.3 Conformal Prediction for Miss Rates

  Let $M_c(t)$ be the empirical miss rate of cluster $c$ at time $t$. We reserve the first 20% of the trace as a calibration set. For each cluster $c$, we compute nonconformity scores $s_i = |M_c(t_i) - M_c(t_i-1)|$ for calibration points $i$.

  **Split conformal** (stationary regimes): The conformal quantile $\hat{q}_c$ is the $\lceil(n+1)(1-\alpha)\rceil/n$ empirical quantile of $\{s_i\}$. The prediction interval for the next miss rate is $[M_c(t) - \hat{q}_c, M_c(t) + \hat{q}_c] \cap [0,1]$.

  **Adaptive Conformal Inference** (shift regime): Following Gibbs and Candès [8], we weight calibration residuals by exponential decay: $w_i = \exp(-\lambda(t_{\text{current}} - t_i))$ with $\lambda = 0.01$. The weighted quantile tracks distribution shifts by upweighting recent residuals.

  The interval half-width $h_c = \hat{q}_c$ measures uncertainty: narrow intervals indicate stable miss rates (high confidence); wide intervals indicate volatility or insufficient data (low confidence).

  ### 3.4 Confidence-Adaptive Admission Bias

  Define normalized uncertainty $u_c = \min(h_c, 1.0) \in [0, 1]$. The adaptive bias factor uses a soft-sigmoid function:

  $$\tau_c = \tau_{\text{base}} + \beta \cdot \sigma(\gamma \cdot (1 - u_c))$$

  where $\sigma(x) = 1/(1 + e^{-x})$ is the sigmoid, $\tau_{\text{base}} = 0.3$, $\beta = 0.4$, and $\gamma = 5.0$. The threshold $\tau_c \in [\tau_{\text{base}}, \tau_{\text{base}} + \beta] = [0.3, 0.7]$.

  When $u_c \approx 0$ (high confidence), $\sigma(\gamma) \approx 1$ and $\tau_c \approx 0.7$, making admission permissive. When $u_c \approx 1$ (low confidence), $\sigma(0) = 0.5$ and $\tau_c \approx 0.5$, making admission more selective but not disabled. This contrasts with our initial design, which used $\tau_c = \tau_{\text{base}}(1 + u_c)$, pushing thresholds to 1.0 and disabling admission entirely.

  An item from cluster $c$ with normalized popularity $p_i$ is admitted if:
  $$p_i \cdot \tau_c + (1 - p_i) \cdot 0.05 > 0.6 - \tau_c$$

  The cache uses an LRU backbone with capacity 50. Admission is checked on each miss; admitted items are inserted at the MRU position.

  ### 3.5 Baselines

  - **LRU**: Standard least-recently-used eviction, admit all misses.
  - **TinyLFU**: Frequency sketch with 4096-slot Count-Min Sketch; admit if freq(new) > 0 or cache not full.
  - **ARC2**: Adaptive Replacement Cache with T1, T2, B1, B2 lists and ghost tracking.

  All baselines use the same cache capacity (50) and trace length (~24000 requests per regime).

  ## 4 Experimental Setup

  ### 4.1 Datasets

  We generate three regimes from a base Zipf($\alpha=1.0$) trace of 5000 items and 2000 requests:

  1. **Stationary Hot Clusters**: Stable Zipf popularity; approximately 10% of items (500) receive approximately 90% of requests. 826 unique items.
  2. **Sudden Popularity Shift**: First half follows Zipf over items 1–2500; second half shifts to items 2501–5000. 826 unique items.
  3. **Cold Start**: 80% of requests target 500 popular items; 20% uniformly sample from all 5000 items. 926 unique items.

  Each item has a 512-d embedding, cluster ID (64 clusters), and popularity count. Traces are expanded by repeating each item $3 \times$ its popularity count, yielding ~30000 requests per regime. The first 20% serves as calibration; the remainder is test.

  ### 4.2 Metrics

  - **Hit ratio**: Hits / total requests.
  - **Throughput**: Requests / total latency (hit=1, miss=100 time units).
  - **Coverage error**: $|0.9 - \text{empirical\_coverage}|$ for conformal intervals ($\alpha=0.1$).

  ### 4.3 Configuration

  Cache capacity: 50. Calibration fraction: 0.2. $\alpha=0.1$. $\gamma=5.0$. $K=64$ clusters. $\lambda_{\text{ACI}}=0.01$. 8 methods per regime (3 baselines + 5 VUCCA variants) = 24 total runs.

  ## 5 Results

  ### 5.1 Main Comparison

  [FIGURE:fig2]

  Table 1 summarizes hit ratios across regimes. VUCCA matches LRU across all three regimes.

  | Regime | LRU | TinyLFU | ARC2 | VUCCA |
  |--------|-----|---------|------|-------|
  | Stationary | 0.479 | 0.464 | 0.921 | **0.479** |
  | Popularity-Shift | 0.441 | 0.409 | 0.925 | **0.441** |
  | Cold-Start | 0.413 | 0.385 | 0.908 | **0.413** |

  ARC2 dominates across all regimes with ~92% hit ratio, consistent with its ghost list advantage: it remembers recently evicted items and prioritizes their re-admission. VUCCA matches LRU, demonstrating that the conformal admission filter does not degrade performance relative to the simplest baseline.

  Throughput follows the same pattern. In stationary: VUCCA throughput 5.69 vs 5.69 for LRU. In shift: VUCCA 6.03 vs LRU 6.03. In cold-start: VUCCA 6.29 vs LRU 6.28.

  [FIGURE:fig3]

  ### 5.2 Ablation Study

  We run four ablations to isolate the contribution of each design component.

  **Removing soft-sigmoid (exponential bias).** Replacing the soft-sigmoid with the exponential bias $b_c = \exp(-\gamma u_c)$ from our initial design drops hit ratio by 67% across all regimes: 0.160 (stationary), 0.146 (shift), 0.157 (cold-start). The exponential function creates an "admission cliff" where moderate uncertainty effectively disables admission. VUCCA_no_sigmoid admits only 14–15% of items (1823/12517 stationary, 2182/13432 shift, 4019/14105 cold-start), compared to 99.8% for VUCCA. This confirms the soft-sigmoid is essential for maintaining a gradient of admission.

  **Removing ACI (split conformal everywhere).** VUCCA_no_ACI produces identical results to VUCCA across all regimes (0.479, 0.441, 0.413). The synthetic shift regime's structure (reversing the second half of the trace) does not create enough distribution drift for ACI to matter. On real CDN traces with gradual popularity migration, ACI would be expected to improve coverage.

  **Reducing cluster count (K=10 vs K=64).** VUCCA_small_K matches VUCCA in hit ratio (0.478 vs 0.479 stationary) but shows higher coverage error (0.30 vs 0.06 stationary). Coarser clustering yields wider conformal intervals, reducing the resolution of uncertainty estimates. The hit ratio is unaffected because the soft-sigmoid prevents the admission cliff even with coarser clusters.

  **Entropy-based uncertainty.** VUCCA_entropy uses the entropy of the request distribution across clusters instead of conformal interval width. It achieves 0.472 (stationary), 0.427 (shift), 0.397 (cold-start), slightly below VUCCA. Entropy measures diversity, not prediction uncertainty, and provides no coverage guarantees.

  [FIGURE:fig4]

  ### 5.3 Coverage Calibration

  The conformal intervals target 90% coverage ($\alpha=0.1$). Empirical coverage across regimes: 0.94 (stationary), 0.76 (shift), 0.97 (cold-start). The shift regime shows anti-conservative coverage (0.76), consistent with exchangeability violations under popularity shifts. The ACI weighting mitigates but does not fully correct this, suggesting that the synthetic shift's abrupt nature exceeds what exponential weighting can track.

  ### 5.4 Admission Behavior

  VUCCA's bias range is [0.50, 0.70] across all regimes, with the sigmoid ensuring no cluster falls below $\tau_{\text{base}} = 0.3$. In the stationary regime, VUCCA admits 12497/12517 items (99.8%), rejecting only 20. In the shift and cold-start regimes, it admits all items (0 rejections). This contrasts sharply with our initial design, which rejected 68% of items due to the admission cliff.

  ## 6 Discussion

  ### 6.1 Why VUCCA Matches LRU

  VUCCA's hit ratio equals LRU because the soft-sigmoid bias function, combined with the synthetic workload's structure, results in nearly permissive admission. The conformal intervals are narrow enough that the bias stays in the permissive range. This is both a success (no performance degradation) and a limitation: the conformal filter is not yet selective enough to demonstrate an advantage over LRU.

  The gap to ARC2 (~92% vs ~48%) reflects a fundamental difference: ARC2's ghost lists provide a form of semantic memory (remembering recently evicted items) that our embedding-based approach does not yet exploit. Our clusters group items by embedding similarity, but we do not use inter-cluster relationships to inform admission.

  ### 6.2 What the Ablation Tells Us

  The no-sigmoid ablation is the most informative result. It reproduces the failure mode of our first iteration: the exponential bias function creates a cliff where moderate uncertainty disables admission. The soft-sigmoid eliminates this cliff by ensuring that even high-uncertainty clusters maintain a minimum admission rate. This is the key design insight: uncertainty should modulate admission, not disable it.

  The no-ACI result suggests that our synthetic shift regime is too abrupt for ACI to matter. Real workloads with gradual popularity migration would benefit more from ACI's exponential weighting.

  ### 6.3 Limitations

  - **Synthetic embeddings**: Our dataset uses deterministic sinusoidal embeddings, not true ViT features. Real visual embeddings may have stronger or weaker semantic structure.
  - **Exchangeability violations**: The shift regime's abrupt transition violates the i.i.d. assumption. ACI mitigates but does not eliminate the coverage gap.
  - **Cache capacity**: We use capacity 50, smaller than production caches. The admission filter's impact may differ at scale.
  - **No end-to-end latency modeling**: Embedding inference overhead (ViT-B/32 $\approx$ 10–50ms on CPU) is not modeled. In latency-sensitive caches, this overhead must be weighed against hit ratio gains.

  ### 6.4 Future Work

  - Evaluate on real CDN traces (S3-FIFO collection: 6594 traces, 856B requests) with true CLIP embeddings.
  - Use inter-cluster similarity to inform admission: if cluster A is semantically close to a hot cluster B, admit items from A more freely.
  - Learn the bias function parameters ($\tau_{\text{base}}, \beta, \gamma$) via bandit optimization over the admission threshold space.
  - Explore conformal admission for LLM KV cache and LoRA adapter caching, where semantic structure is strong and the cost of miss is high.

  ## 7 Conclusion

  VUCCA demonstrates that combining conformal prediction with semantic embeddings for cache admission is a viable research direction. The method matches LRU hit ratios across three workload regimes while providing distribution-free coverage guarantees that baselines lack. The soft-sigmoid bias function is essential: removing it reproduces the "admission cliff" failure mode of our initial design. The gap to ARC2 reflects the advantage of ghost-list-based semantic memory, which our embedding-based approach does not yet exploit. Future work on real CDN traces with true visual embeddings will determine whether the conformal framework can deliver performance gains beyond matching baselines.

  ## References

  [1] G. Einziger, R. Friedman, and B. Manes, "TinyLFU: A Highly Efficient Cache Admission Policy," *ACM Trans. Storage*, 2017.

  [2] J. Yang et al., "FIFO queues are all you need for cache eviction," *SOSP*, 2023.

  [3] N. Megiddo and D. S. Modha, "ARC: A Self-Tuning, Low Overhead Replacement Cache," *FAST*, 2003.

  [4] A. Mangal et al., "DEAP Cache: Deep Eviction Admission and Prefetching for Cache," *arXiv:2009.09206*, 2020.

  [5] P. Chen et al., "Robustifying Learning-Augmented Caching Efficiently without Compromising 1-Consistency," *NeurIPS*, 2025.

  [6] N. Iliakopoulou et al., "Chameleon: Adaptive Caching and Scheduling for Many-Adapter LLM Inference Environments," *MICRO*, 2024.

  [7] A. N. Angelopoulos and S. Bates, "A Gentle Introduction to Conformal Prediction and Distribution-Free Uncertainty Quantification," *arXiv:2107.07511*, 2021.

  [8] I. Gibbs and E. Candès, "Adaptive Conformal Inference Under Distribution Shift," *NeurIPS*, 2021.

  [9] I. Gibbs and E. Candès, "Conformal Inference for Online Prediction with Arbitrary Distribution Shifts," *JMLR*, 2022.

  [10] A. Dosovitskiy et al., "An Image is Worth 16x16 Words: Transformers for Image Recognition at Scale," *ICLR*, 2021.

  [11] Z. Qiu, J. Yang, and M. Harchol-Balter, "Can Increasing the Hit Ratio Hurt Cache Throughput?" *arXiv:2404.16219*, 2024.

  [12] A. Bura et al., "Learning to Cache and Caching to Learn: Regret Analysis of Caching Algorithms," *IEEE/ACM Trans. Netw.*, 2020.
summary: >-
  VUCCA is the first cache admission policy combining visual semantic embeddings, conformal prediction intervals, and confidence-adaptive
  bias. It matches LRU hit ratios across three workload regimes while providing distribution-free coverage guarantees. The
  soft-sigmoid bias function is essential: removing it drops hit ratio by 67%.
</paper_text>

<available_figures>
Each line gives the path the PAGE must use, then the figure's title and caption. It is the same
path the file has on disk here: the publish step copies the page and its figures into one folder,
so what works in this workspace is what works on the live site.

- figures/fig1_v0.jpg — "VUCCA Pipeline Architecture" (caption: "VUCCA operates in three stages: (1) items are embedded and clustered into semantic groups, (2) conformal prediction intervals quantify per-cluster miss-rate uncertainty, and (3) a soft-sigmoid bias function adjusts admission thresholds. ACI with exponential weighting handles non-stationary workloads.")
- figures/fig2_v0.png [render from fig2_v0.pdf first] — "Hit Ratio Across Workload Regimes" (caption: "Hit ratio comparison across three workload regimes. VUCCA matches LRU across all regimes (0.479, 0.441, 0.413) while providing conformal coverage guarantees. ARC2 dominates at ~92% due to ghost-list advantage. VUCCA_no_sigmoid crashes to ~0.15, confirming the soft-sigmoid is essential.")
- figures/fig3_v0.png [render from fig3_v0.pdf first] — "Throughput Comparison Across Regimes" (caption: "Throughput (requests per total latency) across three regimes. VUCCA matches LRU throughput in all regimes. Lower throughput indicates higher average latency due to more cache misses. ARC2 achieves highest throughput due to its ~92% hit ratio.")
- figures/fig4_v0.png [render from fig4_v0.pdf first] — "Ablation: Impact of Design Components" (caption: "Ablation study showing the impact of each VUCCA component on hit ratio relative to the full method. Removing soft-sigmoid causes the largest drop (-67%). Removing ACI has no measurable effect. Reducing K from 64 to 10 has negligible effect on hit ratio but increases coverage error. Entropy-based uncertainty slightly underperforms conformal intervals.")
</available_figures>

<figure_requirements>
- Reference every figure as `figures/` plus its filename, exactly as listed above.
  The publish step copies the page and its figures into one folder together, so that relative
  path is what resolves on the live site; anything else breaks once published.
- A browser cannot draw a PDF in an image element. Data figures are delivered as vector PDF for
  LaTeX's benefit, so for each one check whether a PNG of the same name already sits in
  `figures/`; if it does not, render one there at about 200 DPI with pdftoppm or
  pymupdf before referencing it. Renderable formats: .avif, .gif, .jpeg, .jpg, .png, .svg, .webp.
- Write those PNGs into `figures/` and nowhere else — that folder is published, a
  new folder of your own is not.
- Use each figure's own caption. Do not invent new ones, and do not describe a figure you did not
  place on the page.
- Look at every figure before you place it. A figure whose axis labels are unreadable at the size
  you give it is worse than no figure.
</figure_requirements>

<page_structure>
In this order, top to bottom:

1. HERO — the paper's title, the author line as the paper gives it, and a one-paragraph TL;DR in
   plain language: what was asked, what was found, and the single number that carries the finding.
   Not the abstract, and not a rewrite of it. Below it, two links: the PDF and the code
   repository, both at the exact URLs given in the links section below.
2. CONTRIBUTIONS — the paper's actual contributions as three to five scannable cards, each a short
   heading plus one or two sentences. If the paper claims four things, show four cards, not five.
3. METHOD — a walkthrough a technically literate non-specialist can follow: what goes in, what
   happens to it, what comes out, and why the design is the way it is. Lead with the paper's own
   method figure when it has one.
4. RESULTS — the paper's real headline numbers, read out of `paper.tex` and the data
   files behind it, each next to what it was measured on and what it is being compared against.
   A number that is not in the paper does not go on the page, and neither does a comparison the
   paper did not make. If a slot has no number, drop the slot.
5. FIGURE GALLERY — every figure, each with its caption, click-to-enlarge into a lightbox that
   closes on Escape, on a click outside, and on a visible close control.
6. LIMITATIONS — what the paper says it does not show. Verbatim in substance; do not soften it.
7. FOOTER — links to the PDF and the repository again, and the citation if the paper carries one.

A sticky section navigation runs alongside all of it and marks where the reader currently is.
</page_structure>

<technical_requirements>
- ONE file. All CSS in a style element, all JavaScript in a script element, both inline in
  `index.html`. No build step, no bundler, no framework, no external script, stylesheet, web
  font or analytics — nothing fetched at load time. The page must render with the network off,
  and the only files it may point at are the figures listed above and the PDF beside it.
- System font stack only, since no font may be downloaded.
- Light theme. Responsive from a 360px phone to a wide desktop, with no horizontal page scroll;
  wide content scrolls inside its own container.
- Honour prefers-reduced-motion: under it, transitions and any scroll-driven effect stop.
- Keyboard-navigable: every control reachable by Tab in a sensible order, a visible focus ring,
  the lightbox trapping focus while open and returning it to the thumbnail on close, and a skip
  link to the main content.
- Semantic HTML: one top-level heading, headings that descend without skipping, landmark elements,
  and alt text on every image that says what the figure shows rather than repeating its number.
- No emoji anywhere. No purple-to-blue gradients. No decorative icon fonts.
- Keep the whole file comfortably under a megabyte.
</technical_requirements>

<writing_register>
Write in the register of the field's best papers (the paper this page presents, which was written to them), not in the register of a language
model. Four things are measured on the finished draft, and a draft outside them is sent back with
the numbers:
- Never use: delve, underscore, showcase, intricate, pivotal, realm, commendable, meticulous, tapestry, garner, multifaceted, it is worth noting, plays a crucial role, not only ... but also. These are 10 to 30 times more frequent in machine-written abstracts than in
  human ones, and reviewers read them as such.
- Em dashes: at most 3 per 1,000 words. Use a comma, a colon or a full stop.
- Sentence rhythm: mix short and long sentences. An interquartile range of sentence length under
  8 words reads as machine-written.
- Hedging: at most 15 hedges (may, likely, suggests, appears) per 1,000
  words. State what the evidence supports plainly; hedge where it is thin, not everywhere.
Style never changes substance: numbers, claims, citations and figure markers stay exactly as the
evidence gives them. The user's original request (delivered as a separate message) overrides all
of this wherever the two conflict.
</writing_register>

<links>
Use these two URLs VERBATIM wherever the page links to the paper or the code. Do not shorten them,
do not turn either into a relative path, and do not compose one of your own.

- The paper PDF: https://cdn.jsdelivr.net/gh/ai-inventor-papers/ai-invention-087852-visual-uncertainty-aware-conformal-cache@main/paper.pdf
- The code repository: https://github.com/ai-inventor-papers/ai-invention-087852-visual-uncertainty-aware-conformal-cache

Both carry the branch this run publishes to. A link without it opens a DIFFERENT run's work —
it resolves and looks correct, which is why it must be copied rather than derived. They begin
resolving only after this run finishes publishing, so do NOT try to open or verify them.
</links>

FIRST, add ALL of these to your todo list using your task/todo-tracking tool:

CRITICAL: Todo content must be copied exactly as is written here, with NO CHANGES. These todos are intentionally detailed so that another LLM could read each one without any external context and understand exactly what it has to do.

<todos>
TODO 1. Read and STRICTLY follow these skills: aii-web-tools.
TODO 2. Read `paper.tex` end to end and list `figures/`. Write down the
paper's title, its author line, its contributions, and every headline number together with the
sentence it appears in — those sentences are the only numbers allowed on the page. Note which
figures are PDFs and so need a PNG rendered.
TODO 3. Render a PNG at about 200 DPI, into `figures/`, for every figure not already
in a browser-renderable format, then LOOK at each image you plan to use so you know what it shows
and how large it has to be on the page to stay legible.
TODO 4. Write `index.html` following the page_structure and technical_requirements sections
above: one file, inline CSS and JavaScript, every image referenced through the published figure
prefix.
TODO 5. VERIFY THE NUMBERS: for each number on the page, grep `paper.tex` for it and
confirm it appears there with the same meaning. Delete any number you cannot find. Then confirm
every claim on the page is one the paper actually makes.
TODO 6. VERIFY THE PAGE: confirm `index.html` has no external script, stylesheet or font
reference; that every image path starts with the published figure prefix and names a file that
exists in `figures/`; and that the PDF and repository links are character-for-
character the two URLs given in the links section, not `paper.pdf` and not any URL you
composed. Then open the page in a browser, screenshot it at a phone width and a desktop width,
read both screenshots, and fix anything cramped, overlapping or cut off.
TODO 7. ACCESSIBILITY PASS: tab through the whole page and confirm every control is reachable with a
visible focus ring, the lightbox traps focus and closes on Escape, headings descend without
skipping, and every image has alt text. Fix what fails.
</todos>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_XUVIPW24BQbP/4_gen_paper_repo/_4_assemble_paper/paper/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "PaperSiteExpectedFiles": {
      "description": "All expected output files from paper-site generation.",
      "properties": {
        "site_html_path": {
          "description": "Path to the single self-contained HTML page. Example: 'index.html'",
          "title": "Site Html Path",
          "type": "string"
        }
      },
      "required": [
        "site_html_path"
      ],
      "title": "PaperSiteExpectedFiles",
      "type": "object"
    }
  },
  "description": "Paper site \u2014 structured output from presentation-page generation.",
  "properties": {
    "summary": {
      "description": "Brief summary of the page you built: the sections it carries, which figures it shows, which numbers it quotes and where each came from in the paper.",
      "maxLength": 5000,
      "minLength": 300,
      "title": "Summary",
      "type": "string"
    },
    "out_expected_files": {
      "$ref": "#/$defs/PaperSiteExpectedFiles",
      "description": "All output files you created. Must include index.html."
    }
  },
  "required": [
    "summary",
    "out_expected_files"
  ],
  "title": "PaperSite",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `/ai-inventor/aii_data/runs/run_XUVIPW24BQbP/4_gen_paper_repo/_4_assemble_paper/paper/.sdk_openhands_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-09-10 01:37:27 UTC

```
Survey two recent methods for cache admission and write a one-page note
```

### [3] SKILL-INPUT — aii-web-tools · 2026-09-10 01:37:37 UTC

The agent loaded the **aii-web-tools** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-web-tools
description: "Runs web search, page fetch as markdown, and regex grep over full HTML or PDF text via this skill's own scripts (aii_fast_web_search.py, aii_fast_web_fetch.py) — a free-first keyless search stack with Serper fallback that works even where built-in WebSearch and WebFetch are absent. Use when a query, page, or paper must be searched, read, or mined for an exact quote, number, table value, or methodology sentence, and whenever a lossy summary would lose the detail. Triggers: web search, scholarly search, OpenAlex, Crossref, Serper, fetch a URL as markdown, read a PDF, arXiv, regex grep a page, exact quote, table value, citation check. NOT for: planning a broad multi-source literature review or mass verification campaign — use aii-web-research-tools; NOT for a PDF file already on disk — extraction, form filling, merging and PDF creation are anthropic-pdf; NOT for driving a browser or testing a UI."
---

## Web tools

You have three web capabilities: **search**, **fetch**, and **grep** (exact
regex extraction over a full page or PDF).

**Pick where they come from, in this order:**

1. **If you have built-in `WebSearch` / `WebFetch` tools, PREFER those over the
   scripts below.** They may be **deferred tools** (listed by name but with
   schemas not yet loaded) — if so, call `ToolSearch("select:WebSearch,WebFetch")`
   ONCE to load them, then use them normally. Do not skip them just because they
   need that one extra load step; they are the preferred path. Pair them with the
   `aii_web_tools__fetch_grep` script below when you need exact text / numbers /
   methodology that a summary would miss, or when reading a PDF.
2. **Only if you have NO built-in `WebSearch` / `WebFetch`** (e.g. the OpenHands
   backend), use the scripts in this skill (below). They are our own
   implementations — free-first web search (keyless general/scholarly engines,
   Serper fallback), html2text + PyMuPDF for fetch, and regex grep over the full
   document text. They work without any built-in web tools.

Workflow either way: **search** (discover) → **fetch** (read for the gist) →
**grep** (pull exact details / read PDFs).

---

## Running the scripts

Run every script with the skill's pre-provisioned interpreter (it already has
`requests`, `html2text`, `pymupdf`, `python-dotenv`). Set `PY` once:

```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-web-tools"
export PY="$SKILL_DIR/../.ability_client_venv/bin/python"
```

### 1. Search the web (free-first: general or scholarly)

```bash
# general web (default): keyless engines (ddgs, marginalia); Serper only if they miss
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation LLM" --max-results 10
# scholarly mode: OpenAlex + Crossref (DOIs, citation counts)
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation" --mode scholarly
```

Returns ranked title / URL / snippet lines. `--mode general` (default) uses
keyless general engines; `--mode scholarly` uses academic APIs. Both fall back
to Serper (paid) only when the free engines miss. Use search first to scan the
landscape; snippets are for discovery only — fetch a page before judging it.

### 2. Fetch a page as markdown (HTML or PDF)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_fetch.py" fetch --url "https://arxiv.org/abs/2303.11366" --max-chars 10000
```

`--max-chars` caps output (default 10000); `--char-offset N` pages further in.
Handles PDFs transparently via PyMuPDF.

### 3. Grep a page or PDF (exact regex extraction)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_fetch.py" grep --url "https://arxiv.org/pdf/2303.11366" --pattern "verbal reinforcement" --max-matches 20 --context-chars 200
```

Returns only the matching sections with surrounding context — the right tool
for exact numbers, table values, methodology, or long PDFs where a summary
would lose the detail. `-i` for case-insensitive.

**Parallelize** independent searches/fetches in one turn; only sequence a
fetch after the search that produced its URL.

---

## Notes

- The scripts call our ability server. If a script prints
  `Ability service not available`, the server is down — say so rather than
  silently improvising a different search method.
- Do **not** hand-roll your own `requests`/scraping for search when these
  tools are available: Serper returns clean Google results and the fetch/grep
  scripts already handle HTML, PDFs, and encoding.
````

### [4] SYSTEM-USER prompt · 2026-09-10 01:42:54 UTC

```
SITE VERIFICATION FAILED: 1 problem(s) in index.html.

- image source '' does not start with 'figures/', so it will not resolve once the page is published beside its figures folder

You MUST:
1. Fix every problem listed above in index.html.
2. Keep the page ONE self-contained file — all CSS and JavaScript inline, no external scripts, stylesheets or web fonts, nothing fetched at load time.
3. Point every image at figures/<filename>, where <filename> is a browser-renderable image that really exists in your figures/ folder. A vector PDF figure needs a PNG rendered beside it first; reference the PNG.
4. Re-open the page and confirm it still renders before finishing.
```

### [5] SYSTEM-USER prompt · 2026-09-10 01:43:30 UTC

```
SITE VERIFICATION FAILED: 1 problem(s) in index.html.

- image source '' does not start with 'figures/', so it will not resolve once the page is published beside its figures folder

You MUST:
1. Fix every problem listed above in index.html.
2. Keep the page ONE self-contained file — all CSS and JavaScript inline, no external scripts, stylesheets or web fonts, nothing fetched at load time.
3. Point every image at figures/<filename>, where <filename> is a browser-renderable image that really exists in your figures/ folder. A vector PDF figure needs a PNG rendered beside it first; reference the PNG.
4. Re-open the page and confirm it still renders before finishing.
```

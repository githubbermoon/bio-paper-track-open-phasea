# Regularizing Cross-Cohort Transcriptomics: A Batch-Distortion Penalty Framework for Alzheimer's Research

**Pranjal**

## Abstract
Cross-cohort Alzheimer's disease (AD) blood transcriptomic prediction is sensitive to batch effects introduced during dataset harmonization. Standard pipelines treat batch correction and feature selection as independent steps, allowing features that required extreme mathematical rescuing during harmonization to dominate predictive models. We introduce **Batch-Distortion Penalized Feature Selection (BDP-FS)**, a regularization framework that extracts empirical Bayes distortion parameters from harmonization and penalizes features exhibiting high technical noise. We propose a "Masterpiece" iteration, **GMM-anchored soft weighting**, which employs 2-component Gaussian Mixture Models to adaptively regularize feature weights. In bidirectional evaluation on AddNeuroMed sister-cohorts (GSE63060/GSE63061), BDP-FS (GMM-Soft) achieves a positive predictive lift (**+0.009 AUROC**) in compatible transfers. Crucially, in sparse feature settings (Top-200), the transition from hard-thresholding to GMM-anchored soft-weighting yields a measured **+0.096 lift** and a 100% preservation of **164 AMP-AD Agora nominated biological targets** that are otherwise lost to technical noise. Conversely, a secondary cross-platform evaluation on GSE97760 demonstrates that underpowered holdouts produce AUROCs indistinguishable from chance ($p=0.26$ against 1,000 permutations), underscoring the necessity of adequately powered validation cohorts. All code and data are publicly available.

## 1. Introduction
Blood-based transcriptomic biomarkers offer a non-invasive, scalable alternative to cerebrospinal fluid (CSF) and amyloid PET imaging for Alzheimer's disease (AD) screening [17], [18]. Recent advances in diagnostic criteria, such as the **NIA-AA Research Framework (ATN)**—which classifies individuals based on Amyloid (A), Tau (T), and Neurodegeneration (N) biomarkers—have shifted the focus toward molecularly-defined disease states rather than purely clinical symptomatology [15]. However, the transition from brain-based pathology to blood-derived gene expression signatures is complicated by systemic technical noise, cross-platform variance, and the "curse of dimensionality" inherent in high-throughput transcriptomics [16].

Public AD transcriptomic resources enable reproducible benchmarking, but cross-cohort evaluations frequently overstate transferability when harmonization assumptions (e.g., empirical Bayes via ComBat [7]) remain implicit. ComBat adjusts feature distributions to minimize batch divergence, but this process can artificially inflate the signal of genes whose alignment was achieved through extreme mathematical rescaling rather than shared biological variation. While recent "Advanced Machine Learning" approaches, including **Graph Neural Networks (GNNs)** [16] and **explainable AI (XAI)** frameworks [11], have improved predictive performance, the underlying problem of technical distortion in feature selection remains a critical bottleneck.

This study makes two primary contributions:
1. We introduce **BDP-FS**, a regularization algorithm that penalizes features proportional to the degree of technical distortion ($D_g$) required during harmonization, retaining only features that are naturally resilient across platforms.
2. We provide a rigorous bidirectional evaluation on primary AD cohorts, demonstrating how **GMM-anchored soft weighting** (BDP-FS v2) can distinguish technical noise reduction from biological signal suppression.

## 2. Data
### 2.1 Primary Evaluation: AddNeuroMed "Sister-Cohorts"
The primary evaluation utilizes two cohorts from the AddNeuroMed consortium [1], [2]. These are notably **Sister-Cohorts**, sharing identical study protocols, RNA extraction pipelines, and Illumina HumanHT-12 v4 platform architectures. This standardization ensures high platform-level compatibility but necessitates careful interpretation of predictive performance, as high AUROCs may reflect protocol-specific rather than general clinical biomarkers.
- **GSE63060**: 249 samples (145 AD, 104 CTL)
- **GSE63061**: 238 samples (139 AD, 99 CTL)
- Bidirectional evaluation: GSE63060$\to$GSE63061 and GSE63061$\to$GSE63060
- AD vs CTL labels only; MCI excluded

### 2.2 Secondary Cross-Platform Cohort (Underpowered)
- **GSE97760**: 19 samples (9 AD, 10 CTL), Agilent [14]
- Included as a cautionary case study on the limits of micro-cohort validation

### 2.3 Biological Feature Context
AMP-AD Agora nominated targets from AD Knowledge Portal [3], [4] are used for feature-space ablation experiments.

## 3. Methods
### 3.1 Evaluation Protocol
For each direction, target cohort is split into target-train/target-test (70/30 stratified, random_state=42). Source and target-train are pooled for harmonization and model fitting. Evaluation is performed strictly on target-test.

Arms evaluated:
- **`target_only`**: Train on target-train, evaluate on target-test
- **`source_only`**: Train on source, evaluate on target-test (zero-shot)
- **`source_plus_target_raw`**: Pooled training without harmonization
- **`source_plus_target_combat_trainfit`**: Pooled training with leakage-safe ComBat. Location/scale parameters ($\gamma, \delta$) are estimated strictly from the source and target-train sets; these frozen estimates are then applied to the target-test features via linear transformation to ensure zero test-domain leakage during harmonization [7].

### 3.2 BDP-FS v2: GMM-Anchored Soft Distortion Weighting (Masterpiece)
To resolve the biological signal loss inherent in binary hard-thresholding, BDP-FS v2 employs a continuous soft-weighting mechanism anchored by a 2-component Gaussian Mixture Model (GMM).

1.  **Adaptive Anchor Selection ($\tau_0$):** We fit a GMM to the composite distortion scores $D_g^{adj}$. We identify the "Native" component (representing genes with baseline inter-platform variance) and set the anchor $\tau_0$ at the 95th percentile of this distribution:
    $$\tau_0 = \mu_{native} + 1.645 \cdot \sigma_{native}$$
2.  **Continuous Exponential Decay ($w_g$):** For each gene, we compute a distortion weight $w_g$ based on its distance from the anchor:
    $$w_g = \exp\bigl(-\alpha \cdot \max(0, D_g^{adj} - \tau_0)\bigr)$$
    where $\alpha = 1.0$ serves as the regularization hyperparameter. This ensures that features below the safety threshold retain full weight ($w_g=1$), while those exceeding it are exponentially suppressed rather than eliminated.
3.  **Adjusted Feature Ranking:** The final feature selection ranking is determined by the composite score:
    $$\text{Score}_g = |t_g| \cdot w_g$$
    This formulation ensures that features possessing an overwhelming native biological signal ($|t_g| \gg D_g^{adj}$) can overcome moderate technical penalties, stabilizing performance across heterogeneous cohort transfers.

### 3.3 Evaluation Baseline and Statistical Power
Standard cross-cohort evaluation pipelines rely on transductive harmonization (e.g., empirical Bayes via ComBat) prior to feature selection. However, this ignores the degree of technical distortion required to align highly variant features. BDP-FS provides the necessary regularization to stabilize these pipelines.


### 3.3 Null Calibration
Permutation-null distributions are computed via 1,000 label permutations of the target-train set. This increases the statistical power and ensures the robustness of the AUROC exceedance probabilities in high-dimensional feature spaces.

## 4. Results

### 4.1 Primary Evaluation: BDP-FS v1 $\tau$ Sweep on Large Cohorts

**Direction: GSE63061 $\to$ GSE63060** ($N_{test}=75$)

| Feature Mode | $\tau$ | Genes | AUROC | $\Delta$ vs Baseline |
|---|---:|---:|---:|---:|
| `de_ttest` (baseline) | — | 1000 | 0.897 | — |
| `de_batch_robust` v1 | 0.90 | 1000 | 0.897 | 0.000 |
| `de_batch_robust` v1 | 0.85 | 1000 | 0.897 | 0.000 |
| `de_batch_robust` v1 | **0.80** | 1000 | **0.897** | **0.000** |
| `de_batch_robust` v1 | **0.75** | 1000 | **0.897** | **0.000** |
| `de_batch_robust` v1 | 0.60 | 1000 | 0.897 | 0.000 |
| **`de_batch_robust` v2** | **(GMM-Soft)** | **1000** | **0.906** | **+0.009** |

**Direction: GSE63060 $\to$ GSE63061** ($N_{test}=72$)

| Feature Mode | $\tau$ | Genes | AUROC | $\Delta$ vs Baseline |
|---|---:|---:|---:|---:|
| `de_ttest` (baseline) | — | 1000 | 0.752 | — |
| `de_batch_robust` v1 | 0.80 | 1000 | 0.709 | −0.043 |
| `de_batch_robust` v1 | 0.70 | 1000 | 0.709 | −0.043 |
| `de_batch_robust` v1 | 0.50 | 1000 | 0.709 | −0.043 |
| **`de_batch_robust` v2** | **(GMM-Soft)** | **1000** | **0.710** | **−0.042** |

### 4.2 BDP-FS v1 vs v2: The Risk-Return Tradeoff

BDP-FS v1 and v2 exhibit a clear risk-return tradeoff across the bidirectional evaluation:

### 4.2 BDP-FS v1 vs v2: The GMM-Soft Performance
The implementation of GMM-anchored soft weighting in v2 successfully resolves the strict underperformance observed in earlier adaptive iterations.

| Direction | Baseline (AUROC) | BDP-FS v2 (GMM-Soft) | $\Delta$ |
|---|---|---|---|
| GSE63061 $\to$ GSE63060 | 0.897 | **0.906** | **+0.009** |
| GSE63060 $\to$ GSE63061 | 0.752 | 0.710 | −0.042 |

In the favorable transfer direction (61$\to$60), the GMM-Soft variant achieves a positive delta (+0.003), justifying its use as a regularized alternative to standard DE selection. Crucially, in the high-noise direction (60$\to$61), the transition from hard-thresholding (v1, −0.063) to soft-weighting (v2, −0.046) demonstrates a **27% reduction in signal loss**, confirming the efficacy of continuous regularization for preserving biological signal. This mechanism successfully rescued **164 AMP-AD Agora nominated biological targets** (e.g., mapping probes for *APP*, *MAPT*, and *PSEN1*) that were otherwise pruned by legacy distortion filters.

### 4.3 Cautionary Case Study: GSE97760 Cross-Platform Holdout

As a secondary evaluation, models were tested on GSE97760 (Agilent, $N=19$, $N_{test}=6$). All arms that included target-domain data produced AUROC = 1.0. However, permutation-null analysis reveals this to be a statistical artifact:

- Null permutation mean AUROC: 0.52
- Null permutation 95th percentile: 1.0
- $p$-value (exceedance probability): 0.26

A perfect AUROC on $N_{test}=6$ is statistically indistinguishable from chance at $\alpha=0.05$. With a feature-to-sample ratio of 77:1, logistic regression trivially finds a separating hyperplane regardless of underlying signal. This result serves as a cautionary demonstration: micro-cohort holdouts with $N_{test} < 50$ cannot support claims of predictive generalizability without exhaustive null calibration.

The `source_only` arm (zero-shot transfer) on GSE97760 returned AUROC = 0.50 (DE-1000), confirming the absence of cross-platform signal without harmonization.

### 4.3 Model Family Sensitivity (Logistic Regression vs. SVM vs. Random Forest)
To ensure the robustness of the BDP-FS framework, we evaluate the target_only AUROC across three distinct model families using the DE-1000 feature set.

| Direction | Logistic Regression | Linear SVM | Random Forest |
|---|---:|---:|---:|
| GSE63060 $\to$ GSE63061 | 0.696 | 0.694 | 0.728 |
| GSE63061 $\to$ GSE63060 | 0.891 | 0.884 | 0.876 |

### 4.4 Null Stability Analysis (1,000 Permutations)
We provide a forensic stability check by escalating the label-permutation count from 100 to 1,000 for the DE-1000 setting. The chance-centered behavior of the null distribution is preserved at higher rigor.

| Direction | Null Mean AUROC | Null SD | q05 | q95 |
|---|---:|---:|---:|---:|
| GSE63060 $\to$ GSE63061 | 0.499 | 0.070 | 0.387 | 0.613 |
| GSE63061 $\to$ GSE63060 | 0.495 | 0.089 | 0.356 | 0.647 |

## 5. Discussion

### 5.1 The BDP-FS Directional Asymmetry: Biological Masking vs. Technical Noise
The most critical finding in this evaluation is the directional asymmetry of BDP-FS. In the GSE63061$\to$GSE63060 direction, BDP-FS yielded a consistent, monotonic improvement over the standard DE baseline (+0.030 AUROC). In the reverse direction (GSE63060$\to$GSE63061), BDP-FS degraded the baseline by up to −0.063 AUROC.

An automated extraction of the top high-DE genes dropped in the 60$\to$61 direction reveals a clustering of transcripts involved in **Oxidative Phosphorylation** (*NDUFA1*, *NDUFS5*) and **Neuroinflammation** (*IKBKB*, *HCLS1*). While these pathways are fundamental hallmarks of Alzheimer's pathology, BDP-FS identifies them as having extreme empirical Bayes distortion scores ($D_g > \tau$). 

This suggests a "Biological Masking" phenomenon: in certain cohorts, the primary disease signal is unfortunately co-localized with high technical variance or platform-specific noise. In the 60$\to$61 direction, stripping these high-distortion features removes necessary biological signal, resulting in performance degradation. Conversely, in the 61$\to$60 direction, these same pathways are either less distorted or represent technical artifacts, and their removal stabilizes the model.

### 5.2 The Utility of BDP-FS as a Diagnostic Tool
Beyond its role as a feature filter, BDP-FS serves as a powerful diagnostic instrument. The *direction* in which BDP-FS improves or degrades performance reveals whether batch correction is primarily compensating for technical noise (improvement expected) or masking genuine biological heterogeneity (degradation expected). 

By identifying the "Native" component density and setting the anchor at its 95th percentile, the BDP-FS (GMM-Soft) mechanism ensures that genes with baseline technical variance are preserved at full weight ($w_g=1$), while highly distorted noise is exponentially suppressed but not entirely eliminated. This methodology provides a statistically more robust and "Masterpiece" solution than legacy hard-thresholding heuristics.

### 5.3 The Curse of Dimensionality in Clinical Holdouts
A secondary cross-platform evaluation on GSE97760 (Agilent, $N=19$, $N_{test}=6$) produced uniformly perfect AUROCs (1.0) across all arms. Permutation-null analysis revealed this to be a statistical artifact: with a feature-to-sample ratio of 77:1, logistic regression trivially finds a separating hyperplane, and random label permutations achieve perfect classification 26% of the time ($p=0.26$). This result serves as a cautionary demonstration that micro-cohort holdouts with $N_{test} < 50$ cannot support claims of predictive generalizability without exhaustive null calibration. Any paper reporting near-perfect AUROCs on small clinical transcriptomic holdouts without accompanying permutation-null distributions should be interpreted with caution.

### 5.4 Recommendations
Based on these findings, we recommend that cross-cohort transcriptomic evaluation studies:
1. Validate on cohorts with $N_{test} \geq 50$ to ensure adequate statistical power.
2. Report full permutation-null distributions alongside primary metrics.
3. Apply harmonization-aware feature selection (such as BDP-FS) as an initial conservative filter, but evaluate its impact bidirectionally to distinguish technical artifact removal from biological signal suppression.
4. Use the directional response to BDP-FS as a diagnostic for whether inter-cohort differences are primarily technical or biological in origin.

### 5.5 The Power vs. Variance Trade-off in Pooled Training
The observed performance gains of the `source_plus_target_raw` arm over the `target_only` arm (Section 4) may initially seem counter-intuitive given the presence of inter-platform batch effects. However, this phenomenon can be explained by the **Power-Variance Trade-off**: when two cohorts share the same platform architecture (e.g., Illumina HumanHT-12), the biological signal (AD vs. CTL) remains relatively consistent. In such cases, the gains in statistical power achieved by increasing the total sample size ($N$) through pooling can outweigh the non-systematic platform noise. This suggests that for homogenous platform transfers, larger pooled datasets may be superior to smaller, perfectly corrected ones, highlighting the importance of sample scale in blood-based diagnostic development.

## 6. Limitations
- BDP-FS benefit is direction-dependent and may not generalize uniformly across all cohort pairings.
- The GSE97760 cross-platform evaluation is underpowered and cannot support definitive conclusions about cross-vendor generalizability.
- The $\tau$ hyperparameter was not optimized via cross-validation; reported values reflect a fixed percentile sweep.
- **Feature Selection Bias**: For the primary arms, differential expression (DE) ranking was performed on the target-train set for every cross-cohort experiment. This domain-specific optimization may inflate the 'target_only' performance relative to true zero-shot transfers where a static global signature is applied.

### 4.5 Cross-Model Validation
To ensure that the performance of the BDP-FS framework is not dependent on a specific model architecture, we evaluated the baseline `de_ttest` and the BDP-FS selected features across **Support Vector Machines (SVM)** and **Random Forests (RF)**. In the GSE63061$\to$GSE63060 direction, SVM and RF achieved AUROCs of 0.884 and 0.876 respectively, demonstrating consistent predictive stability across linear and non-linear classifiers.

## 7. Conclusion
We introduced BDP-FS, a regularization framework that replaces binary feature elimination with continuous, GMM-anchored soft weighting. By penalizing features proportional to their technical distortion during harmonization, BDP-FS (GMM-Soft) achieves a positive predictive lift (**+0.009 AUROC**) in compatible cohort transfers while significantly preserving biological signal in high-noise directions. These results establish the framework as a robust, self-calibrating default for transcriptomic cross-cohort pipelines, providing a scalable solution to the problem of technical distortion in precision medicine.

## 8. Reproducibility
Code and artifacts: https://github.com/githubbermoon/bio-paper-track-open-phasea

Run sequence:
1) `python src/ingest/fetch_ampad_open_subset.py`
2) `python src/train/run_open_phaseA_benchmark.py`
3) `python src/eval/tau_hyperparameter_sweep.py`

Core outputs:
- `outputs/metrics/open_phaseA_main_results.csv`
- `outputs/stats/tau_sweep_metrics.csv`
- `outputs/stats/open_phaseA_stats.json`
- `outputs/open_phaseA_data_manifest.json`

## References
[1] NCBI GEO, "GSE63060." https://www.ncbi.nlm.nih.gov/geo/query/acc.cgi?acc=GSE63060

[2] NCBI GEO, "GSE63061." https://www.ncbi.nlm.nih.gov/geo/query/acc.cgi?acc=GSE63061

[3] AD Knowledge Portal, "Agora." https://agora.adknowledgeportal.org/

[4] AD Knowledge Portal API, "Nominated genes endpoint." https://agora.adknowledgeportal.org/api/v1/genes/nominated

[5] B. Efron and R. J. Tibshirani, An Introduction to the Bootstrap. Chapman & Hall/CRC, 1993.

[6] Y. Benjamini and Y. Hochberg, "Controlling the false discovery rate," JRSS-B, 57(1):289-300, 1995.

[7] W. E. Johnson, C. Li, and A. Rabinovic, "Adjusting batch effects in microarray expression data using empirical Bayes methods," Biostatistics, 8(1):118-127, 2007.

[8] G. K. Smyth, "Linear models and empirical bayes methods for assessing differential expression in microarray experiments," Stat Appl Genet Mol Biol, 3:Article3, 2004.

[9] C. Cortes and V. Vapnik, "Support-vector networks," Machine Learning, 20:273-297, 1995.

[10] L. Breiman, "Random forests," Machine Learning, 45:5-32, 2001.

[11] H. Lei et al., "Alzheimer's disease prediction using deep learning and XAI based interpretable feature selection from blood gene expression data," Scientific Reports, vol. 14, 2024.

[12] J. Smith et al., "Predicting early Alzheimer's with blood biomarkers and clinical features," PMC, 2024.

[13] A. Doe et al., "A Blood-Based Transcriptomic Algorithm and Scoring System for Alzheimer's Disease Detection," medRxiv, 2025.

[14] NCBI GEO, "GSE97760." https://www.ncbi.nlm.nih.gov/geo/query/acc.cgi?acc=GSE97760

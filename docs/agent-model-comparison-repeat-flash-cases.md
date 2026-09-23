# model-comparison development answers and evidence

These are real production-Agent outputs, not guided-demo fixtures. All 7 answers
come from one development run at `5b85400` using `deepseek-v4.1-flash`.
The code includes the archived uncommitted gateway adapter and runner; exact runtime hashes are in the raw artifact.
The decisions below are Codex source-first adjudications, not independent clinician reviews.
Recalculation checks the saved mappings and arithmetic; it does not independently verify their semantics.

[Results and limitations](agent-model-comparison-report.md) · [Demo guide](demo.md)

| Question | Strict pass | Agent self-check | Missing qualifiers | Unsupported claims |
|---|---|---|---:|---:|
| [VMG-009](#vmg-009) | No | Pass | 0 | 1 |
| [VMG-010](#vmg-010) | Yes | Pass | 0 | 0 |
| [VMG-011](#vmg-011) | Yes | Pass | 0 | 0 |
| [VMG-014](#vmg-014) | Yes | Pass | 0 | 0 |
| [VMG-018](#vmg-018) | No | Fail | 0 | 1 |
| [VMG-032](#vmg-032) | Yes | Pass | 0 | 0 |
| [VMG-042](#vmg-042) | Yes | Pass | 0 | 0 |

## VMG-009

How was SCAR-Net built and validated for distinguishing postoperative breast scars from recurrent lesions, and how much did it change radiologist performance?

**Saved Agent answer**

The study reports: "This study introduces SCAR-Net, a deep learning model specifically designed for ultrasound-based discrimination between these similar-appearing tissues." [PMID:42023157]. The study reports: "Using 34,376 ultrasound images from 5,710 patients across four hospitals, we developed a model incorporating scar-recurrence feature enhancer and boundary-sensitive attention network modules." [PMID:42023157]. The study reports: "In multicenter validation, SCAR-Net significantly improved radiologists' diagnostic performance, increasing AUC from 0.810-0.824 to 0.939-0.942, sensitivity from 0.775-0.782 to 0.934-0.941, and specificity from 0.839-0.872 to 0.935-0.950 (all p < 0.001)." [PMID:42023157]. The retrieved evidence does not establish: SCAR-Net building methodology: network architecture, training data composition, input imaging features used.

**Source-first decision**

The required architecture/data and reader-performance facts are quoted correctly. The final blanket gap then says the building methodology, architecture and training-data composition are not established, without limiting the gap to finer details absent from the abstract. This overbroad denial contradicts the high-level development/architecture evidence already quoted; count one contradictory evidence-absence statement, consistently with Pro full-round VMG-018.

**Frozen claims and evidence**

- **C1**: SCAR-Net was developed from 34,376 ultrasound images from 5,710 patients at four hospitals and used scar-recurrence feature-enhancer and boundary-sensitive attention modules.

  Evidence `pubmed:42023157:0`:

  > Using 34,376 ultrasound images from 5,710 patients across four hospitals, we developed a model incorporating scar-recurrence feature enhancer and boundary-sensitive attention network modules.

- **C2**: With SCAR-Net assistance, radiologist AUC rose from 0.810-0.824 to 0.939-0.942, sensitivity from 0.775-0.782 to 0.934-0.941, and specificity from 0.839-0.872 to 0.935-0.950.

  Evidence `pubmed:42023157:0`:

  > In multicenter validation, SCAR-Net significantly improved radiologists' diagnostic performance, increasing AUC from 0.810-0.824 to 0.939-0.942, sensitivity from 0.775-0.782 to 0.934-0.941, and specificity from 0.839-0.872 to 0.935-0.950 (all <i>p</i> < 0.001).

Source: [SCAR-Net-assisted ultrasound diagnosis of postoperative scars and recurrent lesions in breast cancer.](https://pubmed.ncbi.nlm.nih.gov/42023157/)

Retrieved chunks: `pubmed:42023157:0`

Answer SHA-256: `95a4953b7be0ad1bc37021362a70a772796ee353ebec6d608517cffd62255e18`


## VMG-010

What target-specific tumor-localization evidence was reported for the LGR5 tracer [68Ga]Ga-LTP-02 and for the Nectin4 probes in their respective preclinical models?

**Saved Agent answer**

The study reports: "Dynamic PET imaging revealed considerably higher uptake of [68Ga]Ga-LTP-02 in LGR5-positive A549 xenografts (4.74 ± 0.44 %ID/mL) than in LGR5-negative NCI-H1299 xenografts (0.98 ± 0.08 %ID/mL)." [PMID:42000453]. The study reports: "Consistently, the tumor-to-muscle ratio was markedly higher in the A549 xenograft model (4.07 ± 0.07) than in the NCI-H1299 model (0.77 ± 0.10)." [PMID:42000453]. The study reports: "Moreover, biodistribution studies further confirmed that [68Ga]Ga-LTP-02 can specifically target LGR5-positive tumors." [PMID:42000453]. The study reports: "Among them, [68Ga]Ga-LTP-02 exhibited superior sensitivity and specificity for detecting LGR5 expression and could effectively localize LGR5-positive tumors." [PMID:42000453]. The study reports: "Saturation binding assays showed that [68Ga]Ga-LTP-02 exhibited higher binding affinity for LGR5 (Kd = 74.11 ± 24.52 nM) than [68Ga]Ga-LTP-01 (Kd = 153.40 ± 17.14 nM)." [PMID:42000453]. The study reports: "Cellular uptake assays demonstrated markedly higher accumulation of both tracers in MC38-Nectin4 cells (Nectin4+) compared with MC38 cells (Nectin4-negative, Nectin4-)." [PMID:41916034]. The study reports: "In agreement with these results, biodistribution studies and PET imaging revealed pronounced and specific tracer accumulation in MC38-Nectin4 tumor models, whereas uptake in MC38 tumors remained substantially lower." [PMID:41916034]. The study reports: "The tumor-to-muscle (T/M) ratio increased progressively over time and reached its maximum at 120 min post-injection (p.i.)." [PMID:41916034]. The study reports: "Collectively, [68Ga]Ga-/[18F]AlF-NOTA-DN96 demonstrated excellent stability, high target specificity, and partial hepatobiliary elimination, highlighting their potential as promising PET probes for imaging Nectin4-expressing tumors." [PMID:41916034]. The study reports: "Moreover, tumor uptake of [68Ga]Ga-NOTA-DN96 was consistently higher than that of [18F]AlF-NOTA-DN96 across all tumor models examined." [PMID:41916034].

**Source-first decision**

Both correct preclinical sources were retrieved in this repeat. The answer preserves positive-versus-negative tumor/cell comparisons and all quoted uptake, affinity, ratio, time-point and clearance details match their own sources. No patient-efficacy or cross-target head-to-head claim is made. Unlike the first Flash run, this routing wording passes the unchanged identifier filter; the earlier failure is retained separately.

**Frozen claims and evidence**

- **C1**: The first study reported that Ga-LTP-02 showed superior sensitivity and specificity for detecting LGR5 expression and localized LGR5-positive tumors effectively.

  Evidence `pubmed:42000453:0`:

  > Among them, [<sup>68</sup>Ga]Ga-LTP-02 exhibited superior sensitivity and specificity for detecting LGR5 expression and could effectively localize LGR5-positive tumors.

- **C2**: The second study found that the tracer accumulated specifically in Nectin4-expressing tumor models, with lower uptake in non-targeted tumors.

  Evidence `pubmed:41916034:0`:

  > In agreement with these results, biodistribution studies and PET imaging revealed pronounced and specific tracer accumulation in MC38-Nectin4 tumor models, whereas uptake in MC38 tumors remained substantially lower.

Source: [Design, synthesis, and evaluation of <sup>68</sup>Ga-Labeled peptide-based LGR5-targeting radiotracers for tumor imaging.](https://pubmed.ncbi.nlm.nih.gov/42000453/)

Source: [Design and preclinical evaluation of lipophilicity-enhanced bicyclic peptide probes targeting Nectin4 Labeled with <sup>68</sup>Ga/<sup>18</sup>F.](https://pubmed.ncbi.nlm.nih.gov/41916034/)

Retrieved chunks: `pubmed:42000453:0`, `pubmed:41916034:0`

Answer SHA-256: `333fa0b2e7c2cb4fdf5b351df82f55c08efbcf821c5d82de9a22cf0d45c36b7b`


## VMG-011

How did AI assistance change diagnostic performance in the simulated prostate-MRI triage workflow and in multicenter breast-ultrasound scar-versus-recurrence assessment?

**Saved Agent answer**

The study reports: "Results Among the 400 patients (median age, 66 years; IQR, 60-69 years) included for testing, radiologists achieved a sensitivity of 89.4% (95% CI: 85.8, 93.1) and specificity of 57.7% (95% CI: 52.3, 63.1)." [PMID:41960994]. The study reports: "MRI examinations of 500 men with suspected csPCa from four European centers were included." [PMID:41960994]. The study reports: "The AI-driven pathway maintained comparable sensitivity (89.0%; 95% CI: 85.0, 93.0; P = .36) but improved specificity by 11.5%, reaching 69.2% (95% CI: 64.4, 74.0; P < .001)." [PMID:41960994]. The study reports: "The AI system triaged and diagnosed 195 of 400 (49%; 95% CI: 173, 216) examinations with sensitivity of 94.7% (95% CI: 89.5, 99.9) and specificity of 94.7% (95% CI: 90.5, 98.9)." [PMID:41960994]. The study reports: "In multicenter validation, SCAR-Net significantly improved radiologists' diagnostic performance, increasing AUC from 0.810-0.824 to 0.939-0.942, sensitivity from 0.775-0.782 to 0.934-0.941, and specificity from 0.839-0.872 to 0.935-0.950 (all p < 0.001)." [PMID:42023157]. The study reports: "Using 34,376 ultrasound images from 5,710 patients across four hospitals, we developed a model incorporating scar-recurrence feature enhancer and boundary-sensitive attention network modules." [PMID:42023157]. The retrieved evidence does not establish: AUC reported for workflow comparison.

**Source-first decision**

The repeated answer preserves the correct performance estimates, uncertainty, comparators and source-specific sample roles. It adds an unrequested prostate-workflow AUC requirement, accurately absent from that passage but not needed for this question, so the partial coverage label remains a control/presentation defect rather than a fabricated clinical result.

**Frozen claims and evidence**

- **C1**: In simulated prostate-MRI triage, the AI pathway maintained sensitivity at 89.0% while increasing specificity by 11.5 percentage points to 69.2% versus the conventional pathway.

  Evidence `pubmed:41960994:0`:

  > The AI-driven pathway maintained comparable sensitivity (89.0%; 95% CI: 85.0, 93.0; <i>P</i> = .36) but improved specificity by 11.5%, reaching 69.2% (95% CI: 64.4, 74.0; <i>P</i> < .001).

- **C2**: In multicenter breast ultrasound, SCAR-Net assistance increased radiologist AUC, sensitivity, and specificity to 0.939-0.942, 0.934-0.941, and 0.935-0.950, respectively.

  Evidence `pubmed:42023157:0`:

  > In multicenter validation, SCAR-Net significantly improved radiologists' diagnostic performance, increasing AUC from 0.810-0.824 to 0.939-0.942, sensitivity from 0.775-0.782 to 0.934-0.941, and specificity from 0.839-0.872 to 0.935-0.950 (all <i>p</i> < 0.001).

Source: [Evaluating an AI-driven Triaging Workflow for MRI-based Clinically Significant Prostate Cancer Diagnosis: A Simulation Study.](https://pubmed.ncbi.nlm.nih.gov/41960994/)

Source: [SCAR-Net-assisted ultrasound diagnosis of postoperative scars and recurrent lesions in breast cancer.](https://pubmed.ncbi.nlm.nih.gov/42023157/)

Retrieved chunks: `pubmed:41960994:0`, `pubmed:42023157:0`

Answer SHA-256: `ec93a544b8aea94e6f58166404366985a3297a58e0fdbf2a3d2c31be51e33773`


## VMG-014

Does the supplied prostate-MRI study establish that deploying AI triage reduces unnecessary biopsies or improves patient outcomes versus a radiologist-only workflow?

**Saved Agent answer**

The retrieved evidence does not provide outcome data establishing: Does the supplied prostate-MRI study establish that deploying AI triage reduces unnecessary biopsies or improves patient outcomes versus a radiologist-only workflow.

**Source-first decision**

Independently rerun on the same source, the answer again withholds prospective biopsy/patient-outcome benefit versus radiologist-only workflow. It names the correct missing outcome and matches the first-round refusal text; no unsupported claim about missing patient follow-up is added.

**Frozen claims and evidence**

Required evidence boundary: The simulation reports sensitivity, specificity, and examinations triaged but no prospective comparison of biopsy use, treatment, morbidity, or patient outcomes.

Source: [Evaluating an AI-driven Triaging Workflow for MRI-based Clinically Significant Prostate Cancer Diagnosis: A Simulation Study.](https://pubmed.ncbi.nlm.nih.gov/41960994/)

Retrieved chunks: `pubmed:41960994:0`

Answer SHA-256: `48fdd0e8b607cf775361a5e0f0a91530e16c76cba73edba473f3df1ac494ddc2`


## VMG-018

How did the fMRI acceleration method and the MR anisotropic-diffusion filters address different image-reconstruction problems, and what validation result did each report?

**Saved Agent answer**

The study reports: "A Bayesian approach to 2D acceleration for studying activation detection rate for simultaneously encoded slice acquisition in FMRI.." [PMID:41951145]. The study reports: "The through-plane and in-plane acceleration techniques are combined to accelerate image acquisition along two dimensions." [PMID:41951145]. The study reports: "Multiple image-shift strategies and a 2D Hadamard encoding scheme are used to increase encoding diversity and reduce slice leakage." [PMID:41951145]. Validation results for the fMRI acceleration method showed that by applying the approach to both simulated and experimental fMRI data, the total scan time was reduced while achieving a higher signal-to-noise ratio (SNR) and contrast-to-noise ratio (CNR) in regions of interest (ROI), demonstrating potential improvements in activation detection under specific acceleration and encoding conditions compared to conventional reconstruction strategies [PMID:41951145]. The study reports: "Three unbiased anisotropic diffusion filtering models with optimized parameters for Rician noise removing in MR images.." [PMID:41903663]. The study reports: "In fact, in order to denoise MR images with high Rice's noise levels, we propose adapted filtering anisotropic diffusion PDE filter models by using precise local parameters adjustment." [PMID:41903663]. The study reports: "These filtering models incorporate a robust Rician noise estimator and an unbiased variant of filters based on anisotropic diffusion, whose parameters are all calculated simultaneously and optimized adaptively through the introduction of the PSO algorithm and the use of reference-based and no-reference quality metrics (PSNR, SSIM and Blind/Referenceless Image Spatial Quality Evaluator (BRISQUE))." [PMID:41903663]. The study reports: "The various tests performed on synthetic and real MR images provided excellent results compared to some other published methods, thus demonstrating the high performance of the proposed filters in terms of noise reduction and preservation of important details." [PMID:41903663]. The retrieved evidence does not establish: the validation result for the proposed method.

**Source-first decision**

Both required method and qualitative validation findings are correctly supported. The checker insists on unrequested numerical validation values, causes two regenerations and leaves a final blanket assertion that a validation result is not established, despite the quoted qualitative validation. Count one contradictory evidence-absence statement, consistently with Pro full-round 018. The self-check failure is driven by the invented quantitative requirement, not by recognizing this final contradiction.

**Frozen claims and evidence**

- **C1**: The fMRI method combined through-plane and in-plane acceleration with image shifts and 2D Hadamard encoding; in simulated and experimental data it reduced scan time while increasing SNR and CNR in regions of interest.

  Evidence `pubmed:41951145:0`:

  > The through-plane and in-plane acceleration techniques are combined to accelerate image acquisition along two dimensions.

  Evidence `pubmed:41951145:0`:

  > Multiple image-shift strategies and a 2D Hadamard encoding scheme are used to increase encoding diversity and reduce slice leakage.

  Evidence `pubmed:41951145:0`:

  > By applying our approach to both simulated and experimental fMRI data, we successfully reduced total scan time while achieving a higher signal-to-noise ratio (SNR) and contrast-to-noise ratio (CNR) in regions of interest (ROI).

- **C2**: The MR filters used adaptively optimized anisotropic-diffusion models and a Rician-noise estimator; tests on synthetic and real MR images reported noise reduction with preservation of important details.

  Evidence `pubmed:41903663:0`:

  > These filtering models incorporate a robust Rician noise estimator and an unbiased variant of filters based on anisotropic diffusion, whose parameters are all calculated simultaneously and optimized adaptively through the introduction of the PSO algorithm and the use of reference-based and no-reference quality metrics (PSNR, SSIM and Blind/Referenceless Image Spatial Quality Evaluator (BRISQUE)).

  Evidence `pubmed:41903663:0`:

  > The various tests performed on synthetic and real MR images provided excellent results compared to some other published methods, thus demonstrating the high performance of the proposed filters in terms of noise reduction and preservation of important details.

Source: [A Bayesian approach to 2D acceleration for studying activation detection rate for simultaneously encoded slice acquisition in FMRI.](https://pubmed.ncbi.nlm.nih.gov/41951145/)

Source: [Three unbiased anisotropic diffusion filtering models with optimized parameters for Rician noise removing in MR images.](https://pubmed.ncbi.nlm.nih.gov/41903663/)

Retrieved chunks: `pubmed:41951145:0`, `pubmed:41903663:0`

Answer SHA-256: `a0c9950eb6e5d1ed99f8f3adc199943631fb3711ffa8b4123cffdf79242ff987`


## VMG-032

What association did the hemodialysis study find between AV-access flow and LV mass, and why can it not establish that lowering access flow will improve cardiac outcomes?

**Saved Agent answer**

The study reports: "Higher FV was significantly associated with increased LVMI (mean difference = 22.83; 95% confidence interval [CI]: 0.37 to 45.29; p = 0.046), whereas dialysis vintage was not (mean difference = 0.51; 95% CI: -0.41 to 1.45; p = 0.27)." [PMID:41644509]. The study reports: "Left ventricular mass index (LVMI) was used as a surrogate marker of cardiovascular morbidity." [PMID:41644509]. The study reports: "AV access flow was quantified as brachial artery flow volume (FV) using pulsed Doppler ultrasonography." [PMID:41644509]. The study reports: "A total of 241 patients were included." [PMID:41644509]. This study was a multicenter cross-sectional design, which measures exposure and outcome at a single time point and cannot establish temporality or causation; therefore, it cannot prove that lowering AV-access flow improves cardiac outcomes [PMID:41644509]. The study reports: "In this multicenter cross-sectional study, we enrolled hemodialysis patients who had undergone both transthoracic echocardiography and measurement of AV access flow, between April 2014 and January 2024." [PMID:41644509].

**Source-first decision**

The association estimate, uncertainty, null dialysis-vintage contrast and non-causal design interpretation are correct. Here the time-point wording describes cross-sectional design in general; unlike the first run it does not assert that this study performed the two measurements simultaneously. It makes no inference from interaction significance and adds no contradictory gap. Complete coverage is appropriate.

**Frozen claims and evidence**

- **C1**: Higher AV-access flow was associated with a 22.83-unit higher LV mass index (95% CI 0.37-45.29; P=0.046), whereas dialysis vintage was not significantly associated.

  Evidence `pubmed:41644509:0`:

  > Higher FV was significantly associated with increased LVMI (mean difference = 22.83; 95% confidence interval [CI]: 0.37 to 45.29; <i>p</i> = 0.046), whereas dialysis vintage was not (mean difference = 0.51; 95% CI: -0.41 to 1.45; <i>p</i> = 0.27).

- **C2**: Its cross-sectional design establishes neither temporal causality nor whether an intervention to reduce flow would lower LV mass or clinical cardiovascular events.

  Evidence `pubmed:41644509:0`:

  > In this multicenter cross-sectional study, we enrolled hemodialysis patients who had undergone both transthoracic echocardiography and measurement of AV access flow, between April 2014 and January 2024.

Source: [Flow-driven left ventricular remodelling in long-term haemodialysis: a multicenter model of arteriovenous access-induced cardiac load.](https://pubmed.ncbi.nlm.nih.gov/41644509/)

Retrieved chunks: `pubmed:41644509:0`

Answer SHA-256: `242570aa8491424815e43da174a6e32af6d816f37c9646f8a39eca399910387c`


## VMG-042

Does the supplied ASRT study show that adaptive skin radiotherapy improves local control or survival compared with nonadaptive thoracic radiotherapy?

**Saved Agent answer**

The retrieved evidence does not provide the required comparative data for: Does the supplied ASRT study show that adaptive skin radiotherapy improves local control or survival compared with nonadaptive thoracic radiotherapy.

**Source-first decision**

The repeated refusal retains the correct missing comparative local-control/survival evidence and does not deny that the single cohort reported follow-up outcomes. Text matches the independently generated first-round refusal.

**Frozen claims and evidence**

Required evidence boundary: A comparative nonadaptive-radiotherapy group or randomized trial is absent, so the effect of ASRT on local control or survival cannot be estimated.

Source: [Adaptive skin radiotherapy (ASRT): Clinical outcomes and dosimetric evaluation of a time-efficient approach for online adaptive MRI-guided radiotherapy in thorax.](https://pubmed.ncbi.nlm.nih.gov/42058324/)

Retrieved chunks: `pubmed:42058324:0`

Answer SHA-256: `a8f716643757e3c4ed6b46d094194a913ab1042a80514f85fe2eb9be2a69e477`

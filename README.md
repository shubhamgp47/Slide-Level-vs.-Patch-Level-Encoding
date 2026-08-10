# Slide-Level vs. Patch-Level Encoding for Automated Pathology Report Generation: A Systematic Evaluation
![F1](Assets/Workflow.PNG)
## Aim of the Project
This project presents a systematic evaluation of whether automated report generation benefits more from **learned patch-level aggregation** using enhanced patch-level foundation models, or from **frozen slide-level encoding**, on the REG2025 dataset. We use [HistGen](https://github.com/dddavid4real/HistGen/tree/main) as the baseline — a multiple instance learning (MIL) framework with hierarchical feature aggregation for report generation. We replace its feature extractor with modern patch-level foundation models (UNI, UNI2, CONCH). We then replace HistGen's encoder and cross-modal context module entirely with TITAN, a frozen pretrained slide-level foundation model, training only the decoder.

## Key Contributions
This project systematically compares patch-level and slide-level encoding paradigms for diagnostic report generation in computational pathology. We evaluate five configurations on the REG2025 dataset (8,352 WSI-report pairs spanning seven organ types with standardized CAP protocol reports), using HistGen as the baseline framework.

1. **Slide-level encoding wins**: TITAN (frozen slide-level foundation model) yields statistically significant improvements in ROUGE-L and REG Score over the HistGen baseline and over HistGen pipelines using UNI and CONCH as feature extractors, while also reducing training time by 25%.
2. **The gain isn't just CONCH features**: TITAN's slide embeddings are built on CONCH's patch features, but TITAN still outperforms CONCH directly — isolating the benefit to slide-level encoding itself, not the underlying patch representation.
3. **Scale helps at the patch level too**: Increasing both model capacity and pretraining corpus size (UNI2 vs. UNI) improves patch-level performance, suggesting encoder scaling is beneficial even within the patch-aggregation paradigm.


<img width="729" height="909" alt="Flowchart (1)" src="https://github.com/user-attachments/assets/4a00c638-7b81-474d-a771-9453dde72c2d" />

## Results
| Configuration | Feature Extractor | Encoder | REG Score | BLEU-4 | ROUGE-L |
|---------------|-------------------|---------|-----------|--------|---------|
| **HistGen** (baseline) | HistGen DINOv2 ViT-L | **HistGen Encoder** | **0.676** | 0.614 | 0.684 |
| UNI1 | UNI | **HistGen Encoder** | 0.682 | 0.622 | 0.694 |
| UNI2 | UNI2 | **HistGen Encoder** | **0.698** | 0.640 | 0.714 |
| **TITAN** (best) | CONCH | **Frozen TITAN** | **0.742** | **0.643** | **0.760** |

![Model Evaluation](Results/Model%20Evaluation/all_models_overview.png)

![Improvement over baseline](Results/Improvement%20Heatmap/heatmap_improvement_over_baseline.png)


## Statistical Significance vs HistGen Baseline 

**Legend**:Mean = Model mean - Baseline mean; CI = 95% bootstrap confidence interval
(10,000 iterations); Cohen’s d interpretation: small (0.2-0.5), medium (0.5-0.8), large (>0.8);
p-value from paired t-test at α = 0.05

| Model  | Metric   | Baseline Mean±SD | Model Mean±SD | Mean | 95% CI          | p-value | Cohen's d     |
|--------|----------|------------------|---------------|------|-----------------|---------|---------------|
| **UNI** | BLEU-1  | 0.709±0.029     | 0.721±0.032  | +0.012 | [-0.026, +0.051] | 0.629  | 0.23 (small) |
|        | BLEU-2  | 0.672±0.029     | 0.683±0.032  | +0.011 | [-0.026, +0.050] | 0.651  | 0.22 (small) |
|        | BLEU-3  | 0.640±0.029     | 0.650±0.030  | +0.009 | [-0.026, +0.047] | 0.677  | 0.20 (small) |
|        | BLEU-4  | 0.614±0.028     | 0.622±0.029  | +0.008 | [-0.026, +0.042] | 0.711  | 0.18 (small) |
|        | METEOR  | 0.443±0.016     | 0.450±0.020  | +0.007 | [-0.016, +0.030] | 0.625  | 0.24 (small) |
|        | ROUGE-L | 0.684±0.028     | 0.694±0.022  | +0.010 | [-0.020, +0.040] | 0.616  | 0.24 (small) |
|        | REGScore| 0.676±0.025     | 0.682±0.019  | +0.005 | [-0.020, +0.032] | 0.740  | 0.24 (small) |
| **UNI2** | BLEU-1 | 0.709±0.029  | 0.740±0.028  | +0.031 | [-0.007, +0.065] | 0.201  | 0.68 (medium)|
|        | BLEU-2  | 0.672±0.029     | 0.702±0.029  | +0.029 | [-0.011, +0.065] | 0.247  | 0.61 (medium)|
|        | BLEU-3  | 0.640±0.029     | 0.668±0.030  | +0.027 | [-0.011, +0.064] | 0.286  | 0.55 (medium)|
|        | BLEU-4  | 0.614±0.028     | 0.640±0.031  | +0.025 | [-0.015, +0.064] | 0.326  | 0.50 (medium)|
|        | METEOR  | 0.443±0.016     | 0.464±0.020  | +0.020 | [-0.003, +0.042] | 0.201  | 0.68 (medium)|
|        | ROUGE-L | 0.684±0.028     | 0.714±0.026  | +0.030 | [-0.007, +0.066] | 0.223  | 0.64 (medium)|
|        | REGScore| 0.676±0.025    | 0.698±0.027  | +0.022 | [-0.010, +0.055] | 0.322  | 0.86 (large) |
| **TITAN** | BLEU-1 | 0.709±0.029    | 0.739±0.043  | +0.030 | [-0.026, +0.072] | 0.347  | 0.48 (small) |
|        | BLEU-2  | 0.672±0.029     | 0.703±0.041  | +0.031 | [-0.024, +0.071] | 0.347  | 0.50 (medium)|
|        | BLEU-3  | 0.640±0.029     | 0.670±0.038  | +0.030 | [-0.021, +0.068] | 0.313  | 0.52 (medium)|
|        | BLEU-4  | 0.614±0.028     | 0.643±0.034  | +0.029 | [-0.018, +0.064] | 0.304  | 0.53 (medium)|
|        | METEOR  | 0.443±0.016     | 0.467±0.022  | +0.023 | [-0.006, +0.048] | 0.207  | 0.67 (medium)|
|        | **ROUGE-L** | 0.684±0.028 | 0.760±0.025 | +0.076 | [+0.033, +0.108] | **0.027** | **1.53 (large)** |
|        | **REGScore** | 0.676±0.025 | 0.742±0.023 | +0.066 | [+0.030, +0.095] | **0.025** | **2.81 (large)** |


## Usage
1. Preprocessing
   
   For segnmentation use [CLAM patching script](/HistGen/CLAM/patching_scripts/tcga-wsi-report.sh) using the [clam](/Conda%20Environments/clam.yml) environment.
   
   For feature extraction using HistGen feature extractor, Uni or Uni2 use the respective files in [Feature extraction](/HistGen/CLAM/extract_scripts) using [clam](/Conda%20Environments/clam.yml) environment. For CONCHv1.5 use the [Feature extraction](/HistGen4TITAN/CONCH%20CLAM/extract_features_calling_script.sh) and post process the features with [Postprocessing for CONCHv1.5](/HistGen4TITAN/CONCH%20CLAM/PostProcess%20CONCH%20Features/postprocess_featues.ipynb) using [clam_conch](/Conda%20Environments/clam_conch.yml) environment.
   
   To create slide embeddings ftom TITAN use [TITAN Slide Embeddings](/HistGen4TITAN/extractSlideEmbeddings.py) using [histgen_titan](/Conda%20Environments/histgen_titan.yml) environment.

2. Training
   
   To train Histgen baseline and other patch level encoder variants (UNI and UNI2) use the files [HistGen Training](/HistGen/train_wsi_reportseed4x.sh), [UNI Training](/HistGen/train_wsi_report_uni1_seed4x.sh), and [UNI2 Training](/HistGen/train_wsi_report_uni2_seed4x.sh) respectively using the [histgen](/Conda%20Environments/histgen.yml) environment.

   To train TITAN, use [TITAN Training](/HistGen4TITAN/train_wsi_report_TITAN.sh) using [histgen_titan](/Conda%20Environments/histgen_titan.yml) environment.

4. Inference

   For BLUE, METEOR, ROUGE-L, use the files [HistGen Testing](/HistGen/test_wsi_report_seed4x.sh), [UNI Testing](/HistGen/test_wsi_report_UNI1_seed4x.sh) [UNI2 Testing](/HistGen/test_wsi_report_UNI2_1_seed4x.sh) with [histgen](/Conda%20Environments/histgen.yml) environment. For TITAN use [TITAN Testing](/HistGen4TITAN/test_wsi_report_5_seed4x.sh) with [histgen_titan](/Conda%20Environments/histgen_titan.yml) environment.

   For REGScore use the file [HistGen Testing](/Other%20Activities/REG2025%20Inference/reg_evaluator.py) with [reg2025-eval](/Conda%20Environments/reg2025-eval.yml) environmet for all the models.

Sample job scripts are present in [Scripts](/Job%20Scripts/)

All the results can be found in [Results](/Results/)


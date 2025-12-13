# 🧬 TCGA-BRCA Multi-Modal Machine Learning Pipeline

<div align="center">

[![DOI](https://img.shields.io/badge/DOI-10.20944%2Fpreprints202512.0929.v1-blue)](https://doi.org/10.20944/preprints202512.0929.v1)
[![License: MIT](https://img.shields.io/badge/License-MIT-yellow.svg)](https://opensource.org/licenses/MIT)
[![R Version](https://img.shields.io/badge/R-%E2%89%A5%204.0-blue)](https://www.r-project.org/)
[![TCGA](https://img.shields.io/badge/Data-TCGA--BRCA-green)](https://portal.gdc.cancer.gov/)

**A comprehensive production-ready pipeline for breast cancer progression prediction using multi-omics integration**

[Quick Start](#-quick-start) • [Features](#-features) • [Results](#-expected-results) • [Citation](#-citation)

</div>

---

## 🌟 Features

This pipeline represents a complete end-to-end solution for multi-modal breast cancer prognosis prediction, incorporating several key innovations that address common challenges in genomic machine learning:

**Multi-Modal Integration** combines clinical features with pathway-level gene expression, microRNA abundance, and regulatory interaction features to create a comprehensive molecular portrait of each tumor sample.

**View-Specific Preprocessing** tackles the dimensionality imbalance problem by performing independent feature selection and scaling within each omics modality, ensuring that high-dimensional views don't overwhelm smaller feature sets during integration.

**Balanced Class Distribution** redefines the prediction target using Stage IIA as the cutoff point, achieving a well-balanced 46% early versus 54% late stage distribution that improves model training compared to the highly skewed original staging system.

**Production-Ready Implementation** includes comprehensive error handling, progress reporting, reproducible random seeds, and complete documentation to ensure reliability in research and clinical settings.

**Biological Interpretability** leverages pathway-level aggregation to reduce the feature space from 18,000 genes to 150 interpretable biological pathways, while interaction features capture known miRNA-target regulatory relationships.

---

## 🚀 Quick Start

### Step 1: Environment Setup

Begin by creating your project directory structure, which will organize all data, models, and results:

```bash
mkdir tcga-brca-ml && cd tcga-brca-ml
mkdir scripts
```

### Step 2: Script Installation

Copy all pipeline scripts from the output directory to your scripts folder:

```bash
cp /mnt/user-data/outputs/FINAL_PIPELINE/*.R scripts/
```

### Step 3: Pipeline Execution

You have two options for running the complete analysis pipeline:

**🎯 Option A - Automated Execution (Recommended)**

The automated approach runs all scripts in the correct sequence with proper error checking:

```bash
cp /mnt/user-data/outputs/FINAL_PIPELINE/00_RUN_COMPLETE_PIPELINE.sh .
bash 00_RUN_COMPLETE_PIPELINE.sh
```

**⚙️ Option B - Manual Step-by-Step**

For more control or debugging, you can execute each script individually from your project root:

```bash
# Data Acquisition (45-60 minutes) - Skip if data already exists
Rscript scripts/01_pull_tcga_data.R

# Preprocessing and Normalization (5 minutes)
Rscript scripts/02_preprocess_normalize.R

# Pathway Feature Engineering (10-15 minutes)
Rscript scripts/03_engineer_pathway_features.R

# miRNA Interaction Features (5 minutes)
Rscript scripts/04_engineer_mirna_interactions.R

# Clinical Feature Integration (3 minutes)
Rscript scripts/05_integrate_clinical_features.R

# Multi-Modal Data Integration (2 minutes)
Rscript scripts/06_integrate_multimodal.R

# Exploratory Analysis (5 minutes)
Rscript scripts/07_eda_and_de_analysis.R

# Machine Learning Benchmarking (15-20 minutes)
Rscript scripts/08_ml_benchmarking.R

# Network Analysis (3 minutes)
Rscript scripts/09_network_analysis.R

# Figure Generation (2 minutes)
Rscript scripts/10_generate_figures.R
```

**⏱️ Total Pipeline Runtime:** Approximately 45-60 minutes excluding initial data download

---

## 📋 Pipeline Components

Each script in the pipeline serves a specific purpose in the analysis workflow:

| Script | Purpose | Runtime | Output Files |
|:------:|---------|:-------:|--------------|
| **01** | Downloads raw TCGA-BRCA multi-omics data from GDC portal | 45-60 min | `data/raw/*.rds` |
| **02** | Normalizes expression data and creates binary outcome labels | 5 min | `data/processed/*.rds` |
| **03** | Computes GSVA pathway enrichment scores from gene expression | 10-15 min | 150 pathway features |
| **04** | Engineers miRNA-target interaction features from known databases | 5 min | 200 interaction features |
| **05** | Encodes and integrates clinical variables with molecular data | 3 min | 7 clinical features |
| **06** | Performs view-specific preprocessing and creates data splits | 2 min | Train/validation/test sets |
| **07** | Conducts exploratory analysis and differential expression | 5 min | DE results and visualizations |
| **08** | Trains XGBoost ensemble models and benchmarks performance | 15-20 min | Model files and metrics |
| **09** | Constructs and analyzes miRNA-mRNA regulatory networks | 3 min | Network topology files |
| **10** | Generates publication-quality figures and visualizations | 2 min | 3 PDF figure files |

---

## 📊 Expected Results

### Model Performance on Held-Out Test Set

The integrated multi-modal model demonstrates substantial improvements over single-modality approaches:

```
Model Type      AUC     Accuracy  Sensitivity  Specificity  F1 Score
─────────────────────────────────────────────────────────────────────
Clinical Only   0.715   0.728     0.745        0.711        0.735
Pathway Only    0.742   0.751     0.768        0.734        0.758
miRNA Only      0.668   0.695     0.723        0.667        0.702
Interaction     0.728   0.734     0.751        0.717        0.741
─────────────────────────────────────────────────────────────────────
INTEGRATED      0.782   0.791     0.808        0.774        0.801
```

The integrated model achieves an AUC of 0.782, representing a 6.7% improvement over the next-best single-modality approach.

### Feature Importance Analysis

The model assigns importance across all feature types, with pathway features contributing the most information:

```
Feature Type    Total Gain  Mean Gain  Number Features  Percentage
────────────────────────────────────────────────────────────────────
Pathway         38.2%       0.025      150              38.2%
Clinical        22.1%       0.316      7                22.1%
Interaction     17.8%       0.009      200              17.8%
miRNA           11.9%       0.012      100              11.9%
```

This distribution demonstrates effective feature integration, with no single modality dominating the predictions.

### Sample Distribution

The pipeline processes a well-balanced cohort from TCGA-BRCA:

```
Total Samples: 946
  ├─ Early Stage (I/IIA):    441 samples (46.6%)
  └─ Late Stage (IIB/III/IV): 505 samples (53.4%)
```

This balance, achieved by using Stage IIA as the classification cutoff, supports robust model training.

---

## 📁 Directory Structure

The pipeline creates an organized directory hierarchy for all data and results:

```
tcga-brca-ml/
│
├── scripts/                      # Complete pipeline scripts (01-10)
│
├── data/
│   ├── raw/                      # Downloaded TCGA multi-omics data
│   ├── processed/                # Normalized and filtered datasets
│   ├── integrated/               # Multi-modal integrated feature matrices
│   └── splits/                   # Train/validation/test partitions
│
├── models/
│   └── multi_modal/              # Trained XGBoost ensemble models
│
└── results/
    ├── multi_modal/              # Performance metrics and predictions
    ├── eda/                      # Differential expression analysis
    ├── network/                  # miRNA-mRNA network topology
    └── figures/                  # Publication-ready visualizations
```

---

## 🛠️ System Requirements

### Required R Packages

The pipeline depends on packages from both CRAN and Bioconductor repositories:

**CRAN Packages** provide general data manipulation and machine learning functionality:

```r
install.packages(c("tidyverse", "caret", "xgboost", "pROC", "igraph"))
```

**Bioconductor Packages** offer specialized genomics and pathway analysis tools:

```r
if (!requireNamespace("BiocManager", quietly = TRUE))
    install.packages("BiocManager")

BiocManager::install(c(
    "TCGAbiolinks",        # TCGA data retrieval
    "SummarizedExperiment", # Genomic data structures
    "edgeR",               # Differential expression
    "DESeq2",              # RNA-seq analysis
    "GSVA",                # Pathway enrichment
    "msigdbr"              # Pathway databases
))
```

### System Specifications

Your computing environment should meet these minimum requirements for optimal performance:

- **R Version:** 4.0 or higher
- **Memory:** At least 16 GB RAM (32 GB recommended)
- **Storage:** 50 GB free disk space for TCGA data and results
- **Network:** Stable internet connection for downloading TCGA data

---

## 💡 Key Innovations

This pipeline introduces several methodological advances that address common challenges in multi-omics machine learning:

**View-Specific Preprocessing Strategy**

Traditional concatenation of multi-omics data often leads to dimensionality bias, where high-dimensional views dominate feature selection and model learning. This pipeline implements independent feature selection and scaling within each omics modality before integration, ensuring balanced representation across all data types.

**Balanced miRNA Representation**

In naive concatenation approaches, miRNA features typically comprise less than 5% of the top-ranked features due to their lower dimensionality compared to gene expression. Through view-specific preprocessing and interaction feature engineering, this pipeline achieves 23% miRNA-related feature representation in the top-100, capturing critical regulatory information.

**Pathway-Level Gene Expression**

Rather than using individual gene expression values, the pipeline aggregates genes into 150 biologically meaningful pathways using GSVA enrichment scores. This reduces the feature space from over 18,000 genes while improving interpretability and biological relevance.

**Outcome Definition for Balanced Classes**

The original TCGA staging system produces a highly imbalanced dataset with 97% of samples in early stages. By redefining the outcome using Stage IIA as the cutoff between early and late progression, the pipeline achieves a well-balanced 46/54% distribution that significantly improves model training dynamics.

**Regulatory Interaction Features**

Beyond measuring miRNA and mRNA abundances independently, the pipeline engineers interaction features that capture known regulatory relationships. These product terms between miRNAs and their validated targets encode the joint behavior of regulatory pairs, revealing coordinated dysregulation patterns.

---

## 🔧 Troubleshooting Guide

### Memory Limit Errors

**Symptom:** Error message mentioning "vector memory limit" during data download

**Solution:** Script 01 already optimizes memory usage by retaining only the unstranded assay. If problems persist, increase R's memory allocation before running the script:

```r
Sys.setenv("R_MAX_VSIZE" = 32e9)  # Sets 32GB limit
```

### Sample Mismatch Issues

**Symptom:** Error indicating "No common samples" between data types

**Solution:** This issue has been addressed in script 02, which automatically strips assay prefixes from miRNA column names to ensure proper sample matching across modalities.

### Class Imbalance Warnings

**Symptom:** Highly imbalanced class distribution affecting model training

**Solution:** Script 02 implements the Stage IIA cutoff strategy, which automatically produces a balanced 46/54% distribution. If you're still seeing imbalance, verify that the staging information is correctly loaded.

### Unexpectedly Low Performance

**Symptom:** Area under the ROC curve (AUC) below 0.70

**Diagnostic Steps:**

First, verify your sample sizes by checking that the training set contains at least 600 samples. Second, confirm the outcome balance shows approximately 40-60% late stage samples. Third, ensure the integrated feature matrix contains 450 or more features across all modalities. If any of these checks fail, review the earlier preprocessing steps for potential errors.

---

## 📚 Citation

If you use this code or derived figures in academic work, please cite:

Roy, K. R. (2025). *View-specific preprocessing for multi-modal integration improves breast cancer progression prediction: a machine learning analysis of TCGA-BRCA.* SSRN. https://doi.org/10.2139/ssrn.5876162

### BibTeX

```bibtex
@article{roy2025view,
  author  = {Roy, Kushal Raj},
  title   = {View-specific preprocessing for multi-modal integration improves breast cancer progression prediction: a machine learning analysis of TCGA-BRCA},
  year    = {2025},
  journal = {SSRN Electronic Journal},
  doi     = {10.2139/ssrn.5876162},
  url     = {https://doi.org/10.2139/ssrn.5876162}
}
```

---

## 📄 License

**Code:** This pipeline is released under the MIT License, allowing free use, modification, and distribution with attribution.

**Data:** TCGA data is publicly available and distributed under CC0 (public domain dedication).

---

## 📧 Contact

**Kushal Raj Roy**  
Department of Biology and Biochemistry  
University of Houston  
Houston, Texas, USA  
📧 krroy@uh.edu

For questions, bug reports, or collaboration inquiries, please reach out via email or open an issue in the repository.

---

<div align="center">

**⭐ If you find this pipeline useful, please consider starring the repository! ⭐**

</div>

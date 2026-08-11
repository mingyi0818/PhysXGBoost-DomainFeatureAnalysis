# NewsFeat: Why News Popularity Prediction Fails - An Information-Theoretic Analysis of Feature Engineering Futility

> An information-theoretic analysis of why news popularity prediction fails despite domain feature engineering. This work demonstrates that the feature space is information-saturated and that domain features cannot extract additional signal, with R2 scores near zero across all models.

**Task**: Regression | **Target**: shares | **Primary Metric**: R2

## Dataset

| Item | Detail |
|------|--------|
| Name | Online News Popularity (UCI ML Repository) |
| File | `data/news_pop.csv` |
| Size | 18.52 MB |
| Source | UCI Machine Learning Repository - Online News Popularity Dataset. 39,644 samples with 61 features covering content metrics (words, links, LDA topics), temporal indicators, and digital media characteristics from Mashable. |
| Task | Regression |
| Target | shares |
| Metric | R2 |

## Method

PhysXGBoost framework: domain feature engineering + tree models. The approach systematically compares Raw features vs Domain-derived features (incorporating domain knowledge) across four tree-based models: XGBoost, LightGBM, CatBoost, and RandomForest, with 5 random seeds per configuration.

## Directory Structure

```
54_NewsPopularity/
├── data/          # Dataset files
├── code/          # Source code
├── results/       # Experimental results (JSON/CSV)
├── paper/         # Paper draft
└── plots/         # Figures (PNG, 300 DPI)
```

## Key Results

| Metric | Best Model | Value |
|--------|-----------|-------|
| R2 | CatBoost (R2 near zero; Raw = Domain, demonstrating feature engineering futility) | R2 = 0.0049 |

> All metrics are computed on the **test set** (20% holdout) and averaged across 5 random seeds [42, 123, 456, 789, 2024]. Results are sourced from `results/summary.json`.

### Result Files

| File | Description |
|------|-------------|
| `summary.json` | Main results: mean/std metrics for Raw vs Domain features, Wilcoxon test p-values |
| `comprehensive_results.json` | Ablation and sensitivity analysis |
| `per_seed_results.json` | Per-seed detailed results for each (model, feature_set, seed) |
| `additional_metrics.json` | Additional metrics (Accuracy, F1, RMSE, MAE, 95% CI, Cohen's d) |

## Environment Requirements

- Python 3.10+
- OS: Windows 11 Professional (tested)
- CPU: Intel Xeon W7-2595X (24 cores, 2.5-4.8 GHz)
- RAM: 48 GB DDR5 RDIMM
- GPU: NVIDIA RTX 2000 Pro (16 GB) -- not required for tree models

### Python Dependencies

```
xgboost>=2.0.0, lightgbm>=4.0.0, catboost>=1.2.0, scikit-learn>=1.3.0, pandas>=2.0.0, numpy>=1.24.0, scipy>=1.11.0, matplotlib>=3.7.0
```

## How to Reproduce

See [reproduce.md](reproduce.md) for detailed step-by-step instructions.

## Citation

If you use this code or data, please cite the original dataset source and this repository.

## License

This project is for academic research purposes. Dataset licenses follow their respective sources.

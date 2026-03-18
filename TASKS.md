# mlflow-ai-experiment
**Mission:** Use MLFlow to compare all state of the art ML models on some domain of your choice

## Phase 1: Planning & Setup
- [x] Define specific domain and problem: Select text classification domain using IMDB movie reviews dataset for sentiment analysis, document requirements and success criteria
  - Deliverable: `docs/problem-statement.md` with dataset choice, evaluation metrics (accuracy, F1, inference time), and baseline expectations
- [x] Set up MLFlow tracking infrastructure: Configure MLFlow tracking URI (local directory or Docker), initialize experiments, create project structure
  - Deliverable: `mlruns/` directory with tracking configured, `setup_mlflow.py` script, and `config.yaml` for experiment parameters
- [x] Create development environment: Create `requirements.txt` with core dependencies (mlflow, transformers, datasets, torch/tensorflow, scikit-learn, pandas, numpy) and set up virtual environment
  - Deliverable: `requirements.txt` file, `environment.yml` (conda) or `pyproject.toml`, and verified working environment with all packages installed
- [x] Establish project structure and baseline: Create organized directory layout (`src/`, `data/`, `models/`, `experiments/`, ` notebooks/`) and implement a simple baseline model (e.g., TF-IDF + Logistic Regression)
  - Deliverable: Complete folder structure with `src/baseline.py`, baseline training script that logs to MLFlow, and initial baseline metrics documented

## Phase 2: Data Management & Preprocessing
- [x] Download and prepare dataset: Download IMDB dataset using HuggingFace `datasets` library, perform initial exploration, and create standardized train/validation/test splits
  - Deliverable: `data/` folder with processed splits (`train.csv`, `validation.csv`, `test.csv`), `src/data_loader.py` with dataset handling, and data exploration notebook `notebooks/01_data_exploration.ipynb`
 - [x] Implement text preprocessing pipeline: Create modular preprocessing functions for tokenization, padding, and cleaning; implement different tokenization strategies for classical ML vs. transformers
   - Deliverable: `src/preprocessing.py` with configurable pipelines, `src/tokenizers.py` for BERT/RoBERTa/DistilBERT tokenizers, and tests in `tests/test_preprocessing.py`
- [x] Create data utilities for MLFlow logging: Implement data versioning approach and utilities to log dataset statistics, splits, and preprocessing parameters to MLFlow
  - Deliverable: `src/data_utils.py` with functions to log data artifacts and metrics, `src/data_versioning.py` with checksum-based versioning, and updated data loading scripts
- [x] Benchmark data pipeline performance: Measure and log data loading times, preprocessing throughput, and memory usage for different batch sizes
  - Deliverable: Performance benchmark script `scripts/benchmark_data.py`, performance results logged to MLFlow, and optimization recommendations in `docs/data_performance.md`

## Phase 3: Model Implementation & Training
- [x] Implement HuggingFace transformer integration: Create wrapper classes for transformer models (BERT, RoBERTa, DeBERTa, XLNet) with unified interface, supporting custom heads for classification
  - Deliverable: `src/models/transformers.py` with model factory pattern, individual model classes for each architecture, and configuration handling
- [x] Build classical ML model implementations: Implement traditional models (Logistic Regression, SVM, Random Forest, XGBoost) using scikit-learn and compare against transformers
  - Deliverable: `src/models/classical.py` with all classical model implementations, hyperparameter tuning configurations, and comparison baseline script
- [x] Implement state-of-the-art models beyond transformers: Add cutting-edge models like ELECTRA, ALBERT, DistilBERT, and potentially GPT-based classifiers to ensure comprehensive coverage
  - Deliverable: Extended `src/models/transformers.py` with additional models, model zoo configuration in `config/models.yaml`, and training scripts for each model family
- [x] Create unified training pipeline: Implement modular training loop with logging, checkpointing, early stopping, mixed precision training, and support for both PyTorch and TensorFlow backends
  - Deliverable: `src/training.py` with complete training pipeline, `src/train.py` CLI, configuration schema in `config/training_schema.yaml`, and comprehensive documentation

## Phase 4: Experimentation, Logging & Analysis
- [ ] [DEBUG-NEEDED] - [ ] [DEBUG-NEEDED] - [ ] Set up comprehensive MLFlow experiment tracking: Create separate experiments for each model family, implement custom MLFlow tags (model_type, dataset_version, preprocessing_config), and enable artifact logging for models and predictions
  - Deliverable: `src/experiment_tracker.py` with experiment management functions, automated tagging system, and artifact storage structure in `artifacts/`
- [ ] Design hyperparameter optimization framework: Integrate Optuna or Ray Tune with MLFlow for automated hyperparameter search across all models, define search spaces for each model architecture
  - Deliverable: `src/hyperopt.py` with optimization loops, search space definitions in `config/hyperparams/`, script `scripts/run_hyperopt.py`, and example results
- [ ] Implement automated model evaluation suite: Create evaluation script that computes all metrics (accuracy, precision, recall, F1, confusion matrix, inference latency, memory footprint) and logs them consistently
  - Deliverable: `src/evaluation.py` with comprehensive metrics calculation, `scripts/evaluate_all.py` for batch evaluation, standardized MLFlow metrics naming, and comparison tables generation
- [ ] Build analysis and visualization dashboards: Create Jupyter notebooks and Streamlit/Plotly Dash app for interactive comparison of all models, metric correlation analysis, and statistical significance testing
  - Deliverable: Interactive dashboard `app/dashboard.py` or `notebooks/analysis.ipynb`, comparison visualizations (bar charts, ROC curves, latency vs accuracy plots), statistical test results in `docs/model_comparison.md`
- [ ] Generate final report and recommendations: Compile comprehensive comparison report with best-performing models per metric, computational cost analysis, and deployment recommendations
  - Deliverable: Final report `docs/FINAL_REPORT.md` with executive summary, detailed model comparison tables, deployment guidelines, `models/best_models/` directory with top 3 models saved, and reproducibility checklist

## Additional Considerations
- [ ] Ensure reproducibility: Implement deterministic training where possible, log all random seeds, dependency versions, and hardware specifications
  - Deliverable: `src/reproducibility.py` with seed management, complete environment logging to MLFlow, and reproducibility documentation
- [ ] Implement model artifact management: Create standardized model packaging (ONNX conversion where applicable), versioning scheme, and export formats for deployment
  - Deliverable: Model export utilities in `src/export.py`, standardized artifact structure, and deployment instructions in `docs/deployment.md`
```

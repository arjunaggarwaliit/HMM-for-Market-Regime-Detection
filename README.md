# HMM for Market Regime Detection

[![License: MIT](https://img.shields.io/badge/License-MIT-yellow.svg)](https://opensource.org/licenses/MIT)
[![Python 3.9+](https://img.shields.io/badge/Python-3.9%2B-blue.svg)](https://www.python.org/)
[![Made with Jupyter](https://img.shields.io/badge/Made%20with-Jupyter-orange.svg)](https://jupyter.org/)

A research-oriented framework for identifying financial market regimes using **Hidden Markov Models (HMMs)** and a suite of alternative machine learning methods. This project provides a unique educational resource by offering both a fully transparent, from-scratch implementation of core HMM algorithms alongside practical library-based applications, enabling a deep conceptual understanding of probabilistic regime detection.

---

## Overview

Market regimes, distinct periods characterized by persistent levels of volatility, trend, or mean reversion, pose a significant challenge to static investment strategies. This repository demonstrates how HMMs, as unsupervised probabilistic models, can effectively uncover these latent states from observable market data like returns and volatility. The project emphasizes a comparative analysis, benchmarking HMMs against both probabilistic (Gaussian Mixture Models) and deterministic (K-Means, Hierarchical Clustering) alternatives, as well as supervised and anomaly detection methods, to provide a holistic view of regime classification in quantitative finance.

---

## Key Features

- **Dual HMM Implementation:** Includes a **from-scratch, NumPy-based HMM** (Forward-Backward, Viterbi, Baum-Welch) for educational clarity, alongside optimized implementations using industry-standard libraries like `hmmlearn` and `pomegranate`.
- **Comprehensive Benchmarking:** Compares HMMs with a wide array of alternative methods including GMMs, K-Means, DBSCAN, Agglomerative Clustering, Isolation Forest, Random Forest, and Wasserstein-distance based clustering.
- **Rigorous Quantitative Evaluation:** Employs financial and statistical metrics such as **Log-Likelihood, AIC/BIC, Regime Persistence, Regime Purity, Sharpe, Sortino, Max Drawdown, Calmar, VaR/CVaR, Hit Rate, and Wasserstein Distances** to assess model quality and financial interpretability.
- **Modular and Reproducible Design:** Built with a clear separation of concerns: utility modules for data fetching, preprocessing, visualization, and metrics; and a logical progression of Jupyter notebooks for a structured research workflow.
- **Interactive Visualizations:** Features rich, interactive Plotly charts that overlay detected regimes on price charts, display state transition matrices, and visualize distributional characteristics of each regime.

---

## Project Structure

```
HMM-for-Market-Regime-Detection/
|-- app/                         # FastAPI backend, routes, schemas, services, Ray tasks, optimization
|-- market_regime/               # Reusable HMM market regime Python package
|-- src/                         # React dashboard source
|-- public/                      # Frontend static assets and runtime config
|-- docker/                      # Backend/frontend Dockerfiles and Nginx runtime config
|-- k8s/                         # Minimal Kubernetes deployment and service manifests
|-- requirements/                # Python dependency files
|-- docs/                        # Project report and mathematical reference PDFs
|-- examples/                    # Reusable Python API examples
|-- utils/                       # Research utility modules used by notebooks
|-- hmm_from_scratch/            # Educational NumPy HMM implementation
|-- hmm_libraries/               # Library-based HMM experiments
|-- alternative_methods/         # Alternative clustering/ML approaches
|-- model_comparison/            # Model comparison notebooks
|-- docker-compose.yml           # Full-stack local container orchestration
|-- package.json                 # React/Vite dependencies and scripts
`-- README.md
```
---

## Mathematical Core

The project's foundation is the **Gaussian Hidden Markov Model**, a doubly stochastic process where a sequence of unobserved (hidden) states generates a sequence of observable, continuous emissions.

- **Hidden States ($S_t \in \{1, \ldots, N\}$):** Represent the latent market regimes (e.g., low-volatility bull, high-volatility bear, transitional). These states evolve according to a first-order Markov process defined by the transition probability matrix $\mathbf{A}$.
- **Observations ($O_t$):** These are the financial time series features we can measure, such as daily log-returns, realized volatility, or momentum. The probability of observing $O_t$ given the current state $S_t$ is modeled as a multivariate Gaussian distribution, parameterized by mean vectors $\boldsymbol{\mu}_i$ and covariance matrices $\boldsymbol{\Sigma}_i$ for each state $i$.

**Core Algorithms:**

- **Forward-Backward Algorithm:** Computes the posterior probabilities of being in a particular state at each time point:
$$\gamma_t(i) = P(S_t = i \mid O_1, \ldots, O_T, \lambda)$$

* **Viterbi Algorithm:** Finds the most likely sequence of hidden states:
$$\hat{S}_1, \dots, \hat{S}_T = \underset{S_1, \dots, S_T}{\arg \max} \, P(S_1, \dots, S_T \mid O_1, \dots, O_T, \lambda)$$

- **Baum-Welch Algorithm (EM):** An Expectation-Maximization procedure that iteratively re-estimates the model parameters $\lambda = (\mathbf{A}, \boldsymbol{\mu}, \boldsymbol{\Sigma})$ to maximize the likelihood of the observed data.

---

## Installation

**Prerequisites:** Python 3.9 or higher.

**1. Clone the repository:**
```bash
git clone https://github.com/arjunaggarwaliit/HMM-for-Market-Regime-Detection.git
cd HMM-for-Market-Regime-Detection
```

**2. Install dependencies:**

It is highly recommended to use a virtual environment.

```bash
py -3.12 -m venv venv
source venv/bin/activate   # On Windows: venv\Scripts\activate
pip install -r requirements/base.txt
pip install -r requirements/backend.txt
```

---

## Usage

The project can now be used either as a reusable Python package or explored
sequentially through Jupyter notebooks.

### Reusable Python API

```python
from market_regime.data_loading import load_market_data
from market_regime.inference import predict_market_regime, prediction_to_frame
from market_regime.preprocessing import prepare_market_features

data = load_market_data("SPY", start="2018-01-01")
features = prepare_market_features(data)

prediction = predict_market_regime(features)
result = prediction_to_frame(features, prediction)

hidden_states = prediction.hidden_states
transition_probabilities = prediction.transition_probabilities
predicted_regime_labels = prediction.predicted_regime_labels
```

The package separates the production workflow into focused modules:

- `market_regime.data_loading` - CSV and Yahoo Finance loading helpers.
- `market_regime.preprocessing` - returns, volatility, and technical features.
- `market_regime.model_training` - HMM fitting and training result objects.
- `market_regime.inference` - `predict_market_regime(data)` and prediction helpers.
- `market_regime.visualization` - Plotly charts for regimes and transitions.
- `market_regime.hmm` - the reusable univariate Gaussian HMM implementation.

To run the included example:

```bash
python -m examples.predict_regime
```

### FastAPI Backend

Start the minimal API backend with:

```bash
uvicorn app.main:app --reload
```

### React Dashboard

Start the Vite dashboard with:

```bash
npm install
npm run dev
```

The frontend runs at `http://127.0.0.1:5173` and calls the FastAPI backend at
`http://127.0.0.1:8000` by default. Override the API base URL with
`VITE_API_BASE_URL` when needed.

### Docker Compose

Run the full-stack application with:

```bash
docker-compose up
```

Use `docker-compose up --build` after changing Dockerfiles or dependencies.

The containerized frontend is served at `http://localhost:3000`. It calls the
backend through the frontend container's `/api` proxy, which forwards requests to
the `backend` service on Docker's internal network. The backend is also exposed
directly at `http://localhost:8000`.

Useful environment variables:

- `API_BASE_URL` - frontend runtime API URL, defaults to `/api` in Docker.
- `HOST` - backend bind host, defaults to `0.0.0.0`.
- `PORT` - backend port, defaults to `8000`.
- `BACKEND_CORS_ORIGINS` - comma-separated list of allowed browser origins.

### Kubernetes With Minikube

Start Minikube:

```bash
minikube start
```

Build the Docker images inside Minikube's Docker environment.

On PowerShell:

```powershell
minikube docker-env | Invoke-Expression
docker build -t hmm-backend:latest -f docker/backend/Dockerfile .
docker build -t hmm-frontend:latest -f docker/frontend/Dockerfile .
```

On macOS/Linux shells:

```bash
eval $(minikube docker-env)
docker build -t hmm-backend:latest -f docker/backend/Dockerfile .
docker build -t hmm-frontend:latest -f docker/frontend/Dockerfile .
```

Apply the Kubernetes manifests:

```bash
kubectl apply -f k8s/deployment.yaml
kubectl apply -f k8s/service.yaml
```

Check the running pods:

```bash
kubectl get pods
kubectl get services
```

Open the frontend:

```bash
minikube service frontend
```

Open the backend directly:

```bash
minikube service backend
```

The frontend service uses NodePort `30080`, and the backend service uses
NodePort `30081`. Inside the cluster, the frontend container proxies `/api`
requests to the `backend` service.

Available endpoints:

- `GET /health`
- `POST /predict`
- `POST /predict-ticker`
- `POST /batch-predict`

Example prediction payload:

```json
{
  "data": [
    {
      "date": "2024-01-02",
      "open": 100.0,
      "high": 101.2,
      "low": 99.5,
      "close": 100.8,
      "volume": 1200000
    }
  ],
  "n_states": 3,
  "n_iter": 100
}
```

Example ticker prediction payload:

```json
{
  "ticker": "SPY",
  "start_date": "2023-01-01",
  "end_date": "2024-01-01",
  "n_states": 3,
  "n_iter": 100,
  "tol": 0.000001,
  "random_state": 42
}
```

Example batch prediction payload:

```json
{
  "tickers": ["SPY", "QQQ", "DIA"],
  "start_date": "2023-01-01",
  "end_date": "2024-01-01"
}
```

Batch prediction uses Ray remote tasks when Ray is available. If Ray cannot be
initialized, the backend logs the issue and falls back to sequential processing
so the API remains available.

Example optimization payload:

```json
{
  "assets": [
    {
      "ticker": "SPY",
      "price": 100,
      "expected_profit": 3,
      "risk_score": 4,
      "regime_label": "Low Volatility Bull"
    },
    {
      "ticker": "QQQ",
      "price": 120,
      "expected_profit": 5,
      "risk_score": 8,
      "regime_label": "High Volatility Bull"
    }
  ],
  "scenarios": [
    {
      "name": "Base Case",
      "budget": 500,
      "max_risk": 25,
      "max_units_per_asset": 5
    }
  ]
}
```

Optimization follows the course architecture:
FastAPI -> Ray Worker -> OR-Tools Solver -> Response. If Ray is unavailable, the
same solver runs sequentially so the educational endpoint remains usable.

### Notebook Workflow

Start a Jupyter server from the project's root directory:

```bash
jupyter lab
```

Run the notebooks in the recommended order to follow the research narrative:

1. `hmm_from_scratch/hmm_from_scratch.ipynb` - Understand the inner workings of an HMM by using a custom implementation.
2. `hmm_libraries/hmm_libraries.ipynb` - See how the same problem is solved efficiently using `hmmlearn` and `pomegranate`.
3. `alternative_methods/alternative_methods.ipynb` - Explore how other unsupervised and supervised methods perform on the regime detection task.
4. `model_comparison/model_comparison.ipynb` - Examine the final comparative analysis across all models to draw conclusions.

The current Overleaf-ready reports are:

- `docs/comprehensive_project_report.tex` - full 15-20 page project report covering ML, backend, frontend, Ray, OR-Tools, Docker, and Kubernetes.
- `docs/ml_notebook_review_report.tex` - focused notebook review and reproduced SPY model comparison.

Recreate the notebook-review report inputs with:

```bash
python scripts/generate_ml_review_report.py
```

---

## Methodology & Results

The project follows a rigorous, multi-stage methodology:

1. **Data Acquisition & Feature Engineering:** Fetches OHLCV data for a specified ticker (default `SPY`) via `yfinance`. Constructs a rich feature set including log-returns, realized volatility over multiple windows, momentum, and higher-order moments to serve as the observation sequence.

2. **Model Training & Decoding:** Each model is trained on a training set. For HMMs, the Baum-Welch algorithm learns the optimal transition and emission parameters. The Viterbi algorithm is then used to decode the most probable sequence of hidden regimes for the entire time series.

3. **Regime Interpretation:** Decoded states are analyzed post-hoc. Statistical summaries of returns and volatility are computed for each state to assign meaningful labels (e.g., *"Low Volatility Bull"*, *"High Volatility Bear"*, *"Transitional"*).

4. **Comparative Evaluation:** A dashboard-style notebook (`model_comparison`) presents a unified comparison of all models using the defined metrics, providing a clear, quantitative basis for assessing model suitability.

---

## Evaluation Metrics

| Metric | Description |
|---|---|
| **Log-Likelihood** | Measures how well the model fits the observed data. Higher values (closer to zero) indicate a better fit. |
| **AIC / BIC** | Penalized measures of model fit, trading off goodness-of-fit against model complexity. Lower values are preferred for model selection. |
| **Regime Persistence** | The average duration (in days) of a regime. Higher persistence often corresponds to more interpretable and stable regimes. |
| **Regime Purity** | Compares predicted regimes against a simple, threshold-based volatility regime ("Low", "Med", "High") to measure alignment with an intuitive baseline. |
| **Conditional Sharpe Ratio** | Calculates the risk-adjusted return within each identified regime, providing a direct financial interpretation of the regime's characteristics. |
| **Sortino Ratio** | Measures annualized return relative to downside volatility, which is useful when upside volatility should not be penalized. |
| **Max Drawdown / Calmar** | Captures worst compounded peak-to-trough loss and compares annualized return against that drawdown. |
| **Hit Rate** | Measures the fraction of positive-return days inside each regime. |
| **VaR / CVaR 5%** | Estimates the 5th percentile loss threshold and average loss in the worst 5% tail of each regime. |
| **Wasserstein Distance** | Measures the "earth mover's distance" between the empirical return distributions of different regimes. Larger distances indicate better separation and distinctiveness of the identified states. |

---

## Implementation Details

### `hmm_from_scratch`

This module contains a fully self contained `GaussianHMM` class written in Python with NumPy. It implements all core algorithms:

- `forward_pass()` - Computes scaled forward probabilities.
- `backward_pass()` - Computes scaled backward probabilities.
- `viterbi()` - Implements the Viterbi algorithm in log-space for numerical stability.
- `fit()` - Performs parameter learning via the Expectation-Maximization (Baum-Welch) algorithm.

### `hmm_libraries`

This notebook demonstrates the practical application of HMMs using two popular libraries:

- **`hmmlearn`** - A scikit-learn compatible library offering `GaussianHMM` and `GMMHMM` models.
- **`pomegranate`** - A modern probabilistic modeling library that provides a flexible `DenseHMM` implementation.

The notebook verifies the numerical consistency between these libraries and the custom implementation, comparing execution speed and ease of use.

### `utils/`

The utility modules provide a solid foundation for the entire project:

- **`data_utils.py`** - Handles all data acquisition and feature engineering. Includes functions to fetch data from Yahoo Finance, compute log-returns, realized volatility, and other technical indicators, and to create feature matrices for modeling.
- **`viz_utils.py`** - Provides a suite of functions for creating interactive Plotly charts. Includes tools for overlaying regime bands on price charts, plotting transition matrices as heatmaps, and visualizing distributional characteristics of regimes.
- **`metrics.py`** - Implements all the quantitative evaluation metrics used across the project, ensuring consistency and reproducibility in the analysis.

---

## References

1. Rabiner, L. R. (1989). A tutorial on hidden Markov models and selected applications in speech recognition. *Proceedings of the IEEE*, 77(2), 257–286.
2. Nguyen, N., & Nguyen, D. (2015). Hidden Markov Model for Stock Selection. *Risks*, 3(4), 455–473.
3. McGreevy, J. (2021). Hidden Markov Models in Finance. Imperial College London, MSc Thesis.
4. Tsang, E. (2021). Market Regime Detection using Hidden Markov Models in QSTrader. *QuantStart*.
5. Chen, X. (2025). HMM-based market regime detection with reinforcement learning. *IDS*.
6. Hikmath Technologies: Market Regime Detection: From HMMs to Wasserstein Clustering.

---

## Acknowledgements

This project was developed as part of the coursework for **AI111 (Mathematical Foundations of AI & Data Engineering)** under the guidance and mentorship of [**Dr. Puneet Kumar**](https://puneetkumar.com/). It builds upon the theoretical foundations and practical applications of Hidden Markov Models in quantitative finance, drawing inspiration from both academic research and industry practices in market regime detection.

---

## License

This project is licensed under the **MIT License**. See the [LICENSE](LICENSE) file for details.

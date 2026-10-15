# 🚀 SkyRocket Customer Service AI Automation
# Customer Chatbot Analysis

An AI-powered customer support analytics project designed to analyze customer service conversations, discover recurring topics, extract important entities, and evaluate the quality of support responses.

## Project Overview

This project explores how NLP and large language models can help teams understand customer conversations, identify common issues, and assess support-response quality.

## Key Features

- **Topic Discovery:** Identify recurring themes in customer conversations.
- **Entity Extraction:** Extract useful information from conversations.
- **Response Evaluation:** Assess support responses using defined quality criteria.
- **Interactive Dashboard:** Explore conversation analytics through a web interface.
- **API Integration:** Expose selected functionality through API endpoints.

## Technology Stack

Python, NLP, machine learning, large language models, data processing, and web application development.

## Project Status

Portfolio learning project. Setup instructions, configuration requirements, and verified run commands will be documented as the application is tested locally.

## Credits

This repository is an independently maintained copy of the original project by [avinash7055](https://github.com/avinash7055/Customer_chatbot_analysis). Original work and applicable license terms are acknowledged. Additional modifications will be documented as they are implemented.



## 🚀 Quick Start

### Prerequisites
- Python 3.8+
- pip (Python package manager)
- Git

### Installation

1. **Clone the repository**
   ```bash
   git clone https://github.com/avinash7055/Customer_chatbot_analysis.git
   cd skyrocket-netomi-submission
   ```

2. **Set up a virtual environment** (recommended)
   ```bash
   python -m venv venv
   source venv/bin/activate  # On Windows: .\venv\Scripts\activate
   ```

3. **Install dependencies**
   ```bash
   pip install -r requirements.txt
   ```

4. **Set up environment variables**
   Create a `.env` file in the root directory with your configuration:
   ```env
   # API Keys
   OPENAI_API_KEY=your_openai_api_key
   GROQ_API_KEY=your_groq_api_key
   
   # Application Settings
   DEBUG=True
   SECRET_KEY=your_secret_key
   ```

5. **Run the application**
   ```bash
   # Start the backend server
   cd webapp/backend
   python app.py
   
   # In a new terminal, start the frontend (if available)
   cd ../frontend
   # Follow frontend specific instructions
   ```

## 🏗️ Project Structure

```
src/
├── skyrocket/                 # Core application code
│   ├── core/                 # Core business logic
│   ├── data/                 # Data processing modules
│   ├── pipelines/            # Data processing pipelines
│   └── utils/                # Utility functions

webapp/
├── backend/                  # Backend API server
│   ├── app.py               # Main FastAPI application
│   └── routes/              # API endpoints
└── frontend/                # Frontend application (if applicable)

data/                        # Data files (input/output)
config/                      # Configuration files
docs/                        # Documentation
scripts/                     # Utility scripts
```

## 📚 Documentation

For detailed documentation, please refer to the [docs](docs/) directory.

## 🤝 Contributing

Contributions are welcome! Please follow these steps:

1. Fork the repository
2. Create a feature branch (`git checkout -b feature/AmazingFeature`)
3. Commit your changes (`git commit -m 'Add some AmazingFeature'`)
4. Push to the branch (`git push origin feature/AmazingFeature`)
5. Open a Pull Request

## 📄 License

This project is licensed under the MIT License - see the [LICENSE](LICENSE) file for details.

## 🙏 Acknowledgments

- [Netomi](https://netomi.com/) for the opportunity
- All open-source libraries and tools used in this project

## 📋 Table of Contents

- [Overview](#overview)
- [Key Features](#key-features)
- [Quick Start](#quick-start)
- [Project Structure](#project-structure)
- [Usage Guide](#usage-guide)
- [Technical Approach](#technical-approach)
- [Results & Insights](#results--insights)
- [Dashboard](#dashboard)
- [Production Deployment](#production-deployment)

---

## 🎯 Overview

This submission demonstrates senior-level AI automation engineering for SkyRocket's customer service optimization. The system analyzes 6,500+ customer queries and GenAI responses using modern LLM-first techniques exclusively powered by **Groq API**.

### Business Impact

- **💰 $300K+ annual savings potential** through improved containment
- **📈 70-85% containment rate** (queries resolved without human escalation)
- **⚡ <200ms Groq inference latency** for real-time classification
- **🎯 10 semantic topics discovered** with automated labeling
- **🔍 Hybrid entity extraction** for structured data capture

---

## ✨ Key Features

### 1. **Modern Topic Discovery**
- Sentence embeddings (all-MiniLM-L6-v2)
- UMAP dimensionality reduction
- HDBSCAN clustering
- **Groq LLM cluster labeling** (llama-3.1-70b)

### 2. **LLM-as-a-Judge Evaluation**
- Automated response quality assessment
- 6 evaluation dimensions:
  - Accuracy (1-5)
  - Empathy (1-5)
  - Completeness (1-5)
  - Hallucination detection (True/False)
  - Escalation needed (True/False)
  - Bias detection (True/False)

### 3. **Hybrid Entity Extraction**
- spaCy NER for standard entities
- **Groq LLM** for domain-specific extraction
- Structured JSON output (ORDER_ID, TRACKING_NUMBER, etc.)

### 4. **Few-Shot Topic Classification**
- Fast inference with Mixtral-8x7b
- 85%+ accuracy on discovered topics
- Production-ready prompt templates

### 5. **Synthetic Data Generation**
- **Groq-powered** realistic query generation
- Balances low-volume topics
- 50 queries per topic

### 6. **Interactive Dashboard**
- Real-time metrics (Streamlit + Plotly)
- Containment & escalation tracking
- Topic trends & quality monitoring
- Hallucination detection
- Model drift simulation

### 7. **Production ETL Pipeline**
- Prefect 2.0 orchestration
- Pandera data quality validation
- Automated error handling & retries
- Monitoring & alerting hooks

---

## 🚀 Quick Start

### Prerequisites

- Python 3.9+
- Groq API key ([Get one here](https://console.groq.com/))

### Installation (< 10 minutes)

```bash
# 1. Clone or extract the submission
cd skyrocket-netomi-submission

# 2. Create virtual environment
python -m venv venv
source venv/bin/activate  # Windows: venv\Scripts\activate

# 3. Install dependencies
pip install -r requirements.txt

# 4. Download spaCy model
python -m spacy download en_core_web_sm

# 5. Configure API key
cp .env.example .env
# Edit .env and add your GROQ_API_KEY

# 6. Prepare data
cd src
python prepare_data.py
```

### Run Analysis Pipeline

```bash
# Topic Discovery (5-10 minutes)
python topic_discovery.py

# Entity Extraction (2-3 minutes)
python entity_extractor.py

# LLM Judge Evaluation (10-15 minutes for 100 samples)
python llm_judge.py

# Few-Shot Classification
python topic_classifier.py

# Synthetic Data Generation
python synthetic_data.py
```

### Launch Dashboard

```bash
cd ../dashboard
streamlit run app.py
```

Dashboard opens at `http://localhost:8501`

---

## 📁 Project Structure

```
skyrocket-netomi-submission/
├── config/
│   └── prompts/                         # Prompt templates and configs
│
├── data/                                # Data storage
│   ├── queries.csv                      # Extracted customer queries
│   ├── genai_responses.csv              # Query-response pairs
│   └── ...
│
├── docs/                                # Documentation
│   └── webapp/                          # Webapp specific docs
│
├── scripts/                             # Utility scripts
│   ├── setup.bat                        # Setup script
│   └── start_webapp.bat                 # Webapp launcher
│
├── src/
│   └── skyrocket/                       # Main package
│       ├── core/                        # Core logic (Discovery, Extraction, Judge)
│       ├── data/                        # Data processing & generation
│       └── pipelines/                   # ETL Pipelines
│
├── webapp/                              # Web Application
│   ├── backend/                         # FastAPI Backend
│   └── frontend/                        # HTML/JS Frontend
│
├── report/                              # Analysis Report
├── requirements.txt                     # Dependencies
└── README.md                            # Project Overview
```

---

## 📖 Usage Guide

### 1. Setup

```bash
# Run the automated setup script
scripts\setup.bat
```

### 2. Data Preparation

```bash
python src/skyrocket/data/prepare_data.py
```

**Output:**
- Converts Excel to CSV
- Prints data statistics
- Identifies patterns

### 3. Topic Discovery

```bash
python src/skyrocket/core/topic_discovery.py
```

**What it does:**
- Generates embeddings for all queries
- Clusters with HDBSCAN
- Labels clusters using Groq LLM
- Outputs exactly 10 topics with 5 examples each

**Output files:**
- `data/topic_discovery_results.json`

### 4. Entity Extraction

```bash
python src/skyrocket/core/entity_extractor.py
```

**What it does:**
- Extracts entities using spaCy NER
- Supplements with Groq structured extraction
- Identifies ORDER_ID, TRACKING_NUMBER, PRODUCT_NAME, etc.

**Output files:**
- `data/entity_extraction_results.json`

### 5. Response Evaluation

```bash
python src/skyrocket/core/llm_judge.py
```

**What it does:**
- Evaluates query-response pairs with Groq LLM
- Scores on 6 dimensions
- Calculates containment rate
- Identifies hallucinations

**Output files:**
- `data/evaluated_responses.csv`
- `data/evaluation_report.json`

**Note:** Processes 100 samples by default. Edit `main()` to process full dataset.

### 6. Few-Shot Classification

```bash
python src/skyrocket/core/topic_classifier.py
```

**What it does:**
- Builds few-shot prompt from discovered topics
- Tests classification accuracy
- Uses fast Mixtral-8x7b model

### 7. Synthetic Data Generation

```bash
python src/skyrocket/data/synthetic_data.py
```

**What it does:**
- Identifies low-volume topics
- Generates 50 realistic queries per topic using Groq
- Balances training data

---

## 🔬 Technical Approach

### Why Groq?

✅ **Ultra-fast inference** (<200ms latency)  
✅ **Cost-effective** at scale  
✅ **Production-ready** API  
✅ **Multiple models** (llama, mixtral, gemma)  
✅ **Structured output** support  

### Architecture

```
Data → Embeddings → UMAP → HDBSCAN → Groq Labeling
                                           ↓
                                    Topic Framework
                                           ↓
                              ┌────────────┴────────────┐
                              ↓                         ↓
                    Few-Shot Classifier      Synthetic Generator
                     (Mixtral-8x7b)           (Llama-3.1-70b)
                              ↓                         ↓
                         Production Use           Data Augmentation


Query + Response → Groq LLM-as-a-Judge → Evaluation Scores
                        (Llama-3.1-70b)          ↓
                                          Metrics Dashboard
```

### Model Selection

| Use Case | Model | Rationale |
|----------|-------|-----------|
| Topic Labeling | llama-3.1-70b | Best semantic understanding |
| Response Evaluation | llama-3.1-70b | Nuanced judgment needed |
| Entity Extraction | llama-3.1-8b | Fast, structured output |
| Classification | mixtral-8x7b | Speed + accuracy balance |
| Synthetic Data | llama-3.1-70b | Creative generation |

---

## 📊 Results & Insights

### Discovered Topics (Top 10)

1. **Order Cancellation** - 892 queries (13.6%)
2. **Tracking & Shipping** - 784 queries (12.0%)
3. **Account Access Issues** - 651 queries (10.0%)
4. **Payment & Refunds** - 589 queries (9.0%)
5. **Product Information** - 512 queries (7.8%)
6. **Delivery Issues** - 487 queries (7.5%)
7. **Returns & Exchanges** - 423 queries (6.5%)
8. **Account Management** - 398 queries (6.1%)
9. **Order Modifications** - 356 queries (5.4%)
10. **Technical Support** - 312 queries (4.8%)

### Quality Metrics

- **Average Accuracy:** 4.2/5.0
- **Average Empathy:** 3.8/5.0
- **Average Completeness:** 3.9/5.0
- **Overall Quality:** 3.97/5.0

### Issue Detection

- **Hallucination Rate:** 3.2%
- **Escalation Needed:** 18.5%
- **Containment Rate:** 81.5%
- **Bias Detected:** 0.8%

### Business Impact

- **Current Containment:** 81.5%
- **Target Containment:** 85% (achievable)
- **Monthly Queries:** ~6,500
- **Contained Queries:** 5,298
- **Cost per Agent Query:** $5
- **Monthly Savings:** $26,490
- **Annual Savings:** **$317,880**

---

## 📱 Dashboard

The Streamlit dashboard provides real-time insights:

### Features

1. **Executive Summary**
   - Containment rate
   - Quality scores  
   - Hallucination rate
   - ROI calculator

2. **Topic Analysis**
   - Volume distribution
   - Quality by topic
   - Trend analysis

3. **Quality Monitoring**
   - Score distributions
   - Radar charts
   - Issue flagging

4. **Entity Insights**
   - Most common entities
   - Extraction patterns

5. **Drift Detection**
   - Quality trends over time
   - Automated alerts

### Screenshots

*Dashboard loads data from `data/` directory and visualizes all metrics.*

---

## 🏭 Production Deployment

### Prefect Pipeline

Run the production ETL pipeline:

```bash
cd src/pipelines
python daily_etl_prefect.py
```

**Pipeline includes:**
- ✅ Data extraction
- ✅ Quality validation (Pandera schemas)
- ✅ Topic classification (Groq)
- ✅ Entity extraction
- ✅ Response evaluation (Groq Judge)
- ✅ Metrics calculation
- ✅ Threshold monitoring
- ✅ Results persistence

### CI/CD Integration

```yaml
# .github/workflows/daily-pipeline.yml
name: Daily Customer Query Processing

on:
  schedule:
    - cron: '0 2 * * *'  # Run at 2 AM daily

jobs:
  run-pipeline:
    runs-on: ubuntu-latest
    steps:
      - uses: actions/checkout@v2
      - name: Set up Python
        uses: actions/setup-python@v2
        with:
          python-version: '3.9'
      - name: Install dependencies
        run: pip install -r requirements.txt
      - name: Run pipeline
        env:
          GROQ_API_KEY: ${{ secrets.GROQ_API_KEY }}
        run: python src/pipelines/daily_etl_prefect.py
```

### Monitoring & Alerts

- **Quality thresholds**: Automatic alerts when metrics drop
- **Drift detection**: Monitor topic distribution shifts
- **Hallucination tracking**: Flag suspicious responses
- **Slack/Email integration**: Real-time notifications

---

## 🔧 Configuration

### Environment Variables

```bash
# Required
GROQ_API_KEY=gsk_...

# Optional model overrides
GROQ_MODEL_LARGE=llama-3.1-70b-versatile
GROQ_MODEL_SMALL=llama-3.1-8b-instant
GROQ_MODEL_FAST=mixtral-8x7b-32768
```

### Tuning Parameters

Edit in respective source files:

**Topic Discovery** (`topic_discovery.py`):
```python
UMAP(n_components=5, n_neighbors=15, min_dist=0.0)
HDBSCAN(min_cluster_size=50, min_samples=10)
```

**LLM Judge** (`llm_judge.py`):
```python
temperature=0.2  # Lower = more consistent
max_tokens=500
```

**Classification** (`topic_classifier.py`):
```python
temperature=0.1  # Lower = more deterministic
model="mixtral-8x7b-32768"
```

---

## 📈 Performance

### Speed Benchmarks

| Operation | Time (100 samples) | Time (6500 samples) |
|-----------|-------------------|---------------------|
| Topic Discovery | ~3 min | ~12 min |
| Entity Extraction | 30 sec | ~3 min |
| LLM Judge Evaluation | ~8 min | ~85 min* |
| Classification | 45 sec | ~5 min |

*Groq's ultra-fast inference makes this feasible. Traditional APIs would take hours.*

### Groq Advantages

- **Latency:** <200ms per request
- **Throughput:** High concurrent requests
- **Cost:** Competitive pricing
- **Models:** State-of-the-art llama, mixtral, gemma

---

## 🧪 Testing

Run individual modules in test mode:

```bash
# Test with 10 samples
python topic_discovery.py --sample 10

# Test judge with 50 samples
python llm_judge.py --sample 50
```

---

## 📝 Documentation

- **Full Report:** [`report/SkyRocket_Netomi_Report.md`](report/SkyRocket_Netomi_Report.md)
- **Prompts:** All prompts stored in `prompts/` directory
- **Code Documentation:** Docstrings in all modules

---

## 🎓 Key Takeaways

### What Makes This Production-Grade

1. ✅ **100% Groq LLM** - No legacy sentiment analysis
2. ✅ **Modular architecture** - Easy to extend
3. ✅ **Data quality validation** - Pandera schemas
4. ✅ **Error handling** - Retries & fallbacks
5. ✅ **Monitoring ready** - Metrics & alerts
6. ✅ **Scalable** - Prefect orchestration
7. ✅ **Business-focused** - ROI calculations
8. ✅ **Well-documented** - Clear code & comments

### Innovations

- **Hybrid entity extraction** (spaCy + Groq)
- **Few-shot classification** with Groq
- **Synthetic data generation** for low-volume topics
- **Real-time quality monitoring**
- **Automated drift detection**

---

## 🤝 About This Submission

**Role:** AI Automation Engineer - SkyRocket Customer Service Optimization  
**Company:** Netomi  
**Submission Date:** November 27, 2025  
**Technologies:** Groq, Python, Streamlit, Prefect, Pandas, spaCy, sentence-transformers, HDBSCAN, UMAP  

**Contact:**  
This is a demonstration project showcasing production-ready AI automation engineering.

---

## 📜 License

This is a take-home assignment submission. All rights reserved.

---

## 🙏 Acknowledgments

- **Groq** for ultra-fast LLM inference
- **Netomi** for the opportunity
- **Open-source community** for amazing tools

---

**Made with ❤️ for intelligent customer service automation**

🚀 **Ready to transform customer service with AI!**

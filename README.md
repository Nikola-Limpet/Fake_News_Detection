# 🔍 Fake News Detection System

## AI-Powered Misinformation Detection for ITM-360

![Python](https://img.shields.io/badge/Python-3.8%2B%20%7C%203.12-blue)
![TensorFlow](https://img.shields.io/badge/TensorFlow-2.13-orange)
![Streamlit](https://img.shields.io/badge/Streamlit-1.25-red)
![License](https://img.shields.io/badge/License-MIT-green)

## 📋 Table of Contents
- [Overview](#overview)
- [Features](#features)
- [Architecture](#architecture)
- [Installation](#installation)
- [Dataset Setup](#dataset-setup)
- [Usage](#usage)
- [Model Training](#model-training)
- [API Integration](#api-integration)
- [Performance](#performance)
- [Team](#team)
- [Troubleshooting](#troubleshooting)

## 🎯 Overview

This project implements a comprehensive fake news detection system using multiple machine learning and deep learning approaches. Developed for the ITM-360 Artificial Intelligence course at American University of Phnom Penh, it combines traditional ML methods with state-of-the-art transformer models to accurately identify misinformation.

## ✨ Features

### Core Functionality
- **Multi-Model Support**: Naive Bayes, Random Forest, LSTM, and BERT models
- **Real-time Prediction**: Instant analysis of news articles
- **Explainable AI**: LIME and SHAP integration for transparent predictions
- **Web Interface**: User-friendly Streamlit application
- **API Integration**: Support for NewsAPI for real-time news fetching

### Technical Features
- **Advanced Text Preprocessing**: Lemmatization, stopword removal, and cleaning
- **Multiple Feature Extraction Methods**: TF-IDF, Word2Vec, BERT embeddings
- **Hyperparameter Optimization**: GridSearchCV for optimal model parameters
- **Cross-validation**: Robust model evaluation
- **Visualization Dashboard**: Analytics and performance metrics

## 🏗️ Architecture

```
fake-news-detection/
│
├── models/                    # Trained model files
│   ├── logistic_model.pkl     # Logistic regression model
│   ├── vectorizer.pkl         # TF-IDF vectorizer
│   └── training_results.json  # Model performance metrics
│
├── data/                      # Dataset directory
│   └── fake_news_data.csv     # Combined fake/real news dataset
│
├── archive/                   # Archived/old files
│   ├── streamlit_app_old.py   # Previous version with advanced features
│   └── streamlit_app_working.py # Working version backup
│
├── tests/                     # Unit test files
│   └── test_model_utils.py    # Model utility tests
│
├── src/                       # Source code modules
│   ├── preprocessing.py       # Text preprocessing utilities
│   ├── feature_extraction.py  # Feature extraction methods
│   └── models.py             # Model definitions
│
├── notebooks/                 # Jupyter notebooks for experimentation
│   └── (empty - ready for analysis notebooks)
│
├── logs/                     # Application logs
├── outputs/                  # Model training outputs
├── script/                   # Setup and utility scripts
│   └── quickstart.sh         # Quick setup script
│
├── streamlit_app.py          # Main Streamlit web application
├── fake_news_detection.py    # Model training script
├── model_utils.py            # Model loading and prediction utilities
├── data_preparation.py       # Data processing script
├── demo_improvements.py      # System improvements demo
├── requirements.txt          # Python dependencies
├── config.yaml              # Configuration settings
├── .env                     # Environment variables (NewsAPI key)
└── README.md                # Project documentation
```

## 🚀 Installation

### Prerequisites
- Python 3.8 or higher
- CUDA-capable GPU (optional, for faster training)
- 8GB RAM minimum (16GB recommended)

### Quick Setup (Recommended)
```bash
# Clone the repository
git clone https://github.com/your-username/fake-news-detection.git
cd fake-news-detection

# Run the quickstart script (handles everything automatically)
./script/quickstart.sh
```

### Manual Setup
If you prefer manual installation:

#### Step 1: Create Virtual Environment
```bash
# Using venv
python -m venv venv

# Activate on Windows
venv\Scripts\activate

# Activate on macOS/Linux
source venv/bin/activate
```

#### Step 2: Install Dependencies
```bash
pip install -r requirements.txt

# Download NLTK data
python -c "import nltk; nltk.download('punkt'); nltk.download('punkt_tab'); nltk.download('stopwords'); nltk.download('wordnet')"
```

## 📊 Dataset Setup

> **Note**: Data files are not included in this repository due to GitHub's 100MB file size limit.

### Option 1: Kaggle Dataset (Recommended)
1. Download from [Kaggle Fake and Real News Dataset](https://www.kaggle.com/datasets/clmentbisaillon/fake-and-real-news-dataset)
2. Extract `Fake.csv` and `True.csv` to the `data/` directory
3. Run the data preparation script:
```bash
python data_preparation.py
```
This will create `fake_news_data.csv`, `train.csv`, `test.csv`, and `validation.csv` in the `data/` folder.

### Option 2: Custom Dataset
Your dataset should have the following format:
```csv
text,label
"Article content here...",REAL
"Another article...",FAKE
```
Place it in the `data/` directory as `fake_news_data.csv`.

## 💻 Usage

### Quick Start (TL;DR)
```bash
# 1. Clone and setup
git clone https://github.com/your-username/fake-news-detection.git
cd fake-news-detection
python -m venv venv && source venv/bin/activate  # Windows: venv\Scripts\activate
pip install -r requirements.txt

# 2. Download dataset from Kaggle (see Dataset Setup section)
# Place Fake.csv and True.csv in data/ folder

# 3. Prepare data
python data_preparation.py

# 4. Run the app
streamlit run streamlit_app.py
```

### Data Preparation
1. **Prepare the dataset:**
```bash
python data_preparation.py
```

### Training the Models (Optional)
Pre-trained models are included. To retrain:
```bash
python train_transformer.py  # For transformer model
```

### Running the Streamlit App

```bash
streamlit run streamlit_app.py
```

Navigate to `http://localhost:8501` in your browser.

### Making Predictions

```python
from src.models import FakeNewsPredictor

predictor = FakeNewsPredictor('models/best_model.pkl')
result = predictor.predict("Your news article text here...")
print(f"Prediction: {result['label']}")
print(f"Confidence: {result['confidence']:.2%}")
```

## 🔌 API Integration

### NewsAPI Setup
1. Get API key from [NewsAPI](https://newsapi.org/)
2. Add to `.env` file:
```env
NEWS_API_KEY=your_api_key_here
```

3. Use in the application:
```python
import os
from dotenv import load_dotenv

load_dotenv()
api_key = os.getenv('NEWS_API_KEY')
```

## 📈 Performance

### Model Comparison

| Model | Accuracy | Precision | Recall | F1-Score |
|-------|----------|-----------|--------|----------|
| Naive Bayes | 89.2% | 87.5% | 88.1% | 87.8% |
| Random Forest | 92.1% | 91.3% | 90.2% | 90.7% |
| LSTM | 94.3% | 93.1% | 92.5% | 92.8% |
| BERT | 96.2% | 95.4% | 94.8% | 95.1% |

### Training Time (on GPU)
- Naive Bayes: < 1 minute
- Random Forest: 5-10 minutes
- LSTM: 30-45 minutes
- BERT: 2-3 hours

## 👥 Team

- **Lim Petnikola** (2023465) - Team Leader, Model Development
- **Rim Sovichey** (2024006) - Documentation, Testing
- **Pha Lyheng** (2024007) - Data Preprocessing
- **Sokhonn Raksmeidaravid** (2023503) - UI/UX Development

**Advisor**: Professor Kunthea PIN  
**Institution**: American University of Phnom Penh  
**Course**: ITM-360 Artificial Intelligence

## 🔧 Troubleshooting

### Common Issues

1. **Memory Error during BERT training:**
   - Reduce batch size in configuration
   - Use gradient accumulation
   - Consider using a smaller BERT model (distilbert)

2. **Slow training on CPU:**
   - Install CUDA and cuDNN for GPU support
   - Reduce model complexity
   - Use smaller dataset for testing

3. **Import errors:**
   ```bash
   pip install --upgrade -r requirements.txt
   ```

4. **Streamlit connection error:**
   - Check firewall settings
   - Try different port: `streamlit run app.py --server.port 8502`

### Performance Optimization

```python
# Enable mixed precision training (for GPU)
from tensorflow.keras.mixed_precision import Policy
policy = Policy('mixed_float16')
mixed_precision.set_global_policy(policy)

# Use data generators for large datasets
def data_generator(texts, labels, batch_size):
    while True:
        for i in range(0, len(texts), batch_size):
            yield texts[i:i+batch_size], labels[i:i+batch_size]
```

## 📝 Configuration

Create a `config.yaml` file:

```yaml
# Model Configuration
models:
  naive_bayes:
    alpha: 1.0
  
  random_forest:
    n_estimators: 200
    max_depth: 20
    min_samples_split: 5
  
  lstm:
    embedding_dim: 100
    lstm_units: 128
    dropout: 0.5
    max_length: 100
  
  bert:
    model_name: 'bert-base-uncased'
    max_length: 128
    batch_size: 32

# Training Configuration
training:
  epochs: 10
  validation_split: 0.2
  early_stopping_patience: 3
  learning_rate: 0.001

# Feature Extraction
features:
  tfidf_max_features: 5000
  ngram_range: [1, 2]
  word2vec_size: 100
  word2vec_window: 5
```

## 🔮 Future Enhancements

- [ ] Multi-language support
- [ ] Real-time web scraping
- [ ] Social media integration
- [ ] Fact-checking database integration
- [ ] Mobile application
- [ ] Browser extension
- [ ] API endpoint deployment
- [ ] Automated retraining pipeline

## 📄 License

This project is licensed under the MIT License - see the [LICENSE](LICENSE) file for details.

## 🙏 Acknowledgments

- Kaggle for providing the dataset
- Hugging Face for transformer models
- Streamlit for the web framework
- Our professor and classmates for feedback and support

## 📚 References

1. Shu, K., et al. (2017). "Fake News Detection on Social Media: A Data Mining Perspective"
2. Ahmed, H., et al. (2018). "Detecting opinion spams and fake news using text classification"
3. Devlin, J., et al. (2019). "BERT: Pre-training of deep bidirectional transformers"

---

**Note**: This is an academic project. While the system shows promising results, it should not be the sole determinant for news verification. Always cross-reference with multiple reliable sources.# Fake_News_Detection

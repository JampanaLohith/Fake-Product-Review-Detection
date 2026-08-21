import re
import string
import numpy as np
import scipy.sparse
import nltk
from nltk.corpus import stopwords
from nltk.stem import WordNetLemmatizer
from nltk.sentiment.vader import SentimentIntensityAnalyzer

# Define local NLTK data directory inside project root to ensure it is packaged by Render/Heroku
import os
PROJECT_ROOT = os.path.dirname(os.path.abspath(__file__))
NLTK_DATA_DIR = os.path.join(PROJECT_ROOT, 'nltk_data')
if not os.path.exists(NLTK_DATA_DIR):
    os.makedirs(NLTK_DATA_DIR)

# Tell NLTK to look in this directory
if NLTK_DATA_DIR not in nltk.data.path:
    nltk.data.path.append(NLTK_DATA_DIR)

# Safe download of NLTK resources
def download_nltk_resources():
    resources = {
        'stopwords': 'corpora/stopwords',
        'wordnet': 'corpora/wordnet',
        'omw-1.4': 'corpora/omw-1.4',
        'vader_lexicon': 'sentiment/vader_lexicon'
    }
    for name, path in resources.items():
        try:
            nltk.data.find(path)
        except LookupError:
            nltk.download(name, download_dir=NLTK_DATA_DIR, quiet=True)

# Initialize resources
download_nltk_resources()
try:
    STOPWORDS = set(stopwords.words('english'))
except:
    STOPWORDS = set()
LEMMATIZER = WordNetLemmatizer()
try:
    SIA = SentimentIntensityAnalyzer()
except:
    SIA = None

def preprocess_text(text):
    """
    Cleans raw review text by:
    - Lowercasing
    - Removing punctuation
    - Removing extra spaces
    - Tokenizing & Lemmatizing
    - Removing stopwords
    """
    if not isinstance(text, str):
        return ""
    
    # Lowercase
    text = text.lower()
    
    # Remove punctuation
    text = text.translate(str.maketrans('', '', string.punctuation))
    
    # Tokenize and remove extra spacing
    words = re.findall(r'\b\w+\b', text)
    
    # Lemmatize and remove stopwords
    cleaned_words = [LEMMATIZER.lemmatize(word) for word in words if word not in STOPWORDS]
    
    return " ".join(cleaned_words)

def extract_dense_features(text):
    """
    Extracts hand-crafted numeric features:
    1. Review length (characters)
    2. Number of exclamation marks
    3. Number of capital letters
    4. Average word length
    5. Positive sentiment score
    6. Negative sentiment score
    """
    if not isinstance(text, str):
        text = ""
        
    length = len(text)
    excl_count = text.count('!')
    caps_count = sum(1 for c in text if c.isupper())
    
    words = text.split()
    avg_word_len = np.mean([len(w) for w in words]) if words else 0.0
    
    # Sentiment scores using VADER
    pos_score = 0.0
    neg_score = 0.0
    if SIA:
        scores = SIA.polarity_scores(text)
        pos_score = scores.get('pos', 0.0)
        neg_score = scores.get('neg', 0.0)
        
    return np.array([
        float(length),
        float(excl_count),
        float(caps_count),
        float(avg_word_len),
        float(pos_score),
        float(neg_score)
    ])

def explain_prediction(text, lr_model, vectorizer, scaler):
    """
    Explains the Logistic Regression prediction for a single review.
    Calculates log-odds contribution of both TF-IDF words and dense features.
    """
    explanation = {
        'genuine_indicators': [],
        'fake_indicators': [],
        'intercept': float(lr_model.intercept_[0]),
        'dense_metrics': {}
    }
    
    # 1. Capture original metrics
    dense_raw = extract_dense_features(text)
    explanation['dense_metrics'] = {
        'length': int(dense_raw[0]),
        'exclamation_marks': int(dense_raw[1]),
        'capital_letters': int(dense_raw[2]),
        'avg_word_len': round(dense_raw[3], 2),
        'positive_sentiment': round(dense_raw[4], 2),
        'negative_sentiment': round(dense_raw[5], 2)
    }
    
    # 2. Get scaled dense features and their coefficients
    dense_scaled = scaler.transform(dense_raw.reshape(1, -1))[0]
    num_vocab = len(vectorizer.get_feature_names_out())
    dense_coefs = lr_model.coef_[0][num_vocab:]
    
    dense_names = [
        'Review Length',
        'Exclamation Marks',
        'Capital Letters',
        'Average Word Length',
        'Positive Sentiment',
        'Negative Sentiment'
    ]
    
    # Compute contributions for dense features
    for name, val, coef in zip(dense_names, dense_scaled, dense_coefs):
        contrib = val * coef
        feat_info = {
            'feature': name,
            'contribution': float(contrib),
            'type': 'structural'
        }
        if contrib > 0.01:
            explanation['fake_indicators'].append(feat_info)
        elif contrib < -0.01:
            explanation['genuine_indicators'].append(feat_info)
            
    # 3. Get word (TF-IDF) feature contributions
    clean_text = preprocess_text(text)
    if clean_text:
        tfidf_vector = vectorizer.transform([clean_text])
        # Find active features
        nonzero_indices = tfidf_vector.nonzero()[1]
        word_features = vectorizer.get_feature_names_out()
        
        for idx in nonzero_indices:
            val = tfidf_vector[0, idx]
            coef = lr_model.coef_[0][idx]
            contrib = val * coef
            word = word_features[idx]
            
            feat_info = {
                'feature': f'Word: "{word}"',
                'contribution': float(contrib),
                'type': 'word'
            }
            if contrib > 0.01:
                explanation['fake_indicators'].append(feat_info)
            elif contrib < -0.01:
                explanation['genuine_indicators'].append(feat_info)
                
    # Sort indicators by absolute contribution
    explanation['fake_indicators'].sort(key=lambda x: abs(x['contribution']), reverse=True)
    explanation['genuine_indicators'].sort(key=lambda x: abs(x['contribution']), reverse=True)
    
    return explanation

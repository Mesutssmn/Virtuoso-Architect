# 🎹 Virtuoso Architect

<div align="center">

![License](https://img.shields.io/badge/license-MIT-blue.svg)
![Python](https://img.shields.io/badge/python-3.8%2B-blue)
![Status](https://img.shields.io/badge/status-active-success)

**An AI-Powered System for Quantifying Piano Music Technical Difficulty**

*Transforming subjective musical complexity into objective, data-driven metrics using Machine Learning and Music Information Retrieval*

[Features](#-key-features) • [Installation](#-installation) • [Usage](#-usage-guide) • [Architecture](#-system-architecture) • [Contributing](#-contributing)

</div>

---

## 📋 Table of Contents

- [Overview](#overview)
- [Key Features](#key-features)
- [Project Structure](#project-structure)
- [Technology Stack](#technology-stack)
- [System Architecture](#system-architecture)
- [Installation](#installation)
- [Usage Guide](#usage-guide)
  - [Feature Extraction System](#feature-extraction)
  - [Labeling Systems](#labeling-systems)
  - [Training Pipeline](#training-pipeline)
  - [Evaluation & Verification](#evaluation-verification)
- [Classification Schema](#classification-schema)
- [Feature Engineering](#feature-engineering)
- [Manual Labeling Interface](#manual-labeling-interface)
- [Auto-Labeling System](#auto-labeling-system)
- [Training & Model Architecture](#training-model-architecture)
- [Future Improvements](#future-improvements)
- [Contributing](#contributing)
- [License](#license)

---

<a id="overview"></a>
## 🎯 Overview

**Virtuoso Architect** is a comprehensive, research-grade system designed to objectively quantify the technical difficulty of piano compositions. The project addresses a fundamental challenge in music education and analysis: converting subjective assessments of musical complexity into precise, reproducible metrics.

### The Challenge

Traditional difficulty assessment relies on expert opinion, which is:
- **Subjective**: Varies between evaluators
- **Inconsistent**: Hard to reproduce across pieces
- **Time-consuming**: Requires extensive musical training
- **Non-scalable**: Cannot process large music libraries

### Our Solution

We've built an end-to-end ML pipeline that:

1. **Extracts** musical features from MIDI files using Music Information Retrieval (MIR) techniques
2. **Quantifies** technical complexity through 10+ engineered features
3. **Classifies** pieces into difficulty categories using gradient boosting
4. **Validates** predictions through both automated rules and human-in-the-loop verification

The system achieves **professional-grade accuracy** by combining music theory expertise with modern machine learning, making it suitable for:
- 🎓 Music education platforms
- 📚 Digital sheet music libraries
- 🔬 Music AI research
- 🎼 Composer tools and analysis

---

<a id="key-features"></a>
## ✨ Key Features

### 🎼 Musical Intelligence
- **Advanced Feature Extraction**: 10+ metrics capturing hand stretch, polyphony, rhythm complexity, and more
- **Theory-Driven Design**: Features based on established piano pedagogy and biomechanics
- **MIDI Processing**: Works with standard MIDI files (`.mid`, `.midi`)

### 🤖 Machine Learning Pipeline
- **XGBoost Classifier**: State-of-the-art gradient boosting optimized for tabular data
- **Dual Classification Schema**: Support for both 4-class and 5-class taxonomies
- **Automated Evaluation**: Confusion matrices, precision/recall metrics, classification reports

### 🏷️ Flexible Labeling
- **Auto-Labeling**: Rule-based system applying music theory heuristics
- **Manual Interface**: Web-based UI for human verification and correction
- **Hybrid Workflow**: Combine automated speed with human expertise

### 🔧 Production-Ready
- **Modular Architecture**: Clean separation of concerns (ETL, training, evaluation)
- **Configuration Management**: Centralized config system preventing drift
- **Reproducibility**: Versioned datasets, deterministic splitting, saved models

---

<a id="project-structure"></a>
## 📂 Project Structure

```
Virtuoso-Architect/
│
├── 📁 data/                          # Data Lake & Warehouse
│   ├── raw_midi/                     # Source of truth: Original MIDI files
│   │   └── *.mid, *.midi             # Thousands of piano compositions
│   │
│   └── processed/                    # Transformed data artifacts
│       ├── features_all.csv          # Feature Store: Extracted metrics for all files
│       └── labels/                   # Ground Truth Store
│           ├── auto_4_labels.csv     # Auto-generated 4-class labels
│           ├── auto_5_labels.csv     # Auto-generated 5-class labels
│           ├── manual_4_labels.csv   # Human-verified 4-class labels
│           └── manual_5_labels.csv   # Human-verified 5-class labels
│
├── 📁 models/                        # Trained Model Artifacts
│   ├── difficulty_classifier.pkl     # Trained classification model
│   └── difficulty_classifier_full.pkl # Full dataset model variant
│
├── 📁 scripts/                       # Core ML Pipeline Scripts
│   ├── extract_features.py           # ETL: MIDI → Features (CSV)
│   ├── train_with_labels.py          # Training: Features + Labels → Model
│   ├── evaluate_model.py             # Evaluation: Model + Test Set → Metrics
│   ├── analyze_model.py              # Analysis: Feature importance & correlations
│   └── verify_system.py              # Integration Testing: End-to-End Pipeline
│
├── 📁 src/                           # Source Code Modules
│   ├── main.py                       # 🚀 CLI Entry Point: Single file analysis
│   ├── ml_engine/                    # Machine Learning Core
│   │   ├── __init__.py
│   │   ├── feature_extract.py        # Logic for converting MIDI to features
│   │   └── train.py                  # XGBoost training logic
│   │
│   └── rag_engine/                   # RAG AI Module (OpenAI Integration)
│       ├── __init__.py
│       ├── retriever.py              # GPT-4o connector
│       └── knowledge_base.json       # Pedagogy database
│
├── 📁 tools/                         # Labeling & Utilities
│   └── labeling/                     # Ground Truth Generation Suite
│       ├── config.py                 # 🧠 CENTRAL CONFIG: Label schemas & thresholds
│       │
│       ├── auto/                     # Automated Labeling System
│       │   └── auto_label.py         # Rule engine applying theory-based heuristics
│       │
│       └── manual/                   # Human-in-the-Loop Labeling
│           ├── labeling_server.py    # Flask API serving features & MIDI info
│           ├── labeling_interface.html # Single-page web UI for annotation
│           └── start_labeling.py     # Launcher script (starts server + opens browser)
│
├── 📄 .env.example                   # Template for environment variables
├── 📄 .gitignore                     # Excludes large files, venv, cache
├── 📄 LICENSE                        # MIT License
├── 📄 README.md                      # This file
└── 📄 requirements.txt               # Python dependencies
```

### Directory Philosophy

#### 🗄️ **Data Layer** (`data/`)
- **Separation of Concerns**: Raw MIDI files remain immutable; processed features are derived artifacts
- **Versioning**: Different label versions coexist (e.g., `auto_4_labels.csv` vs `manual_5_labels.csv`)
- **Reproducibility**: Any experiment can be recreated by referencing specific label files

#### 🧠 **Logic Layer** (`scripts/` & `src/`)
- **Scripts**: High-level workflows (extract → train → evaluate)
- **Modules**: Reusable components (feature extraction algorithms, model wrappers)
- **Single Responsibility**: Each script has one clear purpose

#### 🔧 **Tooling Layer** (`tools/`)
- **Labeling First**: Ground truth is critical; dedicated tools ensure quality
- **Config-Driven**: All labeling logic pulls from `config.py` to prevent schema drift

---

<a id="technology-stack"></a>
## 🛠️ Technology Stack & Library Rationale

We selected a robust, data-centric stack optimized for **precision**, **speed**, and **maintainability**.

### Core Dependencies

| Library | Version | Purpose | Why We Chose It |
|---------|---------|---------|-----------------|
| **numpy** | Latest | Numerical Computing | Foundation for all array operations. Fast vectorized math for feature calculations (mean, std, percentiles). Industry standard with C-optimized backends. |
| **pandas** | Latest | Data Manipulation | Handles large CSV datasets (`features_all.csv` with 10,000+ rows). Provides SQL-like operations (filtering, merging, grouping). Essential for train/test splitting and label alignment. |
| **pretty_midi** | Latest | MIDI Parsing | Higher-level abstraction than `mido`. Provides convenient access to notes, instruments, tempo, and timing. Built-in utilities for pitch/time conversions. |
| **scikit-learn** | Latest | ML Utilities | Industry-standard toolkit for data splitting (`train_test_split`), metrics (confusion matrices, classification reports), and preprocessing (normalization, encoding). Ensures reproducibility with `random_state`. |
| **xgboost** | Latest | Gradient Boosting | **The core model**. Chosen over deep learning (e.g., LSTM) because our features are **tabular/structured**. XGBoost excels at learning complex decision boundaries from engineered features. Provides feature importance for interpretability. Faster training than neural networks. |
| **torch** | Latest | Deep Learning (Future) | Currently minimal usage. Reserved for future enhancements (e.g., spectrogram-based models, audio-to-MIDI transcription). PyTorch chosen for its research-friendly API and dynamic computation graphs. |
| **openai** | Latest | LLM Integration (Future) | Placeholder for potential GPT-based feature explanations or automated labeling suggestions. Currently unused but in requirements for rapid prototyping. |
| **tqdm** | Latest | Progress Tracking | Provides progress bars for long-running operations (feature extraction, training). Critical for UX in CLI tools processing 10,000+ files. |
| **music21** | Latest | Music Theory Analysis | Computational music analysis toolkit. Used for advanced feature extraction (key detection, chord analysis, voice separation). Complements `pretty_midi` for high-level musical concepts. |
| **python-dotenv** | Latest | Environment Management | Loads API keys and config from `.env` files. Keeps secrets out of version control. Standard practice for production applications. |
| **matplotlib** | Latest | Visualization | Generates plots for model evaluation (confusion matrices, ROC curves). Essential for debugging feature distributions. |
| **seaborn** | Latest | Statistical Visualization | Higher-level plotting API built on matplotlib. Provides beautiful, publication-ready charts with minimal code (heatmaps, violin plots). |
| **flask** | Latest | Web Framework | Powers the manual labeling interface API. Lightweight WSGI framework perfect for internal tools. No overhead of Django; just RESTful endpoints. |
| **flask-cors** | Latest | CORS Handling | Enables the HTML frontend to communicate with the Flask backend. Critical for local development where frontend and backend run on different ports. |

### Why This Stack?

#### 🎯 **Specialized for Tabular Data**
Unlike audio-based models (which require spectrograms and CNNs), we work with **symbolic music data** (MIDI). Our features are structured and numerical, making **tree-based models** (XGBoost) the optimal choice.

#### 🔬 **Research to Production**
- **Prototyping**: `pandas` + `scikit-learn` for rapid experimentation
- **Training**: `xgboost` for production-grade performance
- **Deployment**: `flask` for serving predictions via API

#### 📊 **Explainability**
XGBoost provides:
- Feature importance scores (which metrics matter most?)
- Tree visualizations (how does the model decide?)
- SHAP value integration (future work)

This is crucial for **music education** where teachers need to understand *why* a piece is difficult.

---

<a id="system-architecture"></a>
## 🏗️ System Architecture

### High-Level Data Flow

```
┌─────────────────┐
│  Raw MIDI Files │
│   (10,000+)     │
└────────┬────────┘
         │
         ▼
┌─────────────────────────────┐
│  Feature Extraction Engine  │
│  (extract_features.py)      │
│                             │
│  • Parse MIDI events        │
│  • Calculate statistics     │
│  • Detect patterns          │
└────────┬────────────────────┘
         │
         ▼
┌─────────────────────────────┐
│   features_all.csv          │
│   (Feature Store)           │
│                             │
│  Columns:                   │
│  • max_stretch              │
│  • avg_density              │
│  • polyphony_score          │
│  • thirds_frequency         │
│  • ... (10 total)           │
└────────┬────────────────────┘
         │
         ├──────────────────────────┐
         │                          │
         ▼                          ▼
┌──────────────────┐      ┌──────────────────┐
│  Auto-Labeling   │      │ Manual Labeling  │
│  (Rule Engine)   │      │  (Human Verify)  │
│                  │      │                  │
│  • Apply         │      │  • Web UI        │
│    thresholds    │      │  • Keyboard      │
│  • Music theory  │      │    shortcuts     │
│    heuristics    │      │  • Listen to     │
│                  │      │    MIDI          │
└────────┬─────────┘      └────────┬─────────┘
         │                         │
         ▼                         ▼
┌──────────────────────────────────────────┐
│         labels/ Directory                │
│                                          │
│  • auto_4_labels.csv                     │
│  • auto_5_labels.csv                     │
│  • manual_4_labels.csv                   │
│  • manual_5_labels.csv                   │
└────────┬─────────────────────────────────┘
         │
         ▼
┌─────────────────────────────┐
│   Training Pipeline         │
│   (train_with_labels.py)    │
│                             │
│  1. Merge features + labels │
│  2. Split 80/20             │
│  3. Train XGBoost           │
│  4. Save model              │
└────────┬────────────────────┘
         │
         ▼
┌─────────────────────────────┐
│   Trained Model             │
│   (xgb_classifier_X.pkl)    │
└────────┬────────────────────┘
         │
         ▼
┌─────────────────────────────┐
│   Evaluation                │
│   (evaluate_model.py)       │
│                             │
│  • Confusion Matrix         │
│  • Precision/Recall         │
│  • Classification Report    │
└─────────────────────────────┘
```

### Component Interactions

#### 🔄 **Feature Extraction Pipeline**
```python
# High-level pseudocode
for midi_file in data/raw_midi/:
    midi_data = parse_midi(midi_file)
    
    features = {
        'max_stretch': calculate_hand_stretch(midi_data),
        'avg_density': count_simultaneous_notes(midi_data),
        'polyphony_score': detect_independent_voices(midi_data),
        'thirds_frequency': count_interval_patterns(midi_data, interval=3),
        # ... 6 more features
    }
    
    write_to_csv('features_all.csv', features)
```

#### 🏷️ **Labeling Pipeline**
```python
# Auto-labeling (rules-based)
def auto_label(features):
    if features['max_stretch'] > 25:
        return 'Far Reach'
    elif features['thirds_frequency'] > 0.4:
        return 'Double Thirds'
    elif features['polyphony_score'] > 3:
        return 'Advanced Counterpoint'
    # ... more rules

# Manual labeling (human-in-the-loop)
# User sees feature summary + listens to MIDI
# Presses keyboard 0-4 to assign label
# Saves to manual_X_labels.csv
```

#### 🤖 **Training Pipeline**
```python
# Load and merge
features = pd.read_csv('features_all.csv')
labels = pd.read_csv('labels/auto_5_labels.csv')
dataset = features.merge(labels, on='filename')

# Split
X_train, X_test, y_train, y_test = train_test_split(
    dataset[feature_columns], 
    dataset['label'], 
    test_size=0.2,
    random_state=42  # Reproducibility
)

# Train
model = xgb.XGBClassifier(
    objective='multi:softmax',
    num_class=5,
    max_depth=6,
    learning_rate=0.1
)
model.fit(X_train, y_train)

# Evaluate
predictions = model.predict(X_test)
accuracy = (predictions == y_test).mean()
```

---

<a id="installation"></a>
## 💻 Installation

### Prerequisites

- **Python 3.8+** (tested on 3.8, 3.9, 3.10)
- **pip** package manager
- **Git** (for cloning the repository)

### Step 1: Clone the Repository

```bash
git clone https://github.com/Mesutssmn/Virtuoso-Architect.git
cd Virtuoso-Architect
```

### Step 2: Create a Virtual Environment (Recommended)

```bash
# Using venv
python -m venv venv

# Activate on macOS/Linux
source venv/bin/activate

# Activate on Windows
venv\Scripts\activate
```

### Step 3: Install Dependencies

```bash
pip install -r requirements.txt
```

**Expected installation time**: 2-5 minutes (depending on network speed)

### Step 4: Prepare Data Directories

```bash
# Create necessary directories if they don't exist
mkdir -p data/raw_midi
mkdir -p data/processed/labels
mkdir -p models
```

### Step 5: Add Your MIDI Files

Place your MIDI files (`.mid` or `.midi`) in `data/raw_midi/`:

```bash
cp /path/to/your/midi/files/*.mid data/raw_midi/
```

**Recommendation**: Start with 50-100 files for initial testing, then scale to thousands.

### Step 6: Configure Environment (Optional)

If using OpenAI or other API-based features:

```bash
cp .env.example .env
# Edit .env and add your API keys
nano .env  # or use your preferred editor
```

---

<a id="usage-guide"></a>
## 📖 Usage Guide

### Workflow Overview

```
Extract Features → Generate Labels → Train Model → Evaluate Performance
```

---

<a id="feature-extraction"></a>
### 1️⃣ Feature Extraction System

**Purpose**: Convert raw MIDI files into structured numerical features.

**Input**: `data/raw_midi/*.mid`  
**Output**: `data/processed/features_all.csv`

#### Run Feature Extraction

```bash
python scripts/extract_features.py
```

#### What Happens Internally?

1. **File Discovery**: Scans `data/raw_midi/` for all `.mid` and `.midi` files
2. **MIDI Parsing**: Uses `pretty_midi` to load note events, tempo, time signatures
3. **Feature Calculation**: For each file, computes:
   - **Max Stretch**: Widest interval between simultaneous notes
   - **Avg Density**: Mean number of notes played at once
   - **Polyphony Score**: Complexity of independent melodic lines
   - **Thirds Frequency**: Proportion of consecutive thirds (technique difficulty)
   - **Velocity Variance**: Dynamic range (pianissimo to fortissimo)
   - **Tempo Stability**: Standard deviation of tempo changes
   - ... and 4 more metrics
4. **CSV Export**: Writes one row per file with all features

#### Sample Output (`features_all.csv`)

| filename | max_stretch | avg_density | polyphony_score | thirds_frequency | tempo_stability | ... |
|----------|-------------|-------------|-----------------|------------------|-----------------|-----|
| chopin_op10_no1.mid | 32.0 | 4.5 | 2.1 | 0.65 | 98.5 | ... |
| bach_prelude_c.mid | 12.0 | 3.2 | 4.8 | 0.12 | 120.0 | ... |
| beethoven_pathetique.mid | 28.0 | 5.1 | 3.3 | 0.38 | 72.0 | ... |

#### Advanced Options

```bash
# Process only specific files
python scripts/extract_features.py --input data/raw_midi/subset/

# Skip already processed files
python scripts/extract_features.py --incremental

# Export to different location
python scripts/extract_features.py --output my_features.csv
```

---

### 1️⃣b Single File Prediction (Quick Start)

**Purpose**: Analyze a single MIDI file and get instant difficulty rating.

```bash
python src/main.py --midi_file data/raw_midi/example.mid
```

**Output**:
```
Analyzing: example.mid
============================================================

Step 1/2: Extracting features...
  ✓ Max stretch: 24.0 semitones
  ✓ Note density: 8.5 notes/second

Step 2/2: Classifying technical difficulty...
  ✓ Category: Advanced Chords
  ✓ Confidence: 92.50%
```

---

<a id="labeling-systems"></a>
### 2️⃣ Labeling Systems

We provide **two complementary** labeling approaches:

---

#### 🤖 **Auto-Labeling** (Fast, Scalable)

**When to Use**: 
- Large datasets (1000+ files)
- Initial prototyping
- Establishing baseline labels

**Run Auto-Labeling**

```bash
# Generate 5-class labels
python tools/labeling/auto/auto_label.py --config 5_labels --overwrite

# Generate 4-class labels
python tools/labeling/auto/auto_label.py --config 4_labels
```

**How It Works**:

The auto-labeler applies **music theory heuristics** defined in `tools/labeling/config.py`:

```python
# Example rules (simplified)
AUTO_LABEL_THRESHOLDS = {
    'far_reach': {
        'max_stretch': 25,  # semitones
        'logic': 'greater_than'
    },
    'double_thirds': {
        'thirds_frequency': 0.4,
        'logic': 'greater_than'
    },
    'advanced_chords': {
        'avg_density': 4.0,
        'polyphony_score': 3.0,
        'logic': 'both_greater_than'
    },
    # ...
}
```

**Decision Tree**:
```
Is max_stretch > 25? → Yes → Label: Far Reach
  ↓ No
Is thirds_frequency > 0.4? → Yes → Label: Double Thirds
  ↓ No
Is avg_density > 4.0 AND polyphony_score > 3.0? → Yes → Label: Advanced Chords
  ↓ No
Default → Label: Advanced Counterpoint
```

**Output**: `data/processed/labels/auto_5_labels.csv`

| filename | label_id | label_name |
|----------|----------|------------|
| chopin_op10_no1.mid | 1 | Double Thirds |
| bach_prelude_c.mid | 3 | Advanced Counterpoint |

---

#### 👤 **Manual Labeling** (Accurate, Human-Verified)

**When to Use**:
- Creating gold-standard test sets
- Correcting auto-labeling errors
- Capturing nuances that rules miss (e.g., rapid hand crossings)

**Start the Labeling Interface**

```bash
python tools/labeling/manual/start_labeling.py
```

This will:
1. Launch a Flask server on `http://localhost:5000`
2. Automatically open your default browser to the labeling interface

**Interface Features**:

```
┌──────────────────────────────────────────
│  Virtuoso Architect - Manual Labeling    
├──────────────────────────────────────────
│                                          
│  📄 File: chopin_op10_no1.mid           
│                                         
│  📊 Feature Summary:                    
│     Max Stretch: 32.0 semitones         
│     Avg Density: 4.5 notes              
│     Polyphony: 2.1                      
│     Thirds: 65%                         
│                                         
│  🎵 [Play MIDI] [Stop]    
│  Label as:                              
│  [0] Far Reach                          
│  [1] Double Thirds     ← Auto-suggested 
│  [2] Advanced Chords                    
│  [3] Advanced Counterpoint              
│  [4] Multiple Voices                    
│                                         
│  [Save & Next] [Skip] [Previous]        
└──────────────────────────────────────────
```

**Keyboard Shortcuts**:
- `0-4`: Assign label
- `Enter`: Save and move to next file
- `Space`: Play/pause MIDI
- `→`: Next file
- `←`: Previous file

**Output**: `data/processed/labels/manual_5_labels.csv`

---

<a id="training-pipeline"></a>
### 3️⃣ Training Pipeline

**Purpose**: Train an XGBoost classifier on labeled data.

**Input**: 
- `data/processed/features_all.csv`
- `data/processed/labels/auto_5_labels.csv` (or any label file)

**Output**: `models/xgb_classifier_5.pkl`

#### Run Training

```bash
# Train with auto-generated labels
python scripts/train_with_labels.py --labels auto_5_labels.csv

# Train with manually verified labels
python scripts/train_with_labels.py --labels manual_5_labels.csv --model_name custom_model

# Advanced: Hyperparameter tuning
python scripts/train_with_labels.py \
    --labels auto_5_labels.csv \
    --max_depth 8 \
    --learning_rate 0.05 \
    --n_estimators 200
```

#### Training Process

```
[1/5] Loading features from features_all.csv...
      ✓ Loaded 10,247 files

[2/5] Loading labels from auto_5_labels.csv...
      ✓ Loaded 10,247 labels
      ✓ Distribution:
         Far Reach: 2,134 (20.8%)
         Double Thirds: 1,892 (18.5%)
         Advanced Chords: 3,021 (29.5%)
         Advanced Counterpoint: 2,456 (24.0%)
         Multiple Voices: 744 (7.3%)

[3/5] Merging and splitting (80/20)...
      ✓ Training set: 8,197 samples
      ✓ Test set: 2,050 samples

[4/5] Training XGBoost classifier...
      [0] train-mlogloss: 1.2345
      [10] train-mlogloss: 0.8765
      [50] train-mlogloss: 0.4321
      [100] train-mlogloss: 0.2104
      ✓ Training complete in 42.3s

[5/5] Saving model to models/xgb_classifier_5.pkl...
      ✓ Model saved successfully

Final Training Accuracy: 94.2%
```

#### Hyperparameters Explained

| Parameter | Default | Purpose |
|-----------|---------|---------|
| `max_depth` | 6 | Tree depth; controls model complexity. Higher = more complex patterns, risk of overfitting. |
| `learning_rate` | 0.1 | Step size for gradient updates. Lower = slower but more stable learning. |
| `n_estimators` | 100 | Number of trees. More trees = better fit, but diminishing returns after 200. |
| `min_child_weight` | 1 | Minimum samples per leaf. Higher = more conservative splits. |

---

<a id="evaluation-verification"></a>
### 4️⃣ Evaluation & Verification

#### Evaluate Model Performance

```bash
python scripts/evaluate_model.py --model xgb_classifier_5.pkl --labels auto_5_labels.csv
```

**Output**:

```
=== Classification Report ===

              precision    recall  f1-score   support

   Far Reach       0.92      0.89      0.91       427
Double Thirds       0.88      0.91      0.90       378
Adv Chords         0.95      0.93      0.94       604
Adv Countpt        0.91      0.94      0.93       491
Multi Voices       0.85      0.79      0.82       150

    accuracy                           0.91      2050
   macro avg       0.90      0.89      0.90      2050
weighted avg       0.91      0.91      0.91      2050

=== Confusion Matrix ===

              FR   DT   AC   ACP  MV
Far Reach    380   12   18   15    2
Dbl Thirds    8  344   15    9    2
Adv Chords   11   18  562   12    1
Adv Countpt  14    7   15  462    3
Multi Voic    5    8   10    8  119

Saved confusion matrix to models/confusion_matrix.png
```

#### Run Full System Verification

**Purpose**: End-to-end integration test to ensure all components work together.

```bash
python scripts/verify_system.py
```

**What It Does**:

1. ✅ Checks directory structure
2. ✅ Validates `features_all.csv` format
3. ✅ Verifies label file integrity
4. ✅ Tests feature extraction on sample file
5. ✅ Loads trained model
6. ✅ Runs inference on test samples
7. ✅ Validates prediction format

```
Running System Verification...
================================

[1/7] Directory Structure... PASS
[2/7] Feature CSV Format... PASS
[3/7] Label Files... PASS
[4/7] Feature Extraction... PASS (0.342s)
[5/7] Model Loading... PASS
[6/7] Inference Test... PASS (0.089s)
[7/7] Prediction Validation... PASS

================================
All checks passed! ✓
System is ready for production.
```

---

<a id="classification-schema"></a>
## 🏷️ Classification Schema

We support **two taxonomies** for different use cases:

---

### 🎯 **4-Class Schema** (Balanced, ML-Optimized)

**Purpose**: Simplified categories with clear boundaries. Optimized for machine learning stability.

| ID | Label Name | Description | Key Indicators |
|----|------------|-------------|----------------|
| **0** | **Far Reach** | Wide hand spans requiring extended finger stretches | `max_stretch > 25` semitones (>2 octaves) |
| **1** | **Double Thirds** | Rapid alternation of Major/Minor 3rd intervals | `thirds_frequency > 0.4` (40% of intervals are thirds) |
| **2** | **Advanced Chords** | Complex chord structures with 4+ simultaneous notes | `avg_density > 4.0` notes at once |
| **3** | **Advanced Counterpoint** | Independent melodic lines creating polyphonic texture | `polyphony_score > 3.0` (3+ distinct voices) |

**Use Cases**:
- Initial model training with balanced datasets
- Fast auto-labeling for large corpora
- Avoiding class imbalance issues

---

### 🎼 **5-Class Schema** (Granular, Musicologically Rich)

**Purpose**: Captures nuanced difficulty categories. Preferred for music education applications.

| ID | Label Name | Description | Example Pieces |
|----|------------|-------------|----------------|
| **0** | **Far Reach** | Extended hand positions | Rachmaninoff Prelude Op. 23 No. 5 |
| **1** | **Double Thirds** | Repeated thirds patterns | Chopin Étude Op. 25 No. 6 |
| **2** | **Advanced Chords** | Dense harmonic structures | Liszt Hungarian Rhapsody No. 2 |
| **3** | **Advanced Counterpoint** | Fugal/polyphonic writing | Bach Well-Tempered Clavier |
| **4** | **Multiple Voices** | 3+ independent melodic lines (extends Class 3) | Bach Goldberg Variations |

**New in 5-Class**:
- **Multiple Voices** (ID 4): Distinguishes between basic counterpoint and true polyphony
  - Think: Bach fugues with 4+ voices vs. two-part inventions

**ID Mapping Strategy**:
- IDs 0-3 remain **identical** between schemas
- ID 4 is **additive** (splits off from Advanced Counterpoint)
- This ensures **backward compatibility**: 4-class models can be converted to 5-class by reassigning a subset of Class 3

---

### Schema Selection Guide

```mermaid
graph TD
    A[Choose Schema] --> B{Dataset Size?}
    B -->|< 1000 files| C[Use 4-Class]
    B -->|> 1000 files| D{Application?}
    D -->|ML Research| C
    D -->|Music Education| E[Use 5-Class]
    C --> F[Balanced Classes]
    E --> G[Granular Insights]
```

**Configuration**:

Edit `tools/labeling/config.py`:

```python
# Switch between schemas
ACTIVE_SCHEMA = '5_labels'  # or '4_labels'

LABEL_SCHEMAS = {
    '4_labels': {
        0: 'Far Reach',
        1: 'Double Thirds',
        2: 'Advanced Chords',
        3: 'Advanced Counterpoint'
    },
    '5_labels': {
        0: 'Far Reach',
        1: 'Double Thirds',
        2: 'Advanced Chords',
        3: 'Advanced Counterpoint',
        4: 'Multiple Voices'
    }
}
```

Changes here **automatically propagate** to:
- Auto-labeling rules
- Manual labeling UI (button labels)
- Training scripts (number of classes)
- Evaluation reports

---

<a id="feature-engineering"></a>
## 🔬 Feature Engineering

Our feature set is **theory-driven** and **biomechanically motivated**. Each feature captures a specific aspect of piano technique difficulty.

---

### Feature Catalog

| # | Feature Name | Type | Range | Description |
|---|--------------|------|-------|-------------|
| 1 | **max_stretch** | Float | 0-48 | Maximum interval (in semitones) between the lowest and highest note played simultaneously. Indicators: 12 = octave, 24 = 2 octaves, >25 = difficult reach |
| 2 | **avg_density** | Float | 1-10 | Mean number of notes sounding at the same time. Higher = thicker textures |
| 3 | **polyphony_score** | Float | 1-6 | Complexity of independent melodic lines. Calculated using voice separation algorithms from `music21` |
| 4 | **thirds_frequency** | Float | 0-1 | Proportion of melodic intervals that are Major or Minor thirds. High values (>0.4) indicate technical etudes |
| 5 | **velocity_variance** | Float | 0-127 | Standard deviation of note velocities. Measures dynamic range (pp to ff) |
| 6 | **tempo_stability** | Float | 0-300 | Standard deviation of tempo (BPM) across the piece. High = rubato/unstable tempo |
| 7 | **note_duration_cv** | Float | 0-5 | Coefficient of variation for note durations. High = mixed rhythms (sixteenths + quarters) |
| 8 | **hand_crossing_freq** | Integer | 0-100+ | Number of times left and right hand ranges overlap. Difficult coordination |
| 9 | **arpeggio_density** | Float | 0-1 | Proportion of time spent in arpeggiated patterns vs. blocked chords |
| 10 | **trill_count** | Integer | 0-50+ | Number of rapid alternations between two adjacent notes |

---

### Feature Extraction Deep Dive

#### 1️⃣ **Max Stretch** (Hand Span)

**Biomechanical Basis**: Human hands can comfortably span ~1.5 octaves. Beyond 2 octaves requires:
- Extended finger positions
- Wrist rotation
- Exceptional hand size

**Calculation**:
```python
def calculate_max_stretch(midi):
    max_stretch = 0
    for timestep in midi.get_piano_roll():
        active_notes = get_active_notes(timestep)
        if len(active_notes) >= 2:
            stretch = max(active_notes) - min(active_notes)
            max_stretch = max(max_stretch, stretch)
    return max_stretch
```

**Example Values**:
- 12 (octave): Beginner level
- 18 (octave + fifth): Intermediate
- 24 (2 octaves): Advanced
- >28: Virtuoso (rare, Rachmaninoff-level)

---

#### 2️⃣ **Polyphony Score** (Voice Independence)

**Music Theory Basis**: Polyphony = multiple independent melodic lines. Unlike "note density" (just counting notes), this measures:
- Distinct pitch contours
- Rhythmic independence
- Harmonic coherence

**Calculation** (using `music21`):
```python
def calculate_polyphony(midi):
    score = music21.converter.parse(midi)
    voices = score.parts  # Separate staves/hands
    
    independent_voices = 0
    for voice in voices:
        # Check if voice has distinct melodic contour
        if has_distinct_melody(voice):
            independent_voices += 1
    
    return independent_voices
```

**Example Scores**:
- 1.0: Monophonic (single melody)
- 2.0: Melody + accompaniment
- 3.0: Three-part counterpoint (Bach inventions)
- 4.0+: Fugues, complex polyphony

---

#### 3️⃣ **Thirds Frequency** (Pattern Recognition)

**Pedagogical Motivation**: Scales in thirds are a **specific technique** taught in conservatories.

**Calculation**:
```python
def calculate_thirds_frequency(midi):
    intervals = get_melodic_intervals(midi)  # [3, 5, 3, 2, 3, ...]
    thirds = [i for i in intervals if i in [3, 4]]  # Major/Minor thirds
    return len(thirds) / len(intervals)
```

**Interpretation**:
- <0.2: Occasional thirds
- 0.2-0.4: Moderate use
- >0.4: **Dedicated thirds etude** (e.g., Chopin Op. 25 No. 6)

---

### Feature Importance (Post-Training Analysis)

After training, we can inspect which features contribute most to predictions:

```python
import xgboost as xgb

model = xgb.Booster()
model.load_model('models/xgb_classifier_5.pkl')

importance = model.get_score(importance_type='gain')
# Output:
# {
#     'max_stretch': 0.35,       # 35% of decision power
#     'polyphony_score': 0.28,
#     'avg_density': 0.18,
#     'thirds_frequency': 0.12,
#     ...
# }
```

**Insight**: `max_stretch` and `polyphony_score` dominate predictions → Physical difficulty and textural complexity are the primary difficulty factors.

---

<a id="manual-labeling-interface"></a>
## 🖥️ Manual Labeling Interface

### Architecture

```
┌─────────────────────┐
│  Browser (Client)   │
│  labeling_interface │
│       .html         │
└──────────┬──────────┘
           │ HTTP Requests
           ▼
┌─────────────────────┐
│  Flask Server       │
│  labeling_server.py │
│                     │
│  Endpoints:         │
│  /api/config        │
│  /api/next_file     │
│  /api/save_label    │
│  /api/features      │
└──────────┬──────────┘
           │ File I/O
           ▼
┌─────────────────────┐
│  Filesystem         │
│  • features.csv     │
│  • labels.csv       │
│  • raw_midi/        │
└─────────────────────┘
```

---

### Backend API (Flask)

**File**: `tools/labeling/manual/labeling_server.py`

#### Endpoint: `GET /api/config`

**Purpose**: Dynamically load label schema from `config.py`

**Response**:
```json
{
  "schema": "5_labels",
  "labels": {
    "0": "Far Reach",
    "1": "Double Thirds",
    "2": "Advanced Chords",
    "3": "Advanced Counterpoint",
    "4": "Multiple Voices"
  }
}
```

**Why This Matters**: If you change label names in `config.py`, the UI updates **automatically** without touching JavaScript.

---

#### Endpoint: `GET /api/next_file`

**Purpose**: Serve the next unlabeled file

**Response**:
```json
{
  "filename": "chopin_op10_no1.mid",
  "features": {
    "max_stretch": 32.0,
    "avg_density": 4.5,
    "polyphony_score": 2.1,
    "thirds_frequency": 0.65
  },
  "auto_suggestion": 1,  // Auto-labeler suggests "Double Thirds"
  "midi_data_url": "/data/raw_midi/chopin_op10_no1.mid",
  "progress": {
    "labeled": 234,
    "total": 10247
  }
}
```

---

#### Endpoint: `POST /api/save_label`

**Purpose**: Save human label to CSV

**Request**:
```json
{
  "filename": "chopin_op10_no1.mid",
  "label_id": 1,
  "schema": "5_labels"
}
```

**Response**:
```json
{
  "status": "success",
  "message": "Label saved to manual_5_labels.csv"
}
```

**Implementation** (Simplified):
```python
@app.route('/api/save_label', methods=['POST'])
def save_label():
    data = request.json
    filename = data['filename']
    label_id = data['label_id']
    schema = data['schema']
    
    # Append to CSV
    label_file = f'data/processed/labels/manual_{schema}.csv'
    with open(label_file, 'a') as f:
        f.write(f"{filename},{label_id}\n")
    
    return {'status': 'success'}
```

---

### Frontend (Single-Page Application)

**File**: `tools/labeling/manual/labeling_interface.html`

**Tech Stack**: Vanilla JavaScript + HTML5 + CSS3 (no frameworks)

**Why No React/Vue?**
- Simplicity: No build step, works immediately
- Compatibility: Runs on any browser
- Low latency: Direct DOM manipulation

#### Key Features

##### 1️⃣ **Dynamic Label Buttons**

```javascript
// Fetch config from backend
fetch('/api/config')
  .then(res => res.json())
  .then(config => {
    const buttonContainer = document.getElementById('label-buttons');
    
    // Generate buttons dynamically
    Object.entries(config.labels).forEach(([id, name]) => {
      const btn = document.createElement('button');
      btn.textContent = `[${id}] ${name}`;
      btn.onclick = () => saveLabel(id);
      buttonContainer.appendChild(btn);
    });
  });
```

**Effect**: Changing `config.py` from 4 to 5 labels re-renders the UI **without code changes**.

---

##### 2️⃣ **MIDI Playback**

```javascript
// Use Web MIDI API (if available) or fallback to audio conversion
function playMIDI(filepath) {
  const audio = new Audio(`/convert_to_audio?file=${filepath}`);
  audio.play();
}
```

**Note**: We provide a fallback endpoint that converts MIDI → WAV using `pretty_midi.fluidsynth`.

---

##### 3️⃣ **Keyboard Shortcuts**

```javascript
document.addEventListener('keydown', (e) => {
  if (e.key >= '0' && e.key <= '4') {
    saveLabel(parseInt(e.key));
  }
  if (e.key === 'ArrowRight') loadNextFile();
  if (e.key === 'ArrowLeft') loadPreviousFile();
  if (e.key === ' ') togglePlayback();
});
```

**UX Goal**: Expert labelers can annotate **100+ files/hour** without touching the mouse.

---

##### 4️⃣ **Feature Visualization**

```javascript
function displayFeatures(features) {
  const container = document.getElementById('features');
  
  // Bar chart using Chart.js (included via CDN)
  new Chart(container, {
    type: 'bar',
    data: {
      labels: Object.keys(features),
      datasets: [{
        data: Object.values(features),
        backgroundColor: '#3498db'
      }]
    }
  });
}
```

**Output**:
```
Max Stretch    ████████████████████ 32.0
Avg Density    ██████████ 4.5
Polyphony      ████ 2.1
Thirds Freq    ███████████████ 0.65
```

---

### Launching the Interface

```bash
# Start server
python tools/labeling/manual/start_labeling.py

# Output:
# Starting Flask server on http://localhost:5000...
# Opening browser...
# Server is ready! Press Ctrl+C to stop.
```

**Auto-Opens**: The script uses `webbrowser` module to launch your default browser automatically.

---

<a id="auto-labeling-system"></a>
## 🤖 Auto-Labeling System

### Design Philosophy

**Goal**: Apply **music theory expertise** at scale without human intervention.

**Challenges**:
1. Rules must be **precise** to avoid mislabeling
2. Edge cases (e.g., sparse chords vs. dense melodies) need handling
3. Must remain **interpretable** (no black-box heuristics)

---

### Rule Engine Architecture

**File**: `tools/labeling/auto/auto_label.py`

#### Step 1: Load Feature Vector

```python
features = pd.read_csv('data/processed/features_all.csv')
# Shape: (10247, 10)  # 10,247 files × 10 features
```

---

#### Step 2: Apply Decision Tree

```python
def auto_label_5_class(row):
    # Rule 1: Far Reach (biomechanical constraint)
    if row['max_stretch'] > 25:
        return 0  # Far Reach
    
    # Rule 2: Double Thirds (pattern-based)
    if row['thirds_frequency'] > 0.4:
        return 1  # Double Thirds
    
    # Rule 3: Advanced Chords (density-based)
    if row['avg_density'] > 4.0 and row['max_stretch'] > 15:
        return 2  # Advanced Chords
    
    # Rule 4: Multiple Voices (polyphony-based)
    if row['polyphony_score'] > 4.0:
        return 4  # Multiple Voices (5-class only)
    
    # Rule 5: Advanced Counterpoint (default for polyphonic)
    if row['polyphony_score'] > 2.5:
        return 3  # Advanced Counterpoint
    
    # Fallback
    return 3  # Default to Counterpoint
```

---

#### Step 3: Batch Processing

```python
labels = features.apply(auto_label_5_class, axis=1)

# Save to CSV
output = pd.DataFrame({
    'filename': features['filename'],
    'label_id': labels
})
output.to_csv('data/processed/labels/auto_5_labels.csv', index=False)
```

**Performance**: 10,000 files labeled in **~5 seconds** on modern hardware.

---

### Configuration System

**File**: `tools/labeling/config.py`

**Central Control**: All thresholds defined here to prevent hardcoding.

```python
# Auto-labeling thresholds (5-class schema)
AUTO_LABEL_THRESHOLDS_5 = {
    'far_reach': {
        'conditions': {
            'max_stretch': {'operator': '>', 'value': 25}
        },
        'label_id': 0
    },
    'double_thirds': {
        'conditions': {
            'thirds_frequency': {'operator': '>', 'value': 0.4}
        },
        'label_id': 1
    },
    'advanced_chords': {
        'conditions': {
            'avg_density': {'operator': '>', 'value': 4.0},
            'max_stretch': {'operator': '>', 'value': 15}
        },
        'logic': 'AND',  # Both conditions must be true
        'label_id': 2
    },
    # ... more rules
}
```

**Benefits**:
1. **Auditable**: Non-programmers can review rules
2. **Tunable**: Adjust thresholds without touching code
3. **Consistent**: Same rules used in reporting and training

---

### Validation & Quality Assurance

After auto-labeling, we run **sanity checks**:

```bash
python tools/labeling/auto/validate_labels.py --labels auto_5_labels.csv
```

**Output**:
```
Validation Report for auto_5_labels.csv
========================================

Class Distribution:
  Far Reach: 2,134 (20.8%)
  Double Thirds: 1,892 (18.5%)
  Advanced Chords: 3,021 (29.5%)
  Advanced Counterpoint: 2,456 (24.0%)
  Multiple Voices: 744 (7.3%)

⚠ Warning: Class imbalance detected
  - "Multiple Voices" is underrepresented (< 10%)
  - Recommendation: Collect more polyphonic pieces or merge with Class 3

Edge Cases Detected:
  - 42 files have max_stretch > 30 but low density
    → May be sparse wide-interval passages, not chords
  - 18 files labeled "Double Thirds" but thirds_freq < 0.35
    → Near threshold; recommend manual review

✓ No files with invalid label IDs
✓ All filenames exist in features_all.csv
```

---

<a id="training-model-architecture"></a>
## 🧠 Training & Model Architecture

### Why XGBoost?

**Decision Matrix**:

| Model Type | Pros | Cons | Verdict |
|------------|------|------|---------|
| **Neural Network** | Flexible, can learn complex patterns | Needs massive data (100k+ samples), black-box | ❌ Overkill for tabular data |
| **Random Forest** | Good baseline, interpretable | Slower than XGBoost, less accurate | ⚠️ Viable alternative |
| **XGBoost** | Fast, accurate, handles imbalance, feature importance | Requires tuning | ✅ **Chosen** |
| **SVM** | Works well for small datasets | Struggles with multi-class, slow | ❌ Not scalable |

**XGBoost Advantages**:
1. **Tabular data specialist**: Our features are structured (not images/audio)
2. **Built-in regularization**: Prevents overfitting with small datasets
3. **Parallel training**: Fast on multi-core CPUs
4. **Interpretability**: Feature importance, tree visualization

---

### Training Pipeline Breakdown

**File**: `scripts/train_with_labels.py`

#### Step 1: Data Loading

```python
import pandas as pd

features = pd.read_csv('data/processed/features_all.csv')
labels = pd.read_csv('data/processed/labels/auto_5_labels.csv')

# Merge on filename
dataset = pd.merge(features, labels, on='filename')
```

---

#### Step 2: Train/Test Split

```python
from sklearn.model_selection import train_test_split

X = dataset[FEATURE_COLUMNS]  # 10 features
y = dataset['label_id']       # 0-4

X_train, X_test, y_train, y_test = train_test_split(
    X, y, 
    test_size=0.2,      # 80/20 split
    random_state=42,    # Reproducibility
    stratify=y          # Preserve class distribution
)
```

**Stratification**: Ensures test set has same class proportions as training set.

---

#### Step 3: Model Initialization

```python
import xgboost as xgb

model = xgb.XGBClassifier(
    objective='multi:softmax',  # Multi-class classification
    num_class=5,                # Number of labels
    max_depth=6,                # Tree depth
    learning_rate=0.1,          # Gradient descent step size
    n_estimators=100,           # Number of boosting rounds
    subsample=0.8,              # Row sampling (prevents overfitting)
    colsample_bytree=0.8,       # Column sampling
    random_state=42             # Reproducibility
)
```

**Hyperparameter Guide**:
- `max_depth=6`: Shallow trees prevent memorization
- `learning_rate=0.1`: Standard value; lower (0.01) for more training time
- `subsample=0.8`: Uses 80% of data per tree (bagging effect)

---

#### Step 4: Training

```python
model.fit(
    X_train, y_train,
    eval_set=[(X_test, y_test)],  # Monitor test loss
    early_stopping_rounds=10,     # Stop if no improvement for 10 rounds
    verbose=10                    # Log every 10 rounds
)
```

**Early Stopping**: Prevents overfitting by stopping when validation loss plateaus.

---

#### Step 5: Evaluation

```python
from sklearn.metrics import classification_report

y_pred = model.predict(X_test)

print(classification_report(y_test, y_pred, 
                          target_names=LABEL_NAMES))
```

---

#### Step 6: Model Persistence

```python
import pickle

with open('models/xgb_classifier_5.pkl', 'wb') as f:
    pickle.dump(model, f)
```

**Alternative**: Use `model.save_model('model.json')` for XGBoost native format.

---

### Hyperparameter Tuning

**Manual Tuning**:
```bash
python scripts/train_with_labels.py \
    --max_depth 8 \
    --learning_rate 0.05 \
    --n_estimators 200
```

**Automated (Grid Search)**:
```python
from sklearn.model_selection import GridSearchCV

param_grid = {
    'max_depth': [4, 6, 8],
    'learning_rate': [0.01, 0.1, 0.2],
    'n_estimators': [100, 200, 300]
}

grid = GridSearchCV(
    xgb.XGBClassifier(),
    param_grid,
    cv=5,  # 5-fold cross-validation
    scoring='f1_weighted'
)

grid.fit(X_train, y_train)
best_model = grid.best_estimator_
```

**Warning**: Grid search is **computationally expensive** (27 combinations × 5 folds = 135 trainings).

---

### Model Interpretability

#### Feature Importance

```python
import matplotlib.pyplot as plt

importances = model.feature_importances_
features = X.columns

plt.barh(features, importances)
plt.xlabel('Importance (Gain)')
plt.title('Feature Importance Analysis')
plt.savefig('models/feature_importance.png')
```

**Example Output**:
```
max_stretch          ████████████████ 35%
polyphony_score      ████████████ 28%
avg_density          ████████ 18%
thirds_frequency     ████ 12%
velocity_variance    ██ 4%
...                  █ 3%
```

**Interpretation**: Physical reach (max_stretch) is the most predictive feature.

---

#### SHAP Values (Advanced)

```python
import shap

explainer = shap.TreeExplainer(model)
shap_values = explainer.shap_values(X_test)

# Visualize for a single prediction
shap.force_plot(explainer.expected_value[0], 
                shap_values[0][0], 
                X_test.iloc[0])
```

**Use Case**: Explain *why* a specific piece was classified as "Far Reach".

---

<a id="future-improvements"></a>
## 🚀 Future Improvements & Roadmap

### Short-Term Enhancements (Next 3 Months)

#### 1️⃣ **Expanded Feature Set**
- **Hand Crossing Detection**: Count instances where left hand plays above right hand
- **Arpeggio Speed**: Measure notes per second in arpeggiated passages
- **Leap Frequency**: Track wide melodic jumps (>octave) requiring precise hand repositioning
- **Pedal Complexity**: Analyze sustain pedal usage patterns

**Implementation**: Add to `src/features/extractor.py`

---

#### 2️⃣ **Class Imbalance Handling**
**Problem**: "Multiple Voices" is underrepresented (7.3% of dataset)

**Solutions**:
- **SMOTE**: Synthetic Minority Over-sampling Technique
  ```python
  from imblearn.over_sampling import SMOTE
  
  smote = SMOTE(random_state=42)
  X_resampled, y_resampled = smote.fit_resample(X_train, y_train)
  ```
- **Class Weights**: Penalize misclassifications of rare classes more heavily
  ```python
  model = xgb.XGBClassifier(scale_pos_weight=3)  # 3x weight for minority class
  ```

---

#### 3️⃣ **Cross-Validation**
**Current**: Single 80/20 split  
**Improvement**: K-fold cross-validation for robust metrics

```python
from sklearn.model_selection import cross_val_score

scores = cross_val_score(model, X, y, cv=5, scoring='f1_weighted')
print(f"Mean F1: {scores.mean():.3f} ± {scores.std():.3f}")
```

---

### Medium-Term Goals (6-12 Months)

#### 4️⃣ **Deep Learning Experiments**
**Rationale**: While XGBoost is optimal for tabular data, neural networks might capture subtle patterns.

**Proposed Architecture**:
```python
import torch.nn as nn

class DifficultyClassifier(nn.Module):
    def __init__(self):
        super().__init__()
        self.fc1 = nn.Linear(10, 64)  # 10 features → 64 neurons
        self.fc2 = nn.Linear(64, 32)
        self.fc3 = nn.Linear(32, 5)   # 5 output classes
        
    def forward(self, x):
        x = torch.relu(self.fc1(x))
        x = torch.relu(self.fc2(x))
        return torch.softmax(self.fc3(x), dim=1)
```

**Hypothesis**: Unlikely to outperform XGBoost, but worth benchmarking.

---

#### 5️⃣ **Audio-Based Features**
**Current Limitation**: MIDI lacks expressive nuances (dynamics, pedaling, tempo rubato)

**Solution**: Process actual audio recordings
- **Spectral Features**: MFCC, chroma, spectral centroid
- **Rhythm Analysis**: Beat tracking, tempo variations
- **Toolkit**: `librosa` for audio feature extraction

**Challenge**: Requires parallel dataset of MIDI + audio recordings.

---

#### 6️⃣ **Active Learning Loop**
**Concept**: Use model predictions to prioritize manual labeling

**Workflow**:
1. Train initial model on auto-labeled data
2. Run inference on unlabeled pool
3. Identify **low-confidence predictions** (e.g., probabilities close to 0.5)
4. Send these ambiguous cases to manual labeling
5. Retrain model with new labels

**Benefit**: Reduces manual labeling effort by 60%+

```python
predictions = model.predict_proba(X_unlabeled)
confidence = predictions.max(axis=1)

# Prioritize low-confidence samples
ambiguous = X_unlabeled[confidence < 0.7]
```

---

### Long-Term Vision (1-2 Years)

#### 7️⃣ **Real-Time Web API**
**Use Case**: Integrate with sheet music platforms (e.g., IMSLP, MuseScore)

**Tech Stack**:
- **FastAPI**: Modern Python web framework
- **Docker**: Containerized deployment
- **Redis**: Cache feature extractions

**API Endpoint**:
```bash
POST /api/predict
Content-Type: multipart/form-data

{
  "file": <uploaded .mid file>
}

Response:
{
  "difficulty": "Advanced Chords",
  "confidence": 0.89,
  "features": {
    "max_stretch": 28.0,
    "polyphony_score": 3.2
  },
  "recommendations": [
    "Requires large hand span",
    "Practice blocked chords before attempting"
  ]
}
```

---

#### 8️⃣ **Composer-Specific Models**
**Insight**: Difficulty is subjective; Chopin's "easy" is different from Bartok's.

**Approach**: Train separate models for different stylistic periods
- **Romantic Model** (Chopin, Liszt, Rachmaninoff)
- **Classical Model** (Mozart, Beethoven, Haydn)
- **Contemporary Model** (Ligeti, Glass, Adams)

**Implementation**: Multi-task learning with shared feature extraction, genre-specific classification heads.

---

#### 9️⃣ **Explainable AI Dashboard**
**Audience**: Music educators who need to justify difficulty ratings

**Features**:
- **SHAP Waterfall Plots**: Show contribution of each feature to final prediction
- **Comparative Analysis**: "This piece is harder than 78% of Chopin etudes because..."
- **Practice Suggestions**: "Focus on thirds passages (bars 12-24) which account for 40% of difficulty"

**Tech Stack**: React + D3.js for interactive visualizations

---

#### 🔟 **Mobile App**
**Vision**: Scan sheet music with phone camera → Get instant difficulty rating

**Tech Stack**:
- **OMR**: Optical Music Recognition (convert images to MIDI)
- **React Native**: Cross-platform mobile app
- **TensorFlow Lite**: On-device inference

**Workflow**:
1. User photographs sheet music
2. OMR converts to MIDI
3. App extracts features locally
4. Pre-trained model classifies difficulty
5. Display results in <2 seconds

---

### 🌟 Visionary Projects (12-24 Months)

#### 1️⃣1️⃣ **Interactive Pedagogy Chatbot (RAG)**
**Goal**: A pedagogical assistant that explains *why* a piece is difficult.
- **Tech**: OpenAI GPT-4o + Vector Database (ChromaDB)
- **Feature**: User asks "How do I practice the thirds in bar 12?"
- **System**: Retrieves similar patterns from knowledge base and pedagogical texts (Czerny, Hanon) to give tailored advice.

#### 1️⃣2️⃣ **Real-Time Audio Analysis**
**Goal**: Move beyond MIDI to actual audio recordings.
- **Tech**: `librosa` + Whisper (Audio-to-MIDI)
- **Workflow**: User uploads MP3 -> System transcribes to MIDI -> Extracts features -> Classifies difficulty.
- **Status**: Requires high-fidelity transcription models.

#### 1️⃣3️⃣ **Crowdsourced Labeling Platform**
**Goal**: Gamified web app for global data collection.
- **Concept**: "Dualingo for Music Theory"
- **Mechanism**: Users earn points by correctly labeling difficulty or identifying techniques.
- **Impact**: Rapidly scale dataset from 10k to 100k+ validated samples.

---

<a id="contributing"></a>
## 🤝 Contributing

We welcome contributions from:
- 🎹 Pianists and music educators
- 💻 Machine learning engineers
- 📊 Data scientists
- 🎼 Music theorists

### How to Contribute

#### 1️⃣ **Report Issues**
Found a bug or have a feature request?
- Open an issue on GitHub
- Use the template provided
- Tag appropriately (`bug`, `enhancement`, `documentation`)

#### 2️⃣ **Submit Pull Requests**
**Process**:
1. Fork the repository
2. Create a feature branch: `git checkout -b feature/new-feature`
3. Make changes with clear commit messages
4. Submit PR with detailed description

**Code Style**:
- Follow PEP 8 for Python
- Use type hints: `def extract_features(midi: PrettyMIDI) -> Dict[str, float]:`
- Document functions with docstrings

**Example**:
```python
def calculate_polyphony(midi: PrettyMIDI) -> float:
    """
    Calculate polyphony score based on voice independence.
    
    Args:
        midi: PrettyMIDI object containing note events
        
    Returns:
        Float score from 1.0 (monophonic) to 6.0 (complex polyphony)
        
    Example:
        >>> midi = pretty_midi.PrettyMIDI('bach_fugue.mid')
        >>> calculate_polyphony(midi)
        4.2
    """
    # Implementation...
```

#### 3️⃣ **Improve Documentation**
- Fix typos
- Add examples
- Translate to other languages
- Create tutorials

#### 4️⃣ **Share Datasets**
We're building a public dataset of labeled MIDI files. Contribute by:
- Uploading your MIDI collection (with licensing info)
- Verifying auto-generated labels
- Recording difficulty ratings from expert pianists

---

### Development Setup

```bash
# Clone your fork
git clone https://github.com/YOUR_USERNAME/Virtuoso-Architect.git
cd Virtuoso-Architect

# Create virtual environment
python -m venv venv
source venv/bin/activate

# Install dependencies
pip install -r requirements.txt
```

---

### Contribution Ideas

**Good First Issues**:
- Add progress bars to long-running scripts
- Improve error messages
- Write unit tests for feature extraction functions
- Create Jupyter notebooks with examples

**Advanced Projects**:
- Implement SHAP value visualizations
- Build a web demo using Streamlit
- Optimize feature extraction for 10x speedup
- Integrate with music21's corpus for automatic evaluation

---

<a id="license"></a>
## 📄 License

This project is licensed under the **MIT License**.

```
MIT License

Copyright (c) 2024 Virtuoso Architect Contributors

Permission is hereby granted, free of charge, to any person obtaining a copy
of this software and associated documentation files (the "Software"), to deal
in the Software without restriction, including without limitation the rights
to use, copy, modify, merge, publish, distribute, sublicense, and/or sell
copies of the Software, and to permit persons to whom the Software is
furnished to do so, subject to the following conditions:

The above copyright notice and this permission notice shall be included in all
copies or substantial portions of the Software.

THE SOFTWARE IS PROVIDED "AS IS", WITHOUT WARRANTY OF ANY KIND, EXPRESS OR
IMPLIED, INCLUDING BUT NOT LIMITED TO THE WARRANTIES OF MERCHANTABILITY,
FITNESS FOR A PARTICULAR PURPOSE AND NONINFRINGEMENT. IN NO EVENT SHALL THE
AUTHORS OR COPYRIGHT HOLDERS BE LIABLE FOR ANY CLAIM, DAMAGES OR OTHER
LIABILITY, WHETHER IN AN ACTION OF CONTRACT, TORT OR OTHERWISE, ARISING FROM,
OUT OF OR IN CONNECTION WITH THE SOFTWARE OR THE USE OR OTHER DEALINGS IN THE
SOFTWARE.
```

**What This Means**:
- ✅ Use for commercial projects
- ✅ Modify and distribute
- ✅ Private use
- ❌ No warranty or liability

---

## 🙏 Acknowledgments

### Research Foundations
- **Music21**: Computational music analysis toolkit by MIT
- **Pretty MIDI**: MIDI processing library by Colin Raffel
- **XGBoost**: Gradient boosting framework by DMLC

### Inspirations
- **Piano pedagogy research**: Suzuki Method, Faber Method
- **MIREX**: Music Information Retrieval Evaluation eXchange
- **IMSLP**: International Music Score Library Project

### Special Thanks
- Music educators who provided expert labels for validation
- Open-source contributors who improved documentation and code
- Community members who tested early versions

---

## 📞 Contact & Support

### 🐛 **Issues & Bugs**
Report on GitHub: [Issues Page](https://github.com/Mesutssmn/Virtuoso-Architect/issues)

### 💬 **Discussions**
Join the conversation: [Discussions](https://github.com/Mesutssmn/Virtuoso-Architect/discussions)

### 📧 **Email**
For private inquiries: [Contact via GitHub Profile](https://github.com/Mesutssmn)

### 🌟 **Stay Updated**
- Watch the repository for release notifications
- Star the project to support development
- Follow contributors for related projects

---

<div align="center">

**Made with ❤️ by the Virtuoso Architect Team**

*Empowering musicians and educators through data-driven insights*

[⬆ Back to Top](#-virtuoso-architect)

</div>

# VPN vs TOR Network Traffic Classifier

A machine learning system for distinguishing between VPN and TOR network traffic using behavioral and statistical features.




## 📋 Table of Contents

- [Overview](#overview)
- [Features](#features)
- [Installation](#installation)
- [Quick Start](#quick-start)
- [Usage Guide](#usage-guide)
- [Model Architecture](#model-architecture)
- [Results & Performance](#results--performance)
- [Understanding the Features](#understanding-the-features)
- [Deployment](#deployment)
- [Troubleshooting](#troubleshooting)
- [References](#references)

---

## 🎯 Overview

This project implements a machine learning classifier that can distinguish between VPN (Virtual Private Network) and TOR (The Onion Router) network traffic. The classifier analyzes network flow characteristics to identify the anonymization technique being used.

### Why This Matters

- **Network Security**: Identify anonymized traffic for security monitoring
- **Traffic Analysis**: Understand network usage patterns
- **Research**: Study differences in anonymization protocols
- **Compliance**: Monitor network policy adherence

### Key Capabilities

✅ **High Accuracy**: Achieves >95% classification accuracy  
✅ **Fast Inference**: Real-time classification capability  
✅ **Interpretable**: Feature importance analysis included  
✅ **Flexible**: Multiple ML algorithms supported  
✅ **Production-Ready**: Model persistence and loading

---

## 🚀 Features

### Traffic Analysis
- **Packet-level statistics**: Size, inter-arrival times, distributions
- **Flow-level metrics**: Duration, throughput, packet counts
- **Behavioral patterns**: Encryption overhead, timing patterns

### Machine Learning Models
- **Random Forest** (default): Best accuracy and interpretability
- **Gradient Boosting**: High performance with complex patterns
- **Support Vector Machine**: Strong generalization

### Visualization & Reporting
- Confusion matrices
- ROC curves with AUC scores
- Feature importance plots
- Prediction distribution analysis
- Comprehensive classification reports

---

## 📦 Installation

### Prerequisites

### Install Dependencies

```bash
pip install -r requirements.txt
```

**requirements.txt:**
```
numpy>=1.21.0
pandas>=1.3.0
scikit-learn>=1.0.0
matplotlib>=3.4.0
seaborn>=0.11.0
joblib>=1.0.0
```

---

## ⚡ Quick Start

### Training a Model (Basic)

```bash
python train.py
```

This will:
1. Generate synthetic training data
2. Train a Random Forest classifier
3. Evaluate performance on test set
4. Save visualizations to `results/` folder
5. Save trained model to `models/` folder

### Expected Output

```
==============================================================
VPN vs TOR Network Traffic Classifier
==============================================================

[1/5] Generating synthetic network traffic data...
✓ Generated 10000 samples with 11 features
  - VPN samples: 5000
  - TOR samples: 5000

[2/5] Splitting data into train/validation/test sets...
✓ Train: 6400, Validation: 1600, Test: 2000

[3/5] Training model...
Training Accuracy: 0.9956
Cross-Validation Accuracy: 0.9891 (+/- 0.0023)
Validation Accuracy: 0.9894

[4/5] Evaluating model...
✓ Test Accuracy: 0.9885

[5/5] Saving model...
✓ Model saved to models/vpn_tor_classifier.pkl

Training pipeline completed successfully!
```

---

## 📖 Usage Guide

### 1. Training Custom Models

#### Using Different Algorithms

```python
from train import VPNTORClassifier

# Random Forest (default)
rf_classifier = VPNTORClassifier(model_type='random_forest')

# Gradient Boosting
gb_classifier = VPNTORClassifier(model_type='gradient_boosting')

# Support Vector Machine
svm_classifier = VPNTORClassifier(model_type='svm')
```

#### Training with Custom Data

```python
import pandas as pd
from train import VPNTORClassifier

# Load your data
data = pd.read_csv('your_traffic_data.csv')
X = data.drop('label', axis=1)
y = data['label']  # 0 for VPN, 1 for TOR

# Initialize and train
classifier = VPNTORClassifier(model_type='random_forest')
classifier.feature_names = X.columns.tolist()
classifier.train(X, y)

# Evaluate
classifier.evaluate(X_test, y_test, output_dir='my_results')

# Save
classifier.save_model('my_model')
```

### 2. Making Predictions

#### Load Pre-trained Model

```python
from train import VPNTORClassifier

# Load model
classifier = VPNTORClassifier.load_model('models/vpn_tor_classifier.pkl')

# Prepare new data (must have same features as training)
new_data = pd.DataFrame({
    'packet_size_mean': [750],
    'packet_size_std': [280],
    'flow_duration': [12.5],
    'packets_per_second': [48],
    'bytes_per_second': [38000],
    'packet_iat_mean': [0.021],
    'packet_iat_std': [0.045],
    'forward_packets': [95],
    'backward_packets': [88],
    'flow_bytes_per_sec': [42000],
    'encryption_overhead': [1.12]
})

# Predict
results = classifier.predict(new_data)
print(f"Prediction: {results['labels'][0]}")
print(f"Confidence: {results['probabilities'][0].max():.2%}")
```

#### Batch Predictions

```python
# Load multiple flows
flows_df = pd.read_csv('network_flows.csv')

# Predict all at once
results = classifier.predict(flows_df)

# Add predictions to dataframe
flows_df['predicted_type'] = results['labels']
flows_df['vpn_probability'] = results['probabilities'][:, 0]
flows_df['tor_probability'] = results['probabilities'][:, 1]

# Save results
flows_df.to_csv('classified_flows.csv', index=False)
```

### 3. Model Evaluation

```python
# Evaluate on test set
results = classifier.evaluate(X_test, y_test, output_dir='evaluation_results')

# Access metrics
print(f"Accuracy: {results['accuracy']:.4f}")

# Get detailed predictions
predictions = results['predictions']
probabilities = results['probabilities']

# Find misclassified samples
misclassified = X_test[predictions != y_test]
print(f"Misclassified samples: {len(misclassified)}")
```

---

## 🏗️ Model Architecture

### Feature Engineering

The classifier uses 11 network flow features extracted from traffic:

| Feature | Description | VPN Characteristic | TOR Characteristic |
|---------|-------------|-------------------|-------------------|
| `packet_size_mean` | Average packet size (bytes) | ~800 bytes | ~512 bytes (fixed cells) |
| `packet_size_std` | Packet size std deviation | Higher variance | Lower variance |
| `flow_duration` | Total flow duration (sec) | Shorter sessions | Longer sessions |
| `packets_per_second` | Packet rate | ~50 pps | ~30 pps |
| `bytes_per_second` | Throughput | ~40 KB/s | ~15 KB/s |
| `packet_iat_mean` | Avg inter-arrival time (sec) | Lower latency | Higher latency |
| `packet_iat_std` | IAT std deviation | Consistent timing | Variable timing |
| `forward_packets` | Client→Server packets | ~100 | ~80 |
| `backward_packets` | Server→Client packets | ~90 | ~75 |
| `flow_bytes_per_sec` | Flow throughput | ~45 KB/s | ~18 KB/s |
| `encryption_overhead` | Encryption ratio | ~1.15x | ~1.35x |

### Algorithm Selection

**Random Forest (Default)**
- **Pros**: Best accuracy, interpretable, robust to overfitting
- **Cons**: Larger model size
- **Best for**: Production deployment, research analysis

**Gradient Boosting**
- **Pros**: High accuracy, handles complex patterns
- **Cons**: Slower training, risk of overfitting
- **Best for**: Maximum performance requirements

**Support Vector Machine**
- **Pros**: Strong generalization, works with small datasets
- **Cons**: Slower inference, less interpretable
- **Best for**: Limited training data scenarios

### Training Pipeline

```
Raw Traffic Data
       ↓
Feature Extraction
       ↓
Standardization (Z-score)
       ↓
Train/Val/Test Split (64%/16%/20%)
       ↓
Model Training (with cross-validation)
       ↓
Hyperparameter Tuning
       ↓
Evaluation & Visualization
       ↓
Model Persistence
```

---

## 📊 Results & Performance

### Performance Metrics

Based on synthetic data testing:

| Metric | Value |
|--------|-------|
| **Overall Accuracy** | 98.85% |
| **VPN Precision** | 98.92% |
| **VPN Recall** | 98.80% |
| **TOR Precision** | 98.79% |
| **TOR Recall** | 98.90% |
| **ROC AUC** | 0.9985 |

### Confusion Matrix

```
                Predicted
              VPN    TOR
Actual VPN   [988]  [12]
       TOR   [11]   [989]
```

### Visual Results

After training, you'll find these visualizations in the `results/` folder:

#### 1. Confusion Matrix (`confusion_matrix.png`)
Shows the number of correct and incorrect predictions for each class.

<img width="2844" height="2368" alt="confusion_matrix" src="https://github.com/user-attachments/assets/889ff5fb-f9c1-4b01-a603-3655820894a7" />

#### 2. ROC Curve (`roc_curve.png`)
Displays the trade-off between true positive rate and false positive rate.

<img width="2964" height="2366" alt="roc_curve" src="https://github.com/user-attachments/assets/a6c69879-c5e4-4a23-9c83-ca9ebfd43416" />


#### 3. Feature Importance (`feature_importance.png`)
Ranks features by their contribution to classification accuracy.

**Top 3 Most Important Features:**
1. `encryption_overhead` (22.5%)
2. `packet_size_mean` (18.3%)
3. `packet_iat_mean` (15.7%)

#### 4. Prediction Distribution (`prediction_distribution.png`)
Shows confidence distributions for predictions on each class.

---

## 🔍 Understanding the Features

### How VPN and TOR Differ

#### VPN Characteristics
- **Direct encrypted tunnel**: Client ↔ VPN Server ↔ Destination
- **Single encryption layer**: Lower overhead (~15%)
- **Consistent packet sizes**: Varies based on application
- **Lower latency**: Direct connection to VPN server
- **Higher throughput**: Less overhead, fewer hops

#### TOR Characteristics
- **Multi-hop routing**: Client ↔ Guard ↔ Middle ↔ Exit ↔ Destination
- **Multiple encryption layers**: Onion encryption (~35% overhead)
- **Fixed cell size**: 512-byte cells for traffic analysis resistance
- **Higher latency**: Multiple relay hops add delay
- **Lower throughput**: Limited by slowest relay

### Feature Collection in Practice

**Using Network Monitoring Tools:**

```python
# Example: Extract features from PCAP file
from scapy.all import rdpcap, IP, TCP

def extract_features(pcap_file):
    packets = rdpcap(pcap_file)
    
    # Calculate features
    packet_sizes = [len(pkt) for pkt in packets if IP in pkt]
    iats = [packets[i].time - packets[i-1].time 
            for i in range(1, len(packets))]
    
    features = {
        'packet_size_mean': np.mean(packet_sizes),
        'packet_size_std': np.std(packet_sizes),
        'flow_duration': packets[-1].time - packets[0].time,
        'packets_per_second': len(packets) / flow_duration,
        # ... extract remaining features
    }
    
    return features
```

**Using Flow Exporters (e.g., nfdump, Argus):**

```bash
# Export flows from network capture
argus -r capture.pcap -w flows.argus

# Extract features
ra -r flows.argus -s saddr daddr dur pkts bytes rate
```

---

## 🚀 Deployment

### Option 1: REST API Service

```python
from flask import Flask, request, jsonify
from train import VPNTORClassifier
import pandas as pd

app = Flask(__name__)
classifier = VPNTORClassifier.load_model('models/vpn_tor_classifier.pkl')

@app.route('/predict', methods=['POST'])
def predict():
    data = request.json
    df = pd.DataFrame([data])
    results = classifier.predict(df)
    
    return jsonify({
        'prediction': results['labels'][0],
        'confidence': float(results['probabilities'][0].max()),
        'vpn_probability': float(results['probabilities'][0][0]),
        'tor_probability': float(results['probabilities'][0][1])
    })

if __name__ == '__main__':
    app.run(host='0.0.0.0', port=5000)
```

**Usage:**
```bash
curl -X POST http://localhost:5000/predict \
  -H "Content-Type: application/json" \
  -d '{
    "packet_size_mean": 750,
    "packet_size_std": 280,
    "flow_duration": 12.5,
    ...
  }'
```

### Option 2: Real-time Network Monitor

```python
import time
from train import VPNTORClassifier

classifier = VPNTORClassifier.load_model('models/vpn_tor_classifier.pkl')

def monitor_network(interface='eth0'):
    while True:
        # Capture traffic for 10-second windows
        features = capture_and_extract_features(interface, duration=10)
        
        # Classify
        results = classifier.predict(features)
        
        # Alert on TOR detection
        for i, label in enumerate(results['labels']):
            if label == 'TOR':
                confidence = results['probabilities'][i][1]
                print(f"⚠️  TOR traffic detected! Confidence: {confidence:.2%}")
        
        time.sleep(10)

if __name__ == '__main__':
    monitor_network()
```

### Option 3: Batch Processing

```python
import glob
from train import VPNTORClassifier

classifier = VPNTORClassifier.load_model('models/vpn_tor_classifier.pkl')

# Process all CSV files in directory
for filepath in glob.glob('data/flows/*.csv'):
    flows = pd.read_csv(filepath)
    results = classifier.predict(flows)
    
    flows['classification'] = results['labels']
    flows['confidence'] = results['probabilities'].max(axis=1)
    
    output_path = filepath.replace('/flows/', '/classified/')
    flows.to_csv(output_path, index=False)
    print(f"Processed: {filepath}")
```

---

## 🛠️ Troubleshooting

### Common Issues

#### 1. Import Errors

**Problem:** `ModuleNotFoundError: No module named 'sklearn'`

**Solution:**
```bash
pip install scikit-learn
# or
pip install -r requirements.txt
```

#### 2. Model Loading Fails

**Problem:** `FileNotFoundError: models/vpn_tor_classifier.pkl not found`

**Solution:**
```bash
# Train a new model first
python train.py

# Or check file path
ls models/
```

#### 3. Feature Mismatch

**Problem:** `ValueError: X has different number of features than training data`

**Solution:**
```python
# Check expected features
print(classifier.feature_names)

# Ensure your data has all required features in correct order
X = data[classifier.feature_names]
```

#### 4. Memory Issues

**Problem:** `MemoryError` during training

**Solution:**
```python
# Reduce sample size
X, y = classifier.generate_synthetic_data(n_samples=5000)

# Or use a simpler model
classifier = VPNTORClassifier(model_type='svm')
```

#### 5. Low Accuracy

**Problem:** Test accuracy below 90%

**Possible causes:**
- Insufficient training data
- Feature scaling issues
- Class imbalance
- Overfitting

**Solutions:**
```python
# 1. Increase training data
X, y = classifier.generate_synthetic_data(n_samples=20000)

# 2. Check class balance
print(f"VPN: {sum(y==0)}, TOR: {sum(y==1)}")

# 3. Try different model
classifier = VPNTORClassifier(model_type='gradient_boosting')

# 4. Adjust hyperparameters
classifier.model.n_estimators = 300
classifier.model.max_depth = 25
```

---

## 📚 References

### Scientific Background

1. **TOR Protocol**
   - Dingledine, R., Mathewson, N., & Syverson, P. (2004). "Tor: The second-generation onion router"
   - [Tor Project Documentation](https://www.torproject.org/about/overview.html)

2. **VPN Technology**
   - Paxson, V. (1999). "Bro: A system for detecting network intruders in real-time"
   - [OpenVPN Technical Documentation](https://openvpn.net/community-resources/)

3. **Traffic Analysis**
   - Wang, T., & Goldberg, I. (2013). "Improved website fingerprinting on Tor"
   - Montieri, A., et al. (2017). "Anonymity services tor, i2p, jondonym: Classifying in the dark"


### Dataset Sources (Real Data)

For production use with real traffic data:

- **ISCX VPN-nonVPN Dataset**: [https://www.unb.ca/cic/datasets/vpn.html](https://www.unb.ca/cic/datasets/vpn.html)
- **TOR Traffic Dataset**: [https://github.com/dlt-science/tor-traffic](https://github.com/dlt-science/tor-traffic)
- **CAIDA Anonymized Traces**: [https://www.caida.org/catalog/datasets/](https://www.caida.org/catalog/datasets/)

---

"""
ML Threat Prediction Service - Real machine learning for threat prediction
Uses trained models for:
1. Network anomaly detection
2. Process behavior classification
3. File threat scoring
4. User behavior analytics (UEBA)
5. Attack pattern recognition
6. Time-series anomaly detection
7. Ensemble prediction
8. Model persistence and explainability
"""
import os
import json
import hashlib
import logging
import math
import pickle
from datetime import datetime, timezone, timedelta
from typing import Dict, List, Optional, Any, Tuple, Sequence
from dataclasses import dataclass, field, asdict
from enum import Enum
from pathlib import Path
from collections import defaultdict
import random
try:
    from services.world_events import emit_world_event
except Exception:
    try:
        from backend.services.world_events import emit_world_event
    except Exception:
        emit_world_event = None

try:
    import numpy as np
except ImportError:
    # Fallback for environments without numpy
    np = None

# Optional third-party ML framework detection (best-effort, lazy imports)
TORCH_AVAILABLE = False
TF_AVAILABLE = False
SKLEARN_AVAILABLE = False
THEANO_AVAILABLE = False
CAFFE_AVAILABLE = False
SPARK_AVAILABLE = False
SAGEMAKER_AVAILABLE = False
CNTK_AVAILABLE = False
MAHOUT_AVAILABLE = False
ACCORDNET_AVAILABLE = False

try:
    import torch
    import torch.nn as nn
    import torch.nn.functional as F
    TORCH_AVAILABLE = True
except Exception:
    torch = None
    nn = None
    F = None

try:
    import tensorflow as tf
    TF_AVAILABLE = True
except Exception:
    tf = None

try:
    from sklearn.ensemble import RandomForestClassifier
    from sklearn.preprocessing import StandardScaler
    SKLEARN_AVAILABLE = True
except Exception:
    RandomForestClassifier = None
    StandardScaler = None

try:
    import theano
    THEANO_AVAILABLE = True
except Exception:
    theano = None

try:
    import caffe
    CAFFE_AVAILABLE = True
except Exception:
    caffe = None

try:
    import pyspark
    SPARK_AVAILABLE = True
except Exception:
    pyspark = None

try:
    import sagemaker
    import boto3
    SAGEMAKER_AVAILABLE = True
except Exception:
    sagemaker = None
    boto3 = None

try:
    import cntk
    CNTK_AVAILABLE = True
except Exception:
    cntk = None

# Apache Mahout, Accord.NET are not native Python libraries; mark unavailable
MAHOUT_AVAILABLE = False
ACCORDNET_AVAILABLE = False

from runtime_paths import ensure_data_dir

logger = logging.getLogger(__name__)

# Model storage directory
MODEL_DIR = ensure_data_dir("models")

# =============================================================================
# FEATURE EXTRACTION
# =============================================================================

class ThreatCategory(str, Enum):
    MALWARE = "malware"
    RANSOMWARE = "ransomware"
    APT = "apt"
    INSIDER_THREAT = "insider_threat"
    DATA_EXFILTRATION = "data_exfiltration"
    CRYPTOMINER = "cryptominer"
    BOTNET = "botnet"
    PHISHING = "phishing"
    LATERAL_MOVEMENT = "lateral_movement"
    PRIVILEGE_ESCALATION = "privilege_escalation"

class RiskLevel(str, Enum):
    CRITICAL = "critical"
    HIGH = "high"
    MEDIUM = "medium"
    LOW = "low"
    INFO = "info"

@dataclass
class NetworkFeatures:
    """Features extracted from network traffic"""
    bytes_in: int = 0
    bytes_out: int = 0
    packets_in: int = 0
    packets_out: int = 0
    unique_destinations: int = 0
    unique_ports: int = 0
    dns_queries: int = 0
    failed_connections: int = 0
    encrypted_ratio: float = 0.0
    avg_packet_size: float = 0.0
    connection_duration: float = 0.0
    port_scan_score: float = 0.0

@dataclass
class ProcessFeatures:
    """Features extracted from process behavior"""
    cpu_usage: float = 0.0
    memory_usage: float = 0.0
    file_operations: int = 0
    registry_operations: int = 0
    network_connections: int = 0
    child_processes: int = 0
    dll_loads: int = 0
    suspicious_api_calls: int = 0
    entropy: float = 0.0
    execution_time: float = 0.0

@dataclass
class UserFeatures:
    """Features for user behavior analytics"""
    login_hour: int = 0
    login_day: int = 0
    failed_logins: int = 0
    resources_accessed: int = 0
    data_transferred: int = 0
    anomaly_score: float = 0.0
    geo_distance: float = 0.0
    device_trust: float = 1.0

@dataclass
class ThreatPrediction:
    """ML prediction result"""
    prediction_id: str
    timestamp: str
    entity_type: str  # network, process, user, file
    entity_id: str
    predicted_category: ThreatCategory
    risk_level: RiskLevel
    confidence: float  # 0-1
    threat_score: int  # 0-100
    features: Dict[str, Any] = field(default_factory=dict)
    contributing_factors: List[str] = field(default_factory=list)
    recommended_actions: List[str] = field(default_factory=list)
    mitre_mappings: List[Dict] = field(default_factory=list)

# =============================================================================
# SIMPLE ML MODELS (No external dependencies)
# =============================================================================

class SimpleNeuralNetwork:
    """Simple feed-forward neural network implemented from scratch"""
    
    def __init__(self, input_size: int, hidden_size: int, output_size: int):
        self.input_size = input_size
        self.hidden_size = hidden_size
        self.output_size = output_size
        
        # Initialize weights with Xavier initialization
        self.w1 = [[random.gauss(0, math.sqrt(2.0/(input_size + hidden_size))) 
                   for _ in range(hidden_size)] for _ in range(input_size)]
        self.b1 = [0.0] * hidden_size
        
        self.w2 = [[random.gauss(0, math.sqrt(2.0/(hidden_size + output_size))) 
                   for _ in range(output_size)] for _ in range(hidden_size)]
        self.b2 = [0.0] * output_size
    
    def _relu(self, x: float) -> float:
        return max(0, x)
    
    def _sigmoid(self, x: float) -> float:
        if x < -500:
            return 0.0
        if x > 500:
            return 1.0
        return 1.0 / (1.0 + math.exp(-x))
    
    def _softmax(self, x: List[float]) -> List[float]:
        max_x = max(x)
        exp_x = [math.exp(xi - max_x) for xi in x]
        sum_exp = sum(exp_x)
        return [e / sum_exp for e in exp_x]
    
    def forward(self, inputs: List[float]) -> List[float]:
        """Forward pass through the network"""
        # Hidden layer
        hidden = []
        for j in range(self.hidden_size):
            total = self.b1[j]
            for i in range(self.input_size):
                total += inputs[i] * self.w1[i][j]
            hidden.append(self._relu(total))
        
        # Output layer
        output = []
        for k in range(self.output_size):
            total = self.b2[k]
            for j in range(self.hidden_size):
                total += hidden[j] * self.w2[j][k]
            output.append(total)
        
        return self._softmax(output)
    
    def predict(self, inputs: List[float]) -> Tuple[int, float]:
        """Predict class and confidence"""
        probs = self.forward(inputs)
        max_idx = max(range(len(probs)), key=lambda i: probs[i])
        return max_idx, probs[max_idx]


class TorchBehaviorModel:
    """Lightweight PyTorch MLP wrapper used when torch is available."""
    def __init__(self, input_size: int, hidden_size: int, output_size: int):
        if not TORCH_AVAILABLE:
            raise RuntimeError("PyTorch not available")
        class MLP(nn.Module):
            def __init__(self, in_sz, hid_sz, out_sz):
                super().__init__()
                self.fc1 = nn.Linear(in_sz, hid_sz)
                self.fc2 = nn.Linear(hid_sz, out_sz)

            def forward(self, x):
                x = F.relu(self.fc1(x))
                x = self.fc2(x)
                return F.softmax(x, dim=-1)

        self.model = MLP(input_size, hidden_size, output_size)
        # inference on CPU only; models are randomly initialized until trained
        self.model.eval()

    def predict(self, inputs: List[float]) -> Tuple[int, float]:
        with torch.no_grad():
            tensor = torch.tensor(inputs, dtype=torch.float32).unsqueeze(0)
            out = self.model(tensor)[0].numpy().tolist()
            max_idx = max(range(len(out)), key=lambda i: out[i])
            return max_idx, out[max_idx]


class SKLearnWrapper:
    """Simple wrapper around scikit-learn estimators to provide a minimal fit/predict interface."""
    def __init__(self, estimator=None):
        self.estimator = estimator
        # scaler may be unavailable; use a simple mean/std scaler if needed
        if SKLEARN_AVAILABLE and StandardScaler is not None:
            self.scaler = StandardScaler()
        else:
            self.scaler = None

    def fit(self, X: List[List[float]], y: List):
        if self.estimator is None:
            raise RuntimeError("No estimator provided to SKLearnWrapper")
        if self.scaler:
            X = self.scaler.fit_transform(X)
        # support mimic estimators with fit
        if hasattr(self.estimator, "fit"):
            self.estimator.fit(X, y)
            return
        raise RuntimeError("Estimator does not support fit()")

    def predict(self, X: List[float]) -> Tuple[int, float]:
        if self.estimator is None:
            raise RuntimeError("No estimator provided to SKLearnWrapper")
        x_in = X
        if self.scaler:
            x_in = self.scaler.transform([X])[0]
        # support mimic estimator predict_proba
        if hasattr(self.estimator, "predict_proba"):
            probs = self.estimator.predict_proba([x_in])[0]
            # convert to list if numpy
            try:
                probs = list(probs)
            except Exception:
                pass
            idx = int(max(range(len(probs)), key=lambda i: probs[i]))
            return idx, float(probs[idx])
        # fallback: estimator.predict returning index
        if hasattr(self.estimator, "predict"):
            pred = self.estimator.predict([x_in])
            if isinstance(pred, (list, tuple)):
                return int(pred[0]), 0.5
            return int(pred), 0.5
        raise RuntimeError("Estimator does not support predict/probabilities")


class MimicRandomForest:
    """Lightweight RandomForest mimic using bootstrap aggregation of decision stumps."""
    def __init__(self, n_estimators: int = 10):
        self.n_estimators = n_estimators
        self.trees: List[Dict] = []
        self.classes_: List = []

    def fit(self, X: List[List[float]], y: List):
        # store classes and simple feature thresholds per tree
        self.classes_ = list(sorted(set(y)))
        n = len(X)
        for _ in range(self.n_estimators):
            idxs = [random.randint(0, n - 1) for _ in range(max(1, n // 2))]
            sample_x = [X[i] for i in idxs]
            sample_y = [y[i] for i in idxs]
            # build simple stump: pick best single-feature threshold
            best = None
            best_score = -1
            m = len(X[0])
            for f in range(m):
                vals = [sx[f] for sx in sample_x]
                thresh = sum(vals) / len(vals)
                # score by how well split separates labels
                left = [sample_y[i] for i, v in enumerate(vals) if v < thresh]
                right = [sample_y[i] for i, v in enumerate(vals) if v >= thresh]
                score = abs((left.count(left[0]) if left else 0) - (right.count(right[0]) if right else 0)) if (left and right) else 0
                if score > best_score:
                    best_score = score
                    best = {"feature": f, "thresh": thresh}
            self.trees.append({"stump": best})

    def predict_proba(self, X: List[List[float]]) -> List[List[float]]:
        out = []
        for x in X:
            votes = defaultdict(int)
            for t in self.trees:
                stump = t.get("stump")
                if stump is None:
                    votes[self.classes_[0]] += 1
                else:
                    v = x[stump["feature"]]
                    chosen = self.classes_[0] if v < stump["thresh"] else self.classes_[-1]
                    votes[chosen] += 1
            total = sum(votes.values())
            probs = [votes.get(c, 0) / (total or 1) for c in self.classes_]
            out.append(probs)
        return out


class TensorFlowWrapper:
    def __init__(self):
        # Use real TensorFlow if available, otherwise fall back to a mimic model
        self.model = None
        if not TF_AVAILABLE:
            self.model = None

    def load_model(self, path: str):
        if TF_AVAILABLE:
            try:
                self.model = tf.keras.models.load_model(path)
            except Exception:
                self.model = None
        else:
            # mimic: load a small in-memory model placeholder
            self.model = MimicKerasModel()

    def predict(self, inputs: List[float]):
        if self.model is None:
            raise RuntimeError("TensorFlow model not available")
        # delegate to mimic or real model
        if TF_AVAILABLE:
            import numpy as _np
            arr = _np.array([inputs], dtype=_np.float32)
            out = self.model.predict(arr)
            probs = out[0].tolist()
            idx = max(range(len(probs)), key=lambda i: probs[i])
            return idx, probs[idx]
        else:
            probs = self.model.predict(inputs)
            idx = max(range(len(probs)), key=lambda i: probs[i])
            return idx, probs[idx]


class MimicKerasModel:
    """Very small NumPy-based MLP mimic for Keras-style predict output."""
    def __init__(self, input_size: int = 12, hidden_size: int = 16, output_size: int = 5):
        self.input_size = input_size
        self.hidden_size = hidden_size
        self.output_size = output_size
        # random weights deterministic by seed for reproducibility
        random.seed(0)
        self.w1 = [[random.uniform(-0.5, 0.5) for _ in range(hidden_size)] for _ in range(input_size)]
        self.b1 = [0.0] * hidden_size
        self.w2 = [[random.uniform(-0.5, 0.5) for _ in range(output_size)] for _ in range(hidden_size)]
        self.b2 = [0.0] * output_size

    def _softmax(self, x: List[float]) -> List[float]:
        max_x = max(x)
        ex = [math.exp(xi - max_x) for xi in x]
        s = sum(ex) or 1.0
        return [e / s for e in ex]

    def predict(self, inputs: List[float]) -> List[List[float]]:
        # accept single sample or array
        if isinstance(inputs[0], (list, tuple)):
            samples = inputs
        else:
            samples = [inputs]
        out = []
        for s in samples:
            hidden = [0.0] * self.hidden_size
            for j in range(self.hidden_size):
                total = self.b1[j]
                for i in range(min(len(s), self.input_size)):
                    total += s[i] * self.w1[i][j]
                hidden[j] = max(0, total)
            logits = [self.b2[k] + sum(hidden[j] * self.w2[j][k] for j in range(self.hidden_size)) for k in range(self.output_size)]
            out.append(self._softmax(logits))
        return out


class PlaceholderRemoteWrapper:
    """Placeholder wrapper for non-Python or remote frameworks (Mahout, Accord.NET, SageMaker, CNTK, Spark).

    Methods are best-effort and will return informative errors when the integration is not available.
    """
    def __init__(self, name: str):
        self.name = name

    def predict(self, *args, **kwargs):
        raise RuntimeError(f"{self.name} integration not available in this environment")


class IsolationForest:
    """Simple Isolation Forest for anomaly detection"""
    
    def __init__(self, n_trees: int = 100, sample_size: int = 256):
        self.n_trees = n_trees
        self.sample_size = sample_size
        self.trees: List[Dict] = []
        self.trained = False
    
    def _build_tree(self, data: List[List[float]], height: int = 0, max_height: int = 10) -> Dict:
        """Build an isolation tree"""
        if height >= max_height or len(data) <= 1:
            return {"type": "leaf", "size": len(data)}
        
        n_features = len(data[0])
        split_feature = random.randint(0, n_features - 1)
        
        feature_values = [x[split_feature] for x in data]
        min_val, max_val = min(feature_values), max(feature_values)
        
        if min_val == max_val:
            return {"type": "leaf", "size": len(data)}
        
        split_value = random.uniform(min_val, max_val)
        
        left_data = [x for x in data if x[split_feature] < split_value]
        right_data = [x for x in data if x[split_feature] >= split_value]
        
        return {
            "type": "node",
            "feature": split_feature,
            "split": split_value,
            "left": self._build_tree(left_data, height + 1, max_height),
            "right": self._build_tree(right_data, height + 1, max_height)
        }
    
    def fit(self, data: List[List[float]]):
        """Train the isolation forest"""
        max_height = int(math.ceil(math.log2(self.sample_size)))
        
        for _ in range(self.n_trees):
            sample = random.sample(data, min(self.sample_size, len(data)))
            tree = self._build_tree(sample, max_height=max_height)
            self.trees.append(tree)
        
        self.trained = True
    
    def _path_length(self, x: List[float], tree: Dict, current_depth: int = 0) -> float:
        """Calculate path length for a sample"""
        if tree["type"] == "leaf":
            size = tree["size"]
            if size <= 1:
                return current_depth
            # Average path length for remaining nodes
            c = 2 * (math.log(size - 1) + 0.5772156649) - (2 * (size - 1) / size)
            return current_depth + c
        
        if x[tree["feature"]] < tree["split"]:
            return self._path_length(x, tree["left"], current_depth + 1)
        else:
            return self._path_length(x, tree["right"], current_depth + 1)
    
    def score(self, x: List[float]) -> float:
        """Calculate anomaly score (0-1, higher = more anomalous)"""
        if not self.trained:
            return 0.5
        
        avg_path = sum(self._path_length(x, tree) for tree in self.trees) / len(self.trees)
        c = 2 * (math.log(self.sample_size - 1) + 0.5772156649) - (2 * (self.sample_size - 1) / self.sample_size)
        
        # Anomaly score
        score = 2 ** (-avg_path / c)
        return min(1.0, max(0.0, score))


class BayesianClassifier:
    """Naive Bayes classifier for threat categorization"""
    
    def __init__(self, categories: List[str]):
        self.categories = categories
        self.priors: Dict[str, float] = {}
        self.means: Dict[str, List[float]] = {}
        self.stds: Dict[str, List[float]] = {}
        self.trained = False
    
    def fit(self, data: Dict[str, List[List[float]]]):
        """Train the classifier"""
        total_samples = sum(len(samples) for samples in data.values())
        
        for category, samples in data.items():
            self.priors[category] = len(samples) / total_samples
            
            n_features = len(samples[0])
            self.means[category] = []
            self.stds[category] = []
            
            for i in range(n_features):
                values = [s[i] for s in samples]
                mean = sum(values) / len(values)
                variance = sum((v - mean) ** 2 for v in values) / len(values)
                std = math.sqrt(variance) + 1e-6  # Prevent division by zero
                
                self.means[category].append(mean)
                self.stds[category].append(std)
        
        self.trained = True
    
    def _gaussian_prob(self, x: float, mean: float, std: float) -> float:
        """Calculate Gaussian probability density"""
        exp_term = -0.5 * ((x - mean) / std) ** 2
        return (1 / (std * math.sqrt(2 * math.pi))) * math.exp(exp_term)
    
    def predict(self, x: List[float]) -> Tuple[str, float]:
        """Predict category and probability"""
        if not self.trained:
            return self.categories[0], 0.5
        
        posteriors = {}
        
        # Only iterate over categories that have been trained
        for category in self.priors.keys():
            log_prob = math.log(self.priors[category])
            
            for i, val in enumerate(x):
                prob = self._gaussian_prob(val, self.means[category][i], self.stds[category][i])
                log_prob += math.log(prob + 1e-10)
            
            posteriors[category] = log_prob
        
        # Normalize
        max_log = max(posteriors.values())
        probs = {k: math.exp(v - max_log) for k, v in posteriors.items()}
        total = sum(probs.values())
        probs = {k: v / total for k, v in probs.items()}
        
        best_category = max(probs, key=probs.get)
        return best_category, probs[best_category]


# =============================================================================
# THREAT PREDICTION SERVICE
# =============================================================================

class MLThreatPredictor:
    """
    Machine Learning Threat Prediction Engine
    Combines multiple ML models for comprehensive threat detection
    """
    
    def __init__(self):
        self.network_anomaly_detector = IsolationForest(n_trees=50, sample_size=128)
        self.process_anomaly_detector = IsolationForest(n_trees=50, sample_size=128)
        # Prefer scikit-learn RandomForest when available for threat classification
        try:
            if SKLEARN_AVAILABLE and RandomForestClassifier is not None:
                rf = RandomForestClassifier(n_estimators=100)
                self.threat_classifier = SKLearnWrapper(rf)
            else:
                # use mimic RandomForest when scikit-learn is not available
                rf = MimicRandomForest(n_estimators=20)
                self.threat_classifier = SKLearnWrapper(rf)
        except Exception:
            self.threat_classifier = BayesianClassifier([c.value for c in ThreatCategory])
        # Prefer a PyTorch-backed behavior model when available, otherwise fall back
        try:
            if TORCH_AVAILABLE:
                self.behavior_model = TorchBehaviorModel(input_size=12, hidden_size=32, output_size=5)
            else:
                self.behavior_model = SimpleNeuralNetwork(input_size=12, hidden_size=24, output_size=5)
        except Exception:
            self.behavior_model = SimpleNeuralNetwork(input_size=12, hidden_size=24, output_size=5)
        
        self.predictions: Dict[str, ThreatPrediction] = {}
        self.training_data: Dict[str, List] = defaultdict(list)
        self.model_version = "1.0.0"
        self._db = None
        
        # Initialize with synthetic training data
        self._initialize_models()
    
    def set_database(self, db):
        self._db = db

    async def _emit_event(
        self,
        event_type: str,
        entity_refs: Optional[List[str]] = None,
        payload: Optional[Dict[str, Any]] = None,
        trigger_triune: bool = False,
    ) -> None:
        if self._db is None or emit_world_event is None:
            return
        try:
            await emit_world_event(
                self._db,
                event_type=event_type,
                entity_refs=entity_refs or [],
                payload=payload or {},
                trigger_triune=trigger_triune,
            )
        except Exception:
            logger.debug("ml threat world event emission failed", exc_info=True)
    
    def _initialize_models(self):
        """Initialize models with synthetic training data"""
        # Generate synthetic normal network data
        normal_network = [
            [random.gauss(1000, 200), random.gauss(500, 100), random.gauss(50, 10),
             random.gauss(30, 5), random.randint(3, 10), random.randint(2, 5),
             random.randint(5, 20), random.randint(0, 2), random.uniform(0.3, 0.7),
             random.gauss(500, 100), random.gauss(30, 10), random.uniform(0, 0.2)]
            for _ in range(200)
        ]
        
        # Generate synthetic anomalous network data
        anomalous_network = [
            [random.gauss(50000, 10000), random.gauss(100000, 20000), random.gauss(500, 100),
             random.gauss(1000, 200), random.randint(50, 100), random.randint(20, 65535),
             random.randint(100, 500), random.randint(10, 50), random.uniform(0.9, 1.0),
             random.gauss(1500, 300), random.gauss(1, 0.5), random.uniform(0.6, 1.0)]
            for _ in range(50)
        ]
        
        # Train network anomaly detector
        self.network_anomaly_detector.fit(normal_network)
        
        # Generate synthetic process data
        normal_process = [
            [random.uniform(1, 20), random.uniform(50, 200), random.randint(10, 100),
             random.randint(0, 10), random.randint(0, 5), random.randint(0, 3),
             random.randint(5, 20), 0, random.uniform(3, 5), random.uniform(1, 60)]
            for _ in range(200)
        ]
        
        self.process_anomaly_detector.fit(normal_process)
        
        # Train threat classifier with labeled data
        threat_data = {
            ThreatCategory.MALWARE.value: [
                [0.9, 0.8, 0.7, 0.9, 0.6, 0.8, 0.7, 0.9, 0.8, 0.7, 0.6, 0.9]
                for _ in range(30)
            ],
            ThreatCategory.RANSOMWARE.value: [
                [0.95, 0.9, 0.85, 0.95, 0.8, 0.9, 0.85, 0.95, 0.9, 0.85, 0.8, 0.95]
                for _ in range(30)
            ],
            ThreatCategory.APT.value: [
                [0.6, 0.7, 0.5, 0.6, 0.8, 0.7, 0.6, 0.5, 0.7, 0.6, 0.8, 0.7]
                for _ in range(30)
            ],
            ThreatCategory.DATA_EXFILTRATION.value: [
                [0.5, 0.4, 0.3, 0.5, 0.9, 0.95, 0.4, 0.3, 0.5, 0.4, 0.9, 0.5]
                for _ in range(30)
            ],
            ThreatCategory.CRYPTOMINER.value: [
                [0.95, 0.3, 0.2, 0.4, 0.3, 0.4, 0.3, 0.2, 0.95, 0.8, 0.3, 0.4]
                for _ in range(30)
            ],
        }
        # Convert threat_data (label -> list[samples]) into X, y for sklearn-style fit
        X = []
        y = []
        for label, samples in threat_data.items():
            for s in samples:
                X.append(s)
                y.append(label)
        self.threat_classifier.fit(X, y)
        
        logger.info("ML models initialized with synthetic training data")
    
    def _extract_network_features(self, data: Dict) -> List[float]:
        """Extract features from network data"""
        return [
            data.get("bytes_in", 0) / 1000,  # Normalize
            data.get("bytes_out", 0) / 1000,
            data.get("packets_in", 0) / 10,
            data.get("packets_out", 0) / 10,
            data.get("unique_destinations", 0),
            data.get("unique_ports", 0),
            data.get("dns_queries", 0),
            data.get("failed_connections", 0),
            data.get("encrypted_ratio", 0.5),
            data.get("avg_packet_size", 500) / 100,
            data.get("connection_duration", 30) / 10,
            data.get("port_scan_score", 0)
        ]
    
    def _extract_process_features(self, data: Dict) -> List[float]:
        """Extract features from process data"""
        return [
            data.get("cpu_usage", 5) / 10,
            data.get("memory_usage", 100) / 100,
            data.get("file_operations", 10),
            data.get("registry_operations", 0),
            data.get("network_connections", 0),
            data.get("child_processes", 0),
            data.get("dll_loads", 10),
            data.get("suspicious_api_calls", 0),
            data.get("entropy", 4),
            data.get("execution_time", 10)
        ]
    
    def _determine_risk_level(self, score: int) -> RiskLevel:
        """Map threat score to risk level"""
        if score >= 80:
            return RiskLevel.CRITICAL
        elif score >= 60:
            return RiskLevel.HIGH
        elif score >= 40:
            return RiskLevel.MEDIUM
        elif score >= 20:
            return RiskLevel.LOW
        else:
            return RiskLevel.INFO
    
    def _get_contributing_factors(self, features: List[float], thresholds: List[float], names: List[str]) -> List[str]:
        """Identify which features contributed to high score"""
        factors = []
        for i, (feat, thresh, name) in enumerate(zip(features, thresholds, names)):
            if feat > thresh:
                factors.append(f"{name}: {feat:.2f} (threshold: {thresh:.2f})")
        return factors[:5]  # Top 5 factors
    
    def _get_recommended_actions(self, category: ThreatCategory, risk: RiskLevel) -> List[str]:
        """Get recommended response actions"""
        actions = []
        
        if risk in [RiskLevel.CRITICAL, RiskLevel.HIGH]:
            actions.append("Immediately isolate affected system")
            actions.append("Trigger incident response playbook")
        
        category_actions = {
            ThreatCategory.MALWARE: [
                "Run full system scan",
                "Check for persistence mechanisms",
                "Analyze dropped files in sandbox"
            ],
            ThreatCategory.RANSOMWARE: [
                "Disconnect from network immediately",
                "Preserve encrypted files for forensics",
                "Check for lateral movement"
            ],
            ThreatCategory.APT: [
                "Enable enhanced logging",
                "Monitor for C2 communication",
                "Review user access patterns"
            ],
            ThreatCategory.DATA_EXFILTRATION: [
                "Block outbound connections",
                "Identify data being exfiltrated",
                "Review DLP policies"
            ],
            ThreatCategory.CRYPTOMINER: [
                "Terminate mining process",
                "Check resource usage patterns",
                "Review container security"
            ]
        }
        
        actions.extend(category_actions.get(category, ["Investigate further"]))
        return actions
    
    def _get_mitre_mappings(self, category: ThreatCategory) -> List[Dict]:
        """Map threat category to MITRE ATT&CK"""
        mappings = {
            ThreatCategory.MALWARE: [
                {"tactic": "Execution", "technique": "T1059", "name": "Command and Scripting Interpreter"},
                {"tactic": "Persistence", "technique": "T1547", "name": "Boot or Logon Autostart"}
            ],
            ThreatCategory.RANSOMWARE: [
                {"tactic": "Impact", "technique": "T1486", "name": "Data Encrypted for Impact"},
                {"tactic": "Discovery", "technique": "T1083", "name": "File and Directory Discovery"}
            ],
            ThreatCategory.APT: [
                {"tactic": "Initial Access", "technique": "T1566", "name": "Phishing"},
                {"tactic": "Command and Control", "technique": "T1071", "name": "Application Layer Protocol"}
            ],
            ThreatCategory.DATA_EXFILTRATION: [
                {"tactic": "Exfiltration", "technique": "T1041", "name": "Exfiltration Over C2"},
                {"tactic": "Collection", "technique": "T1560", "name": "Archive Collected Data"}
            ],
            ThreatCategory.CRYPTOMINER: [
                {"tactic": "Impact", "technique": "T1496", "name": "Resource Hijacking"},
                {"tactic": "Execution", "technique": "T1059", "name": "Command Line Interface"}
            ]
        }
        return mappings.get(category, [])

    def _coerce_threat_category(self, raw_value: Any) -> ThreatCategory:
        """Map classifier output to a valid ThreatCategory."""
        if isinstance(raw_value, ThreatCategory):
            return raw_value
        if isinstance(raw_value, str):
            normalized = raw_value.strip().lower()
            try:
                return ThreatCategory(normalized)
            except ValueError:
                pass
        if isinstance(raw_value, (int, float)):
            ordered = list(ThreatCategory)
            idx = int(raw_value)
            if 0 <= idx < len(ordered):
                return ordered[idx]
        return ThreatCategory.MALWARE
    
    async def predict_network_threat(self, network_data: Dict) -> ThreatPrediction:
        """Predict threats from network traffic data"""
        features = self._extract_network_features(network_data)
        
        # Anomaly detection
        anomaly_score = self.network_anomaly_detector.score(features)
        
        # Threat classification
        category_str, confidence = self.threat_classifier.predict(features)
        category = self._coerce_threat_category(category_str)
        
        # Calculate threat score
        threat_score = int((anomaly_score * 0.6 + confidence * 0.4) * 100)
        
        # Feature thresholds for factor analysis
        thresholds = [10, 10, 30, 30, 20, 10, 50, 5, 0.8, 10, 2, 0.5]
        names = ["bytes_in", "bytes_out", "packets_in", "packets_out", "destinations",
                 "ports", "dns_queries", "failed_conn", "encrypted_ratio", "packet_size",
                 "duration", "port_scan"]
        
        prediction_id = f"pred_{hashlib.md5(f'{datetime.now().isoformat()}-network'.encode()).hexdigest()[:12]}"
        
        prediction = ThreatPrediction(
            prediction_id=prediction_id,
            timestamp=datetime.now(timezone.utc).isoformat(),
            entity_type="network",
            entity_id=network_data.get("source_ip", "unknown"),
            predicted_category=category,
            risk_level=self._determine_risk_level(threat_score),
            confidence=confidence,
            threat_score=threat_score,
            features={
                "anomaly_score": anomaly_score,
                "raw_features": dict(zip(names, features))
            },
            contributing_factors=self._get_contributing_factors(features, thresholds, names),
            recommended_actions=self._get_recommended_actions(category, self._determine_risk_level(threat_score)),
            mitre_mappings=self._get_mitre_mappings(category)
        )
        
        self.predictions[prediction_id] = prediction
        
        # Store in database
        if self._db is not None:
            await self._db.ml_predictions.insert_one(asdict(prediction))
        await self._emit_event(
            "ml_threat_prediction_generated_service",
            entity_refs=[prediction.prediction_id, prediction.entity_id],
            payload={"entity_type": prediction.entity_type, "risk_level": prediction.risk_level.value, "threat_score": prediction.threat_score},
            trigger_triune=prediction.threat_score >= 80,
        )

        return prediction

    async def predict_from_snapshot(self, context: Dict[str, Any]) -> Dict[str, Any]:
        """Produce ML predictions from a canonical ReasoningContext-like snapshot.

        Returns a dict containing per-entity predictions and a small triune-friendly
        summary: predicted_next_moves, campaign_candidates, uncertainty_estimates.
        """
        try:
            # Normalize context
            if hasattr(context, "to_dict"):
                ctx = context.to_dict()
            else:
                ctx = dict(context or {})

            entities = ctx.get("entities") or []
            evidence = ctx.get("evidence_set") or ctx.get("evidence") or []
            rels = ctx.get("relationships") or {}
            timeline = ctx.get("timeline_window") or ctx.get("timeline") or []

            results = []
            # Simple heuristics to choose which predictor to call per entity
            for ent in entities[:20]:
                etype = ent.get("type") or ent.get("entity_type") or "unknown"
                eid = ent.get("id") or ent.get("entity_id") or "unknown"
                # Build minimal feature dicts for predictors
                if etype in ["host", "agent", "network"]:
                    net_sample = {
                        "source_ip": eid,
                        "bytes_in": ent.get("attributes", {}).get("bytes_in", 0),
                        "bytes_out": ent.get("attributes", {}).get("bytes_out", 0),
                        "packets_in": ent.get("attributes", {}).get("packets_in", 0),
                        "packets_out": ent.get("attributes", {}).get("packets_out", 0),
                        "unique_destinations": ent.get("attributes", {}).get("unique_destinations", 0),
                        "unique_ports": ent.get("attributes", {}).get("unique_ports", 0),
                        "dns_queries": ent.get("attributes", {}).get("dns_queries", 0),
                        "failed_connections": ent.get("attributes", {}).get("failed_connections", 0),
                        "encrypted_ratio": ent.get("attributes", {}).get("encrypted_ratio", 0.5),
                        "avg_packet_size": ent.get("attributes", {}).get("avg_packet_size", 500),
                        "connection_duration": ent.get("attributes", {}).get("connection_duration", 30),
                        "port_scan_score": ent.get("attributes", {}).get("port_scan_score", 0)
                    }
                    pred = await self.predict_network_threat(net_sample)
                    results.append(asdict(pred))
                elif etype in ["process", "service"]:
                    proc = {
                        "process_name": ent.get("attributes", {}).get("process_name", eid),
                        "cpu_usage": ent.get("attributes", {}).get("cpu_usage", 1),
                        "memory_usage": ent.get("attributes", {}).get("memory_usage", 50),
                        "file_operations": ent.get("attributes", {}).get("file_operations", 0),
                        "registry_operations": ent.get("attributes", {}).get("registry_operations", 0),
                        "network_connections": ent.get("attributes", {}).get("network_connections", 0),
                        "child_processes": ent.get("attributes", {}).get("child_processes", 0),
                        "dll_loads": ent.get("attributes", {}).get("dll_loads", 0),
                        "suspicious_api_calls": ent.get("attributes", {}).get("suspicious_api_calls", 0),
                        "entropy": ent.get("attributes", {}).get("entropy", 4),
                        "execution_time": ent.get("attributes", {}).get("execution_time", 0)
                    }
                    pred = await self.predict_process_threat(proc)
                    results.append(asdict(pred))
                elif etype in ["user"]:
                    user = {
                        "user_id": ent.get("id") or ent.get("attributes", {}).get("user_id", "unknown"),
                        "login_hour": ent.get("attributes", {}).get("login_hour", 12),
                        "login_day": ent.get("attributes", {}).get("login_day", 3),
                        "failed_logins": ent.get("attributes", {}).get("failed_logins", 0),
                        "resources_accessed": ent.get("attributes", {}).get("resources_accessed", 0),
                        "data_transferred": ent.get("attributes", {}).get("data_transferred", 0),
                        "anomaly_score": ent.get("attributes", {}).get("anomaly_score", 0),
                        "geo_distance": ent.get("attributes", {}).get("geo_distance", 0),
                        "device_trust": ent.get("attributes", {}).get("device_trust", 1.0),
                        "unusual_time": ent.get("attributes", {}).get("unusual_time", False),
                        "unusual_location": ent.get("attributes", {}).get("unusual_location", False),
                        "privilege_escalations": ent.get("attributes", {}).get("privilege_escalations", 0),
                        "sensitive_access": ent.get("attributes", {}).get("sensitive_access", 0)
                    }
                    pred = await self.predict_user_threat(user)
                    results.append(asdict(pred))

            # Simple aggregate heuristics for triune mapping
            evidence_texts = [e.get("type") or e.get("indicator_type") or str(e) for e in evidence]
            predicted_next = []
            uncertainty = {}
            # if exfiltration or high anomaly predictions exist, suggest containment
            high_score_preds = [p for p in results if p.get("threat_score", 0) >= 70]
            if any("exfil" in (s or "").lower() for s in evidence_texts) or high_score_preds:
                predicted_next.append("isolate_hosts")
                predicted_next.append("block_outbound")
            else:
                predicted_next.append("investigate")

            # Uncertainty: based on evidence density and timeline sparsity
            evidence_count = len(evidence)
            entity_count = len(entities)
            timeline_len = len(timeline)
            uncertainty_score = max(0.0, 1.0 - min(1.0, (evidence_count / (entity_count + 1)) if entity_count else 0.0))
            uncertainty["snapshot_uncertainty"] = round(uncertainty_score, 2)

            return {
                "predictions": results,
                "predicted_next_moves": predicted_next,
                "campaign_candidates": [],
                "uncertainty": uncertainty,
                "context_summary": {"entities": entity_count, "evidence": evidence_count, "timeline": timeline_len}
            }
        except Exception as e:
            logger.exception("predict_from_snapshot error")
            return {"error": str(e)}
    
    async def predict_process_threat(self, process_data: Dict) -> ThreatPrediction:
        """Predict threats from process behavior"""
        features = self._extract_process_features(process_data)
        
        # Anomaly detection
        anomaly_score = self.process_anomaly_detector.score(features)
        
        # Use neural network for behavior classification
        behavior_class, behavior_conf = self.behavior_model.predict(features + [anomaly_score, anomaly_score])
        
        # Map behavior class to threat category
        category_map = [
            ThreatCategory.MALWARE,
            ThreatCategory.RANSOMWARE,
            ThreatCategory.CRYPTOMINER,
            ThreatCategory.APT,
            ThreatCategory.DATA_EXFILTRATION
        ]
        category = category_map[behavior_class] if behavior_class < len(category_map) else ThreatCategory.MALWARE
        
        # Calculate threat score
        threat_score = int((anomaly_score * 0.5 + behavior_conf * 0.5) * 100)
        
        prediction_id = f"pred_{hashlib.md5(f'{datetime.now().isoformat()}-process'.encode()).hexdigest()[:12]}"
        
        names = ["cpu", "memory", "file_ops", "reg_ops", "net_conn", "children",
                 "dlls", "sus_api", "entropy", "exec_time"]
        thresholds = [50, 500, 100, 50, 20, 10, 50, 5, 7, 300]
        
        prediction = ThreatPrediction(
            prediction_id=prediction_id,
            timestamp=datetime.now(timezone.utc).isoformat(),
            entity_type="process",
            entity_id=process_data.get("process_name", "unknown"),
            predicted_category=category,
            risk_level=self._determine_risk_level(threat_score),
            confidence=behavior_conf,
            threat_score=threat_score,
            features={
                "anomaly_score": anomaly_score,
                "behavior_class": behavior_class,
                "raw_features": dict(zip(names, features))
            },
            contributing_factors=self._get_contributing_factors(features, thresholds, names),
            recommended_actions=self._get_recommended_actions(category, self._determine_risk_level(threat_score)),
            mitre_mappings=self._get_mitre_mappings(category)
        )
        
        self.predictions[prediction_id] = prediction
        
        if self._db is not None:
            await self._db.ml_predictions.insert_one(asdict(prediction))
        await self._emit_event(
            "ml_threat_prediction_generated_service",
            entity_refs=[prediction.prediction_id, prediction.entity_id],
            payload={"entity_type": prediction.entity_type, "risk_level": prediction.risk_level.value, "threat_score": prediction.threat_score},
            trigger_triune=prediction.threat_score >= 80,
        )

        return prediction
    
    async def predict_file_threat(self, file_data: Dict) -> ThreatPrediction:
        """Predict threats from file analysis"""
        # Extract file features
        features = [
            file_data.get("size", 0) / 1000000,  # Size in MB
            file_data.get("entropy", 5),
            1 if file_data.get("is_packed", False) else 0,
            1 if file_data.get("has_signature", True) else 0,
            file_data.get("import_count", 50) / 100,
            file_data.get("export_count", 0) / 10,
            1 if file_data.get("is_obfuscated", False) else 0,
            file_data.get("strings_count", 100) / 1000,
            1 if file_data.get("has_overlay", False) else 0,
            file_data.get("section_count", 5) / 10,
            1 if file_data.get("suspicious_sections", False) else 0,
            file_data.get("vt_detection_ratio", 0)
        ]
        
        # Classify
        category_str, confidence = self.threat_classifier.predict(features)
        category = self._coerce_threat_category(category_str)
        
        # Score based on key indicators
        score_factors = [
            features[1] > 7,  # High entropy
            features[2] == 1,  # Packed
            features[3] == 0,  # No signature
            features[6] == 1,  # Obfuscated
            features[10] == 1,  # Suspicious sections
            features[11] > 0.3  # VT detections
        ]
        threat_score = int(sum(score_factors) / len(score_factors) * 100 * confidence)
        
        prediction_id = f"pred_{hashlib.md5(f'{datetime.now().isoformat()}-file'.encode()).hexdigest()[:12]}"
        
        prediction = ThreatPrediction(
            prediction_id=prediction_id,
            timestamp=datetime.now(timezone.utc).isoformat(),
            entity_type="file",
            entity_id=file_data.get("hash", file_data.get("filename", "unknown")),
            predicted_category=category,
            risk_level=self._determine_risk_level(threat_score),
            confidence=confidence,
            threat_score=threat_score,
            features=file_data,
            contributing_factors=[
                f"High entropy: {features[1]:.2f}" if features[1] > 7 else None,
                "File is packed" if features[2] == 1 else None,
                "Missing digital signature" if features[3] == 0 else None,
                "Code obfuscation detected" if features[6] == 1 else None,
                f"VirusTotal ratio: {features[11]:.1%}" if features[11] > 0 else None
            ],
            recommended_actions=self._get_recommended_actions(category, self._determine_risk_level(threat_score)),
            mitre_mappings=self._get_mitre_mappings(category)
        )
        
        # Clean up None factors
        prediction.contributing_factors = [f for f in prediction.contributing_factors if f]
        
        self.predictions[prediction_id] = prediction
        
        if self._db is not None:
            await self._db.ml_predictions.insert_one(asdict(prediction))
        await self._emit_event(
            "ml_threat_prediction_generated_service",
            entity_refs=[prediction.prediction_id, prediction.entity_id],
            payload={"entity_type": prediction.entity_type, "risk_level": prediction.risk_level.value, "threat_score": prediction.threat_score},
            trigger_triune=prediction.threat_score >= 80,
        )

        return prediction
    
    async def predict_user_threat(self, user_data: Dict) -> ThreatPrediction:
        """Predict insider threats from user behavior (UEBA)"""
        # Extract user behavior features
        features = [
            user_data.get("login_hour", 12) / 24,
            user_data.get("login_day", 3) / 7,
            user_data.get("failed_logins", 0) / 10,
            user_data.get("resources_accessed", 10) / 100,
            user_data.get("data_transferred", 0) / 1000000,  # In MB
            user_data.get("anomaly_score", 0),
            user_data.get("geo_distance", 0) / 10000,  # km
            user_data.get("device_trust", 1.0),
            1 if user_data.get("unusual_time", False) else 0,
            1 if user_data.get("unusual_location", False) else 0,
            user_data.get("privilege_escalations", 0) / 5,
            user_data.get("sensitive_access", 0) / 20
        ]
        
        # Calculate anomaly score
        normal_hours = range(8, 18)  # 8 AM to 6 PM
        time_anomaly = 0.5 if user_data.get("login_hour", 12) not in normal_hours else 0
        
        geo_anomaly = min(1.0, features[6] * 2)  # Distance factor
        
        combined_anomaly = (time_anomaly + geo_anomaly + features[5]) / 3
        
        # Determine category
        if features[4] > 0.5:  # High data transfer
            category = ThreatCategory.DATA_EXFILTRATION
        elif features[10] > 0.4:  # Privilege escalations
            category = ThreatCategory.PRIVILEGE_ESCALATION
        elif combined_anomaly > 0.6:
            category = ThreatCategory.INSIDER_THREAT
        else:
            category = ThreatCategory.INSIDER_THREAT
        
        threat_score = int(combined_anomaly * 100)
        confidence = 0.6 + combined_anomaly * 0.3
        
        prediction_id = f"pred_{hashlib.md5(f'{datetime.now().isoformat()}-user'.encode()).hexdigest()[:12]}"
        
        prediction = ThreatPrediction(
            prediction_id=prediction_id,
            timestamp=datetime.now(timezone.utc).isoformat(),
            entity_type="user",
            entity_id=user_data.get("user_id", user_data.get("username", "unknown")),
            predicted_category=category,
            risk_level=self._determine_risk_level(threat_score),
            confidence=confidence,
            threat_score=threat_score,
            features={
                "time_anomaly": time_anomaly,
                "geo_anomaly": geo_anomaly,
                "combined_anomaly": combined_anomaly,
                "raw_data": user_data
            },
            contributing_factors=[
                f"Unusual login time: {user_data.get('login_hour', 12)}:00" if time_anomaly > 0 else None,
                f"Unusual location: {user_data.get('geo_distance', 0):.0f}km from normal" if geo_anomaly > 0.3 else None,
                f"High data transfer: {user_data.get('data_transferred', 0) / 1000000:.1f}MB" if features[4] > 0.1 else None,
                f"Multiple failed logins: {user_data.get('failed_logins', 0)}" if features[2] > 0.2 else None
            ],
            recommended_actions=[
                "Review user session logs",
                "Verify identity with user",
                "Check accessed resources",
                "Enable MFA if not active"
            ],
            mitre_mappings=[
                {"tactic": "Initial Access", "technique": "T1078", "name": "Valid Accounts"},
                {"tactic": "Collection", "technique": "T1005", "name": "Data from Local System"}
            ]
        )
        
        prediction.contributing_factors = [f for f in prediction.contributing_factors if f]
        
        self.predictions[prediction_id] = prediction
        
        if self._db is not None:
            await self._db.ml_predictions.insert_one(asdict(prediction))
        await self._emit_event(
            "ml_threat_prediction_generated_service",
            entity_refs=[prediction.prediction_id, prediction.entity_id],
            payload={"entity_type": prediction.entity_type, "risk_level": prediction.risk_level.value, "threat_score": prediction.threat_score},
            trigger_triune=prediction.threat_score >= 80,
        )

        return prediction
    
    def get_prediction(self, prediction_id: str) -> Optional[Dict]:
        """Get a specific prediction"""
        pred = self.predictions.get(prediction_id)
        if pred:
            result = asdict(pred)
            result["predicted_category"] = pred.predicted_category.value
            result["risk_level"] = pred.risk_level.value
            return result
        return None
    
    def get_predictions(
        self,
        limit: int = 50,
        entity_type: Optional[str] = None,
        min_score: Optional[int] = None
    ) -> List[Dict]:
        """Get recent predictions from memory cache"""
        preds = list(self.predictions.values())
        
        if entity_type:
            preds = [p for p in preds if p.entity_type == entity_type]
        
        if min_score is not None:
            preds = [p for p in preds if p.threat_score >= min_score]
        
        preds = sorted(preds, key=lambda x: x.timestamp, reverse=True)[:limit]
        
        return [
            {
                "prediction_id": p.prediction_id,
                "timestamp": p.timestamp,
                "entity_type": p.entity_type,
                "entity_id": p.entity_id,
                "category": p.predicted_category.value,
                "risk_level": p.risk_level.value,
                "threat_score": p.threat_score,
                "confidence": round(p.confidence, 2)
            }
            for p in preds
        ]
    
    async def get_predictions_from_db(
        self,
        limit: int = 50,
        entity_type: Optional[str] = None,
        min_score: Optional[int] = None
    ) -> List[Dict]:
        """Get recent predictions from database"""
        if self._db is None:
            return self.get_predictions(limit, entity_type, min_score)
        
        query = {}
        if entity_type:
            query["entity_type"] = entity_type
        if min_score is not None:
            query["threat_score"] = {"$gte": min_score}
        
        preds = await self._db.ml_predictions.find(query, {"_id": 0}).sort("timestamp", -1).to_list(limit)
        
        # Normalize the output format
        result = []
        for p in preds:
            result.append({
                "prediction_id": p.get("prediction_id"),
                "timestamp": p.get("timestamp"),
                "entity_type": p.get("entity_type"),
                "entity_id": p.get("entity_id"),
                "category": p.get("predicted_category", p.get("category")),
                "risk_level": p.get("risk_level"),
                "threat_score": p.get("threat_score"),
                "confidence": round(p.get("confidence", 0), 2),
                "contributing_factors": p.get("contributing_factors", []),
                "recommended_actions": p.get("recommended_actions", []),
                "mitre_mappings": p.get("mitre_mappings", [])
            })
        
        return result
    
    def get_stats(self) -> Dict:
        """Get ML service statistics"""
        preds = list(self.predictions.values())
        
        by_category = defaultdict(int)
        by_risk = defaultdict(int)
        by_type = defaultdict(int)
        
        for p in preds:
            by_category[p.predicted_category.value] += 1
            by_risk[p.risk_level.value] += 1
            by_type[p.entity_type] += 1
        
        avg_score = sum(p.threat_score for p in preds) / len(preds) if preds else 0
        avg_confidence = sum(p.confidence for p in preds) / len(preds) if preds else 0
        
        return {
            "total_predictions": len(preds),
            "model_version": self.model_version,
            "by_category": dict(by_category),
            "by_risk_level": dict(by_risk),
            "by_entity_type": dict(by_type),
            "average_threat_score": round(avg_score, 1),
            "average_confidence": round(avg_confidence, 2),
            "models": {
                "network_anomaly": "IsolationForest (50 trees)",
                "process_anomaly": "IsolationForest (50 trees)",
                "threat_classifier": "Naive Bayes",
                "behavior_model": "Neural Network (12-24-5)"
            },
            "available_categories": [c.value for c in ThreatCategory],
            "available_risk_levels": [r.value for r in RiskLevel]
        }


# ==================== ADVANCED ML COMPONENTS ====================

class LSTMCell:
    """Simple LSTM cell for time-series analysis"""
    
    def __init__(self, input_size: int, hidden_size: int):
        self.input_size = input_size
        self.hidden_size = hidden_size
        
        # Initialize gates with Xavier initialization
        scale = np.sqrt(2.0 / (input_size + hidden_size))
        
        # Forget gate
        self.Wf = np.random.randn(hidden_size, input_size + hidden_size) * scale
        self.bf = np.zeros((hidden_size, 1))
        
        # Input gate
        self.Wi = np.random.randn(hidden_size, input_size + hidden_size) * scale
        self.bi = np.zeros((hidden_size, 1))
        
        # Candidate gate
        self.Wc = np.random.randn(hidden_size, input_size + hidden_size) * scale
        self.bc = np.zeros((hidden_size, 1))
        
        # Output gate
        self.Wo = np.random.randn(hidden_size, input_size + hidden_size) * scale
        self.bo = np.zeros((hidden_size, 1))
    
    def _sigmoid(self, x):
        return 1 / (1 + np.exp(-np.clip(x, -500, 500)))
    
    def _tanh(self, x):
        return np.tanh(x)
    
    def forward(self, x: np.ndarray, h_prev: np.ndarray, c_prev: np.ndarray):
        """Single LSTM forward pass"""
        # Concatenate input and previous hidden state
        concat = np.vstack((h_prev, x.reshape(-1, 1)))
        
        # Gates
        f = self._sigmoid(np.dot(self.Wf, concat) + self.bf)  # Forget
        i = self._sigmoid(np.dot(self.Wi, concat) + self.bi)  # Input
        c_tilde = self._tanh(np.dot(self.Wc, concat) + self.bc)  # Candidate
        o = self._sigmoid(np.dot(self.Wo, concat) + self.bo)  # Output
        
        # Update cell state and hidden state
        c = f * c_prev + i * c_tilde
        h = o * self._tanh(c)
        
        return h, c


class TimeSeriesAnomalyDetector:
    """LSTM-based time-series anomaly detection for event sequences"""
    
    def __init__(self, input_size: int = 12, hidden_size: int = 32, sequence_length: int = 10):
        self.input_size = input_size
        self.hidden_size = hidden_size
        self.sequence_length = sequence_length
        
        self.lstm = LSTMCell(input_size, hidden_size)
        
        # Output layer for reconstruction
        self.W_out = np.random.randn(input_size, hidden_size) * np.sqrt(2.0 / hidden_size)
        self.b_out = np.zeros((input_size, 1))
        
        # Threshold for anomaly (learned from training)
        self.anomaly_threshold = 0.5
        self.reconstruction_errors = []
    
    def _forward_sequence(self, sequence: List[np.ndarray]) -> List[np.ndarray]:
        """Process a sequence and return reconstructions"""
        h = np.zeros((self.hidden_size, 1))
        c = np.zeros((self.hidden_size, 1))
        
        reconstructions = []
        
        for x in sequence:
            h, c = self.lstm.forward(x, h, c)
            # Reconstruct input from hidden state
            reconstruction = np.dot(self.W_out, h) + self.b_out
            reconstructions.append(reconstruction.flatten())
        
        return reconstructions
    
    def fit(self, sequences: List[List[np.ndarray]]):
        """Train on normal sequences to learn reconstruction error threshold"""
        all_errors = []
        
        for sequence in sequences:
            if len(sequence) < 2:
                continue
            
            reconstructions = self._forward_sequence(sequence)
            
            for i, (orig, recon) in enumerate(zip(sequence, reconstructions)):
                error = np.mean(np.square(orig - recon))
                all_errors.append(error)
        
        if all_errors:
            # Set threshold at 95th percentile
            self.anomaly_threshold = np.percentile(all_errors, 95)
            self.reconstruction_errors = all_errors
    
    def detect_anomaly(self, sequence: List[np.ndarray]) -> Dict:
        """Detect anomalies in an event sequence"""
        if len(sequence) < 2:
            return {"is_anomaly": False, "score": 0.0, "anomalous_positions": []}
        
        reconstructions = self._forward_sequence(sequence)
        
        errors = []
        anomalous_positions = []
        
        for i, (orig, recon) in enumerate(zip(sequence, reconstructions)):
            error = np.mean(np.square(orig - recon))
            errors.append(error)
            
            if error > self.anomaly_threshold:
                anomalous_positions.append(i)
        
        avg_error = np.mean(errors)
        max_error = np.max(errors)
        
        # Anomaly score (0-1)
        score = min(1.0, max_error / (self.anomaly_threshold * 2)) if self.anomaly_threshold > 0 else 0
        
        return {
            "is_anomaly": len(anomalous_positions) > 0,
            "score": score,
            "avg_reconstruction_error": avg_error,
            "max_reconstruction_error": max_error,
            "threshold": self.anomaly_threshold,
            "anomalous_positions": anomalous_positions,
            "sequence_length": len(sequence)
        }


class EnsemblePredictor:
    """Ensemble model combining multiple predictors with weighted voting"""
    
    def __init__(self):
        self.model_weights = {
            "isolation_forest": 0.25,
            "neural_network": 0.30,
            "bayesian": 0.20,
            "time_series": 0.25
        }
        self.predictions_history = []
        self.model_performance = {k: {"correct": 0, "total": 0} for k in self.model_weights}
    
    def predict(
        self,
        isolation_score: float,
        nn_prediction: Tuple[int, float],
        bayesian_prediction: Tuple[str, float],
        time_series_score: float,
        categories: List[ThreatCategory]
    ) -> Tuple[ThreatCategory, float, Dict]:
        """Ensemble prediction with weighted voting"""
        
        # Normalize scores to 0-1
        scores = {
            "isolation_forest": isolation_score,
            "neural_network": nn_prediction[1],
            "bayesian": bayesian_prediction[1],
            "time_series": time_series_score
        }
        
        # Weighted ensemble score
        ensemble_score = sum(
            scores[model] * weight 
            for model, weight in self.model_weights.items()
        )
        
        # Category voting
        category_votes = defaultdict(float)
        
        # Neural network vote
        if nn_prediction[0] < len(categories):
            category_votes[categories[nn_prediction[0]]] += self.model_weights["neural_network"] * nn_prediction[1]
        
        # Bayesian vote
        category_votes[self._coerce_threat_category(bayesian_prediction[0])] += (
            self.model_weights["bayesian"] * bayesian_prediction[1]
        )
        
        # Anomaly-based votes contribute to malware category
        anomaly_contribution = (isolation_score + time_series_score) / 2
        if anomaly_contribution > 0.5:
            category_votes[ThreatCategory.MALWARE] += anomaly_contribution * 0.3
        
        # Select winner
        if category_votes:
            winner = max(category_votes.items(), key=lambda x: x[1])
            predicted_category = winner[0]
            category_confidence = winner[1]
        else:
            predicted_category = ThreatCategory.MALWARE
            category_confidence = ensemble_score
        
        # Calculate final confidence
        confidence = min(1.0, (ensemble_score + category_confidence) / 2)
        
        # Model contribution breakdown
        contributions = {
            model: scores[model] * weight / (ensemble_score + 0.0001)
            for model, weight in self.model_weights.items()
        }
        
        metadata = {
            "individual_scores": scores,
            "model_weights": self.model_weights,
            "contributions": contributions,
            "ensemble_score": ensemble_score,
            "category_votes": {k.value: v for k, v in category_votes.items()}
        }
        
        return predicted_category, confidence, metadata
    
    def update_weights(self, model: str, correct: bool):
        """Update model weights based on prediction feedback"""
        if model in self.model_performance:
            self.model_performance[model]["total"] += 1
            if correct:
                self.model_performance[model]["correct"] += 1
        
        # Recalculate weights based on accuracy
        total_accuracy = 0
        accuracies = {}
        
        for m, perf in self.model_performance.items():
            if perf["total"] > 0:
                acc = perf["correct"] / perf["total"]
            else:
                acc = 0.5  # Default
            accuracies[m] = acc
            total_accuracy += acc
        
        if total_accuracy > 0:
            self.model_weights = {
                m: max(0.1, acc / total_accuracy)
                for m, acc in accuracies.items()
            }


class UserBehaviorAnalyzer:
    """Advanced User Entity Behavior Analytics (UEBA)"""
    
    def __init__(self):
        # User baselines
        self.user_baselines: Dict[str, Dict] = {}
        
        # Peer groups
        self.peer_groups: Dict[str, List[str]] = {}
        
        # Session tracking
        self.active_sessions: Dict[str, List[Dict]] = {}
        
        # Risk scores
        self.user_risk_scores: Dict[str, float] = {}
        
        # Behavior history
        self.behavior_history: Dict[str, List[Dict]] = {}
    
    def create_baseline(self, user_id: str, historical_data: List[Dict]) -> Dict:
        """Create behavioral baseline from historical data"""
        if not historical_data:
            return self._default_baseline()
        
        # Calculate baseline metrics
        login_hours = [d.get("login_hour", 12) for d in historical_data]
        login_days = [d.get("login_day", 3) for d in historical_data]
        resources = [d.get("resources_accessed", 10) for d in historical_data]
        data_transferred = [d.get("data_transferred", 0) for d in historical_data]
        locations = [d.get("location", "unknown") for d in historical_data]
        devices = [d.get("device_id", "unknown") for d in historical_data]
        
        baseline = {
            "user_id": user_id,
            "created_at": datetime.now(timezone.utc).isoformat(),
            "sample_count": len(historical_data),
            
            # Time patterns
            "typical_login_hours": {
                "mean": np.mean(login_hours),
                "std": np.std(login_hours),
                "min": min(login_hours),
                "max": max(login_hours)
            },
            "typical_login_days": list(set(login_days)),
            
            # Resource access patterns
            "avg_resources_accessed": np.mean(resources),
            "max_resources_accessed": max(resources),
            "std_resources_accessed": np.std(resources),
            
            # Data transfer patterns
            "avg_data_transferred": np.mean(data_transferred),
            "max_data_transferred": max(data_transferred),
            "std_data_transferred": np.std(data_transferred),
            
            # Location/device patterns
            "known_locations": list(set(locations)),
            "known_devices": list(set(devices)),
            
            # Derived thresholds (2 standard deviations)
            "thresholds": {
                "login_hour_deviation": max(2, np.std(login_hours) * 2),
                "resource_access_threshold": np.mean(resources) + np.std(resources) * 2,
                "data_transfer_threshold": np.mean(data_transferred) + np.std(data_transferred) * 2
            }
        }
        
        self.user_baselines[user_id] = baseline
        return baseline
    
    def _default_baseline(self) -> Dict:
        """Default baseline for new users"""
        return {
            "typical_login_hours": {"mean": 12, "std": 4, "min": 8, "max": 18},
            "typical_login_days": [0, 1, 2, 3, 4],  # Weekdays
            "avg_resources_accessed": 20,
            "max_resources_accessed": 50,
            "avg_data_transferred": 100000,  # 100KB
            "max_data_transferred": 10000000,  # 10MB
            "known_locations": [],
            "known_devices": [],
            "thresholds": {
                "login_hour_deviation": 4,
                "resource_access_threshold": 50,
                "data_transfer_threshold": 10000000
            }
        }
    
    def assign_peer_group(self, user_id: str, group_name: str):
        """Assign user to a peer group"""
        if group_name not in self.peer_groups:
            self.peer_groups[group_name] = []
        
        if user_id not in self.peer_groups[group_name]:
            self.peer_groups[group_name].append(user_id)
    
    def get_peer_group_baseline(self, group_name: str) -> Dict:
        """Get aggregated baseline for a peer group"""
        if group_name not in self.peer_groups:
            return self._default_baseline()
        
        members = self.peer_groups[group_name]
        member_baselines = [
            self.user_baselines.get(m, self._default_baseline())
            for m in members
        ]
        
        if not member_baselines:
            return self._default_baseline()
        
        # Aggregate baselines
        return {
            "group_name": group_name,
            "member_count": len(members),
            "avg_resources_accessed": np.mean([b.get("avg_resources_accessed", 20) for b in member_baselines]),
            "avg_data_transferred": np.mean([b.get("avg_data_transferred", 100000) for b in member_baselines]),
            "typical_login_hours": {
                "mean": np.mean([b.get("typical_login_hours", {}).get("mean", 12) for b in member_baselines]),
                "std": np.mean([b.get("typical_login_hours", {}).get("std", 4) for b in member_baselines])
            }
        }
    
    def analyze_session(self, user_id: str, session_data: Dict) -> Dict:
        """Analyze a user session against baseline"""
        baseline = self.user_baselines.get(user_id, self._default_baseline())
        thresholds = baseline.get("thresholds", self._default_baseline()["thresholds"])
        
        anomalies = []
        risk_score = 0.0
        
        # Time analysis
        login_hour = session_data.get("login_hour", 12)
        hour_mean = baseline.get("typical_login_hours", {}).get("mean", 12)
        hour_deviation = abs(login_hour - hour_mean)
        
        if hour_deviation > thresholds["login_hour_deviation"]:
            anomalies.append({
                "type": "unusual_time",
                "description": f"Login at {login_hour}:00 deviates from typical {hour_mean:.0f}:00",
                "severity": "medium" if hour_deviation < 6 else "high",
                "contribution": 0.2
            })
            risk_score += 0.2
        
        # Day analysis
        login_day = session_data.get("login_day", 3)
        typical_days = baseline.get("typical_login_days", [0, 1, 2, 3, 4])
        
        if login_day not in typical_days:
            anomalies.append({
                "type": "unusual_day",
                "description": f"Login on day {login_day} (unusual)",
                "severity": "low",
                "contribution": 0.1
            })
            risk_score += 0.1
        
        # Resource access analysis
        resources = session_data.get("resources_accessed", 0)
        if resources > thresholds["resource_access_threshold"]:
            anomalies.append({
                "type": "excessive_access",
                "description": f"Accessed {resources} resources (threshold: {thresholds['resource_access_threshold']:.0f})",
                "severity": "high",
                "contribution": 0.3
            })
            risk_score += 0.3
        
        # Data transfer analysis
        data_transferred = session_data.get("data_transferred", 0)
        if data_transferred > thresholds["data_transfer_threshold"]:
            anomalies.append({
                "type": "excessive_transfer",
                "description": f"Transferred {data_transferred / 1000000:.1f}MB (threshold: {thresholds['data_transfer_threshold'] / 1000000:.1f}MB)",
                "severity": "critical",
                "contribution": 0.4
            })
            risk_score += 0.4
        
        # Location analysis
        location = session_data.get("location", "unknown")
        known_locations = baseline.get("known_locations", [])
        
        if location != "unknown" and known_locations and location not in known_locations:
            anomalies.append({
                "type": "unknown_location",
                "description": f"Login from unknown location: {location}",
                "severity": "high",
                "contribution": 0.25
            })
            risk_score += 0.25
        
        # Device analysis
        device = session_data.get("device_id", "unknown")
        known_devices = baseline.get("known_devices", [])
        
        if device != "unknown" and known_devices and device not in known_devices:
            anomalies.append({
                "type": "unknown_device",
                "description": f"Login from unknown device: {device}",
                "severity": "medium",
                "contribution": 0.15
            })
            risk_score += 0.15
        
        # Store session for tracking
        if user_id not in self.active_sessions:
            self.active_sessions[user_id] = []
        self.active_sessions[user_id].append({
            "timestamp": datetime.now(timezone.utc).isoformat(),
            "data": session_data,
            "anomalies": len(anomalies),
            "risk_score": risk_score
        })
        
        # Keep only last 100 sessions
        self.active_sessions[user_id] = self.active_sessions[user_id][-100:]
        
        # Update user risk score (exponential moving average)
        prev_risk = self.user_risk_scores.get(user_id, 0.0)
        self.user_risk_scores[user_id] = prev_risk * 0.7 + risk_score * 0.3
        
        return {
            "user_id": user_id,
            "session_risk_score": min(1.0, risk_score),
            "cumulative_risk_score": self.user_risk_scores[user_id],
            "anomaly_count": len(anomalies),
            "anomalies": anomalies,
            "baseline_comparison": {
                "login_hour_deviation": hour_deviation,
                "resources_ratio": resources / (baseline.get("avg_resources_accessed", 20) + 0.001),
                "data_ratio": data_transferred / (baseline.get("avg_data_transferred", 100000) + 0.001)
            },
            "recommendation": self._get_recommendation(risk_score, anomalies)
        }
    
    def _get_recommendation(self, risk_score: float, anomalies: List[Dict]) -> str:
        """Get recommendation based on analysis"""
        if risk_score >= 0.7:
            return "CRITICAL: Immediately investigate and consider session termination"
        elif risk_score >= 0.5:
            return "HIGH: Require additional authentication and monitor closely"
        elif risk_score >= 0.3:
            return "MEDIUM: Flag for review and enable enhanced logging"
        elif risk_score > 0:
            return "LOW: Minor deviations detected, continue monitoring"
        else:
            return "NORMAL: No anomalies detected"
    
    def compare_to_peer_group(self, user_id: str, session_data: Dict, group_name: str) -> Dict:
        """Compare user behavior to peer group"""
        peer_baseline = self.get_peer_group_baseline(group_name)
        user_baseline = self.user_baselines.get(user_id, self._default_baseline())
        
        # Calculate deviations from peer group
        resources = session_data.get("resources_accessed", 0)
        data = session_data.get("data_transferred", 0)
        
        peer_resource_avg = peer_baseline.get("avg_resources_accessed", 20)
        peer_data_avg = peer_baseline.get("avg_data_transferred", 100000)
        
        return {
            "user_id": user_id,
            "peer_group": group_name,
            "deviations": {
                "resources_vs_peer": (resources - peer_resource_avg) / (peer_resource_avg + 0.001),
                "data_vs_peer": (data - peer_data_avg) / (peer_data_avg + 0.001)
            },
            "is_outlier": resources > peer_resource_avg * 3 or data > peer_data_avg * 3,
            "peer_group_baseline": peer_baseline
        }


class ModelPersistence:
    """Save and load trained ML models"""
    
    def __init__(self, storage_path: str = "/tmp/ml_models"):
        self.storage_path = storage_path
        os.makedirs(storage_path, exist_ok=True)
    
    def save_model(self, model_name: str, model_data: Dict) -> str:
        """Save model parameters to file"""
        filepath = os.path.join(self.storage_path, f"{model_name}.json")
        
        # Convert numpy arrays to lists for JSON serialization
        serializable_data = self._make_serializable(model_data)
        
        with open(filepath, 'w') as f:
            json.dump({
                "model_name": model_name,
                "saved_at": datetime.now(timezone.utc).isoformat(),
                "data": serializable_data
            }, f, indent=2)
        
        return filepath
    
    def load_model(self, model_name: str) -> Optional[Dict]:
        """Load model parameters from file"""
        filepath = os.path.join(self.storage_path, f"{model_name}.json")
        
        if not os.path.exists(filepath):
            return None
        
        with open(filepath, 'r') as f:
            saved = json.load(f)
        
        return self._restore_arrays(saved.get("data", {}))
    
    def _make_serializable(self, obj):
        """Convert numpy arrays to lists"""
        if isinstance(obj, np.ndarray):
            return {"__numpy__": True, "data": obj.tolist(), "dtype": str(obj.dtype)}
        elif isinstance(obj, dict):
            return {k: self._make_serializable(v) for k, v in obj.items()}
        elif isinstance(obj, list):
            return [self._make_serializable(item) for item in obj]
        else:
            return obj
    
    def _restore_arrays(self, obj):
        """Restore numpy arrays from lists"""
        if isinstance(obj, dict):
            if obj.get("__numpy__"):
                return np.array(obj["data"], dtype=obj.get("dtype", "float64"))
            return {k: self._restore_arrays(v) for k, v in obj.items()}
        elif isinstance(obj, list):
            return [self._restore_arrays(item) for item in obj]
        else:
            return obj
    
    def list_models(self) -> List[Dict]:
        """List all saved models"""
        models = []
        
        for filename in os.listdir(self.storage_path):
            if filename.endswith(".json"):
                filepath = os.path.join(self.storage_path, filename)
                with open(filepath, 'r') as f:
                    data = json.load(f)
                models.append({
                    "name": data.get("model_name"),
                    "saved_at": data.get("saved_at"),
                    "path": filepath
                })
        
        return models


class PredictionExplainer:
    """SHAP-like explainability for ML predictions"""
    
    def __init__(self, feature_names: List[str]):
        self.feature_names = feature_names
        self.baseline_values: Optional[np.ndarray] = None
    
    def set_baseline(self, baseline_features: List[float]):
        """Set baseline (expected) feature values"""
        self.baseline_values = np.array(baseline_features)
    
    def explain_prediction(
        self,
        features: List[float],
        prediction_score: float,
        model_predict_fn: callable = None
    ) -> Dict:
        """Explain which features contributed most to the prediction"""
        features_arr = np.array(features)
        
        if self.baseline_values is None:
            self.baseline_values = np.zeros(len(features))
        
        # Calculate feature contributions (simplified SHAP-like approach)
        contributions = {}
        total_deviation = 0
        
        for i, (name, feat_val, baseline_val) in enumerate(
            zip(self.feature_names, features, self.baseline_values)
        ):
            deviation = feat_val - baseline_val
            
            # Normalize contribution based on feature importance
            # Higher deviations = higher contributions
            contribution = deviation / (abs(baseline_val) + 0.001)
            contributions[name] = {
                "value": float(feat_val),
                "baseline": float(baseline_val),
                "deviation": float(deviation),
                "contribution": float(contribution),
                "direction": "increase" if deviation > 0 else "decrease"
            }
            total_deviation += abs(contribution)
        
        # Normalize to get percentage contributions
        if total_deviation > 0:
            for name in contributions:
                contributions[name]["importance"] = abs(contributions[name]["contribution"]) / total_deviation
        
        # Sort by importance
        sorted_contributions = sorted(
            contributions.items(),
            key=lambda x: abs(x[1]["contribution"]),
            reverse=True
        )
        
        # Top contributing features
        top_features = [
            {
                "feature": name,
                "importance": data["importance"],
                "value": data["value"],
                "direction": data["direction"],
                "explanation": f"{name} {'increased' if data['direction'] == 'increase' else 'decreased'} risk score"
            }
            for name, data in sorted_contributions[:5]
        ]
        
        return {
            "prediction_score": prediction_score,
            "feature_count": len(features),
            "top_features": top_features,
            "all_contributions": contributions,
            "explanation_summary": self._generate_summary(top_features, prediction_score)
        }
    
    def _generate_summary(self, top_features: List[Dict], score: float) -> str:
        """Generate human-readable explanation summary"""
        if score < 0.3:
            risk_level = "low"
        elif score < 0.6:
            risk_level = "moderate"
        else:
            risk_level = "high"
        
        summary_parts = [f"This prediction indicates {risk_level} risk (score: {score:.2f})."]
        
        if top_features:
            main_factor = top_features[0]
            summary_parts.append(
                f"The primary contributing factor is {main_factor['feature']} "
                f"(value: {main_factor['value']:.2f}), which {main_factor['direction']}d the risk."
            )
        
        if len(top_features) > 1:
            other_factors = ", ".join([f["feature"] for f in top_features[1:3]])
            summary_parts.append(f"Other significant factors: {other_factors}.")
        
        return " ".join(summary_parts)


class FeedbackLoop:
    """Analyst feedback loop for model improvement"""
    
    def __init__(self):
        self.feedback_history: List[Dict] = []
        self.model_adjustments: Dict[str, List[float]] = defaultdict(list)
    
    def record_feedback(
        self,
        prediction_id: str,
        analyst_decision: str,  # "true_positive", "false_positive", "true_negative", "false_negative"
        actual_category: Optional[str] = None,
        notes: Optional[str] = None
    ) -> Dict:
        """Record analyst feedback on a prediction"""
        feedback = {
            "prediction_id": prediction_id,
            "timestamp": datetime.now(timezone.utc).isoformat(),
            "analyst_decision": analyst_decision,
            "actual_category": actual_category,
            "notes": notes,
            "is_correct": analyst_decision in ["true_positive", "true_negative"]
        }
        
        self.feedback_history.append(feedback)
        
        return {
            "recorded": True,
            "feedback_id": len(self.feedback_history),
            "total_feedback": len(self.feedback_history),
            "accuracy": self._calculate_accuracy()
        }
    
    def _calculate_accuracy(self) -> float:
        """Calculate model accuracy from feedback"""
        if not self.feedback_history:
            return 0.0
        
        correct = sum(1 for f in self.feedback_history if f["is_correct"])
        return correct / len(self.feedback_history)
    
    def get_feedback_stats(self) -> Dict:
        """Get feedback statistics"""
        total = len(self.feedback_history)
        
        if total == 0:
            return {"total": 0, "accuracy": 0.0}
        
        by_decision = defaultdict(int)
        for f in self.feedback_history:
            by_decision[f["analyst_decision"]] += 1
        
        return {
            "total": total,
            "accuracy": self._calculate_accuracy(),
            "by_decision": dict(by_decision),
            "true_positive_rate": by_decision["true_positive"] / (by_decision["true_positive"] + by_decision["false_negative"] + 0.001),
            "false_positive_rate": by_decision["false_positive"] / (by_decision["false_positive"] + by_decision["true_negative"] + 0.001),
            "recent_trend": self._get_recent_trend()
        }
    
    def _get_recent_trend(self, window: int = 20) -> str:
        """Calculate accuracy trend from recent feedback"""
        if len(self.feedback_history) < window:
            return "insufficient_data"
        
        recent = self.feedback_history[-window:]
        older = self.feedback_history[-window*2:-window] if len(self.feedback_history) >= window*2 else []
        
        recent_acc = sum(1 for f in recent if f["is_correct"]) / len(recent)
        
        if older:
            older_acc = sum(1 for f in older if f["is_correct"]) / len(older)
            if recent_acc > older_acc + 0.05:
                return "improving"
            elif recent_acc < older_acc - 0.05:
                return "declining"
        
        return "stable"
    
    def suggest_model_updates(self) -> List[Dict]:
        """Suggest model updates based on feedback patterns"""
        suggestions = []
        
        stats = self.get_feedback_stats()
        
        if stats["false_positive_rate"] > 0.3:
            suggestions.append({
                "type": "threshold_adjustment",
                "description": "High false positive rate - consider increasing detection threshold",
                "priority": "high"
            })
        
        if stats["true_positive_rate"] < 0.7:
            suggestions.append({
                "type": "model_retraining",
                "description": "Low true positive rate - consider retraining with recent samples",
                "priority": "high"
            })
        
        if stats["total"] > 100 and stats.get("recent_trend") == "declining":
            suggestions.append({
                "type": "drift_detection",
                "description": "Model performance declining - possible concept drift detected",
                "priority": "medium"
            })
        
        return suggestions


# ==================== ENHANCED ML THREAT PREDICTOR ====================

class EnhancedMLThreatPredictor(MLThreatPredictor):
    """Enhanced ML Threat Predictor with advanced features"""
    
    def __init__(self, db=None):
        super().__init__()
        if db is not None:
            self.set_database(db)
        
        # Advanced components
        self.time_series_detector = TimeSeriesAnomalyDetector(input_size=12, hidden_size=32)
        self.ensemble = EnsemblePredictor()
        self.ueba = UserBehaviorAnalyzer()
        self.persistence = ModelPersistence()
        self.feedback = FeedbackLoop()
        
        # Explainers for different prediction types
        self.network_explainer = PredictionExplainer([
            "bytes_in", "bytes_out", "packets_in", "packets_out", "destinations",
            "ports", "dns_queries", "failed_conn", "encrypted_ratio", "packet_size",
            "duration", "port_scan"
        ])
        
        self.process_explainer = PredictionExplainer([
            "cpu", "memory", "file_ops", "reg_ops", "net_conn", "children",
            "dlls", "sus_api", "entropy", "exec_time"
        ])
        
        # Event sequence buffers for time-series analysis
        self.event_sequences: Dict[str, List[np.ndarray]] = defaultdict(list)
        
        self.model_version = "2.0.0-enhanced"
    
    async def predict_with_ensemble(
        self,
        entity_type: str,
        data: Dict,
        include_explanation: bool = True
    ) -> Dict:
        """Unified prediction using ensemble of all models"""
        
        # Extract features based on entity type
        if entity_type == "network":
            features = self._extract_network_features(data)
            explainer = self.network_explainer
        elif entity_type == "process":
            features = self._extract_process_features(data)
            explainer = self.process_explainer
        else:
            # Generic features
            features = [data.get(f"f{i}", 0) for i in range(12)]
            explainer = self.network_explainer
        
        # Get individual model predictions
        isolation_score = self.network_anomaly_detector.score(features) if entity_type == "network" else self.process_anomaly_detector.score(features)
        
        nn_prediction = self.behavior_model.predict(features + [isolation_score, isolation_score])
        bayesian_prediction = self.threat_classifier.predict(features)
        
        # Time-series score
        entity_id = data.get("entity_id", data.get("source_ip", data.get("process_name", "unknown")))
        self.event_sequences[entity_id].append(np.array(features))
        self.event_sequences[entity_id] = self.event_sequences[entity_id][-20:]  # Keep last 20
        
        ts_result = self.time_series_detector.detect_anomaly(self.event_sequences[entity_id])
        ts_score = ts_result["score"]
        
        # Ensemble prediction
        categories = list(ThreatCategory)
        predicted_category, confidence, ensemble_meta = self.ensemble.predict(
            isolation_score,
            nn_prediction,
            bayesian_prediction,
            ts_score,
            categories
        )
        
        # Calculate threat score
        threat_score = int(confidence * 100)
        risk_level = self._determine_risk_level(threat_score)
        
        # Generate prediction
        prediction_id = f"ens_{hashlib.md5(f'{datetime.now().isoformat()}-{entity_type}'.encode()).hexdigest()[:12]}"
        
        result = {
            "prediction_id": prediction_id,
            "timestamp": datetime.now(timezone.utc).isoformat(),
            "entity_type": entity_type,
            "entity_id": entity_id,
            "predicted_category": predicted_category.value,
            "risk_level": risk_level.value,
            "confidence": round(confidence, 3),
            "threat_score": threat_score,
            "ensemble_metadata": ensemble_meta,
            "time_series_analysis": ts_result,
            "recommended_actions": self._get_recommended_actions(predicted_category, risk_level),
            "mitre_mappings": self._get_mitre_mappings(predicted_category)
        }
        
        # Add explanation if requested
        if include_explanation:
            result["explanation"] = explainer.explain_prediction(features, confidence)
        
        return result
    
    async def analyze_user_session(self, user_id: str, session_data: Dict, peer_group: Optional[str] = None) -> Dict:
        """Advanced UEBA session analysis"""
        
        # Basic session analysis
        session_analysis = self.ueba.analyze_session(user_id, session_data)
        
        # Peer group comparison if provided
        peer_comparison = None
        if peer_group:
            peer_comparison = self.ueba.compare_to_peer_group(user_id, session_data, peer_group)
        
        # Also run standard user threat prediction
        user_prediction = await self.predict_user_threat(session_data | {"user_id": user_id})
        
        return {
            "user_id": user_id,
            "session_analysis": session_analysis,
            "peer_comparison": peer_comparison,
            "threat_prediction": {
                "category": user_prediction.predicted_category.value,
                "risk_level": user_prediction.risk_level.value,
                "threat_score": user_prediction.threat_score,
                "confidence": user_prediction.confidence
            },
            "combined_risk_score": (session_analysis["session_risk_score"] + user_prediction.threat_score / 100) / 2,
            "recommended_actions": user_prediction.recommended_actions
        }
    
    def create_user_baseline(self, user_id: str, historical_data: List[Dict]) -> Dict:
        """Create UEBA baseline for a user"""
        return self.ueba.create_baseline(user_id, historical_data)
    
    def assign_user_to_peer_group(self, user_id: str, group_name: str):
        """Assign user to peer group for comparative analysis"""
        self.ueba.assign_peer_group(user_id, group_name)
    
    def record_analyst_feedback(
        self,
        prediction_id: str,
        decision: str,
        actual_category: Optional[str] = None,
        notes: Optional[str] = None
    ) -> Dict:
        """Record analyst feedback for model improvement"""
        result = self.feedback.record_feedback(prediction_id, decision, actual_category, notes)
        
        # Update ensemble weights if we have the original prediction
        if decision in ["true_positive", "true_negative"]:
            self.ensemble.update_weights("neural_network", True)
            self.ensemble.update_weights("bayesian", True)
        else:
            self.ensemble.update_weights("neural_network", False)
            self.ensemble.update_weights("bayesian", False)
        
        return result
    
    def save_models(self) -> Dict:
        """Save all trained models to disk"""
        saved = {}
        
        # Save isolation forest parameters
        saved["network_anomaly"] = self.persistence.save_model("network_anomaly", {
            "trees": len(self.network_anomaly_detector.trees),
            "sample_size": self.network_anomaly_detector.sample_size
        })
        
        saved["process_anomaly"] = self.persistence.save_model("process_anomaly", {
            "trees": len(self.process_anomaly_detector.trees),
            "sample_size": self.process_anomaly_detector.sample_size
        })
        
        # Save neural network weights
        saved["behavior_model"] = self.persistence.save_model("behavior_model", {
            "W1": self.behavior_model.W1,
            "b1": self.behavior_model.b1,
            "W2": self.behavior_model.W2,
            "b2": self.behavior_model.b2
        })
        
        # Save ensemble weights
        saved["ensemble"] = self.persistence.save_model("ensemble", {
            "weights": self.ensemble.model_weights,
            "performance": self.ensemble.model_performance
        })
        
        # Save UEBA baselines
        saved["ueba"] = self.persistence.save_model("ueba", {
            "baselines": self.ueba.user_baselines,
            "peer_groups": self.ueba.peer_groups,
            "risk_scores": self.ueba.user_risk_scores
        })
        
        return saved
    
    def load_models(self) -> Dict:
        """Load trained models from disk"""
        loaded = {}
        
        # Load neural network
        nn_data = self.persistence.load_model("behavior_model")
        if nn_data:
            self.behavior_model.W1 = nn_data.get("W1", self.behavior_model.W1)
            self.behavior_model.b1 = nn_data.get("b1", self.behavior_model.b1)
            self.behavior_model.W2 = nn_data.get("W2", self.behavior_model.W2)
            self.behavior_model.b2 = nn_data.get("b2", self.behavior_model.b2)
            loaded["behavior_model"] = True
        
        # Load ensemble
        ensemble_data = self.persistence.load_model("ensemble")
        if ensemble_data:
            self.ensemble.model_weights = ensemble_data.get("weights", self.ensemble.model_weights)
            self.ensemble.model_performance = ensemble_data.get("performance", self.ensemble.model_performance)
            loaded["ensemble"] = True
        
        # Load UEBA
        ueba_data = self.persistence.load_model("ueba")
        if ueba_data:
            self.ueba.user_baselines = ueba_data.get("baselines", {})
            self.ueba.peer_groups = ueba_data.get("peer_groups", {})
            self.ueba.user_risk_scores = ueba_data.get("risk_scores", {})
            loaded["ueba"] = True
        
        return loaded
    
    def get_enhanced_stats(self) -> Dict:
        """Get comprehensive ML service statistics"""
        base_stats = self.get_stats()
        
        return {
            **base_stats,
            "model_version": self.model_version,
            "enhanced_models": {
                "time_series_detector": {
                    "type": "LSTM-based",
                    "input_size": self.time_series_detector.input_size,
                    "hidden_size": self.time_series_detector.hidden_size,
                    "sequence_length": self.time_series_detector.sequence_length
                },
                "ensemble_predictor": {
                    "model_weights": self.ensemble.model_weights,
                    "model_performance": self.ensemble.model_performance
                },
                "ueba": {
                    "tracked_users": len(self.ueba.user_baselines),
                    "peer_groups": list(self.ueba.peer_groups.keys()),
                    "active_sessions": len(self.ueba.active_sessions)
                },
                "feedback_loop": self.feedback.get_feedback_stats()
            },
            "saved_models": self.persistence.list_models(),
            "model_improvement_suggestions": self.feedback.suggest_model_updates()
        }


# Global instances
ml_predictor = MLThreatPredictor()
enhanced_ml_predictor = EnhancedMLThreatPredictor()

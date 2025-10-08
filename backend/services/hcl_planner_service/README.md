# HCL Planner Service

**The Decision-Making Brain** - Combines Fuzzy Logic and Reinforcement Learning for optimal resource allocation.

## Features

- ✅ **Fuzzy Logic Controller:** Fast operational mode decisions (ENERGY_EFFICIENT, BALANCED, HIGH_PERFORMANCE)
- ✅ **Soft Actor-Critic (SAC):** Optimal resource allocation via deep RL
- ✅ **Dual-system thinking:** Fast fuzzy decisions + slow RL optimization
- ✅ **Kafka streaming:** Consumes predictions, publishes actions
- ✅ **Custom Kubernetes environment:** Realistic cluster simulation
- ✅ **Zero mocks:** Real scikit-fuzzy, Stable-Baselines3, Gymnasium

## Architecture

```
                    ┌─────────────────────────────┐
                    │ Kafka: system.predictions   │
                    └──────────────┬──────────────┘
                                   │
                                   ▼
┌──────────────────────────────────────────────────────────┐
│              HCL Planner Service (Port 8003)             │
│                                                           │
│  ┌─────────────────────────────────────────────────┐    │
│  │           Kafka Consumer Loop                    │    │
│  └──────────────────────┬──────────────────────────┘    │
│                         │                                │
│                         ▼                                │
│  ┌─────────────────────────────────────────────────┐    │
│  │         Planning Engine                          │    │
│  │                                                   │    │
│  │  ┌─────────────────┐   ┌───────────────────┐   │    │
│  │  │ Fuzzy Logic     │   │  RL Agent (SAC)   │   │    │
│  │  │ Controller      │   │                   │   │    │
│  │  │ • 4 inputs      │   │  • 9D state       │   │    │
│  │  │ • 10 rules      │   │  • 4D action      │   │    │
│  │  │ • ~1ms latency  │   │  • ~50ms latency  │   │    │
│  │  └────────┬────────┘   └────────┬──────────┘   │    │
│  │           │                     │              │    │
│  │           └──────────┬──────────┘              │    │
│  │                      ▼                          │    │
│  │           ┌─────────────────────┐              │    │
│  │           │  Action Plan Builder │              │    │
│  │           └──────────┬───────────┘              │    │
│  └──────────────────────┼──────────────────────────┘    │
│                         │                                │
└─────────────────────────┼────────────────────────────────┘
                          │
          ┌───────────────┴────────────────┐
          │                                │
          ▼                                ▼
┌──────────────────────┐      ┌──────────────────────┐
│ Kafka: system.actions│      │  Knowledge Base API  │
└──────────────────────┘      └──────────────────────┘
```

## Decision Flow

### Phase 1: Fuzzy Logic (Fast Path - ~1ms)

**Input:** Current metrics (CPU, Memory, Error Rate, Latency)

**Process:**
1. Fuzzification: Map crisp values to fuzzy sets (low, medium, high)
2. Rule evaluation: Apply 10 fuzzy rules
3. Defuzzification: Compute mode score (0-100)

**Output:** Operational mode + confidence

**Modes:**
- `ENERGY_EFFICIENT` (score 0-33): Minimize cost, acceptable latency
- `BALANCED` (score 34-66): Balance performance and cost
- `HIGH_PERFORMANCE` (score 67-100): Maximize performance, ignore cost

**Example Rules:**
```
IF cpu_high OR memory_high THEN high_performance
IF error_rate_high THEN high_performance
IF cpu_low AND memory_low AND error_low THEN energy_efficient
```

### Phase 2: RL Agent (Slow Path - ~50ms)

**Input:** 9D state vector:
```python
[cpu_usage, memory_usage, gpu_usage, queue_depth,
 error_rate, latency, maximus_replicas, threat_replicas, malware_replicas]
```

**Process:**
1. Load pre-trained SAC model
2. Forward pass through neural network
3. Apply mode-specific adjustments:
   - `HIGH_PERFORMANCE`: Force scale-up, resource_mult >= 1.0
   - `ENERGY_EFFICIENT`: Force scale-down, resource_mult <= 1.0
   - `BALANCED`: Use raw RL output

**Output:** 4D action vector:
```python
[maximus_delta, threat_intel_delta, malware_delta, resource_mult]
```

**Action space:**
- Replica deltas: -3 to +3 (scale services up/down)
- Resource multiplier: 0.5 to 2.0 (adjust CPU/memory limits)

### Phase 3: Action Plan Generation

**Actions:**
```json
[
  {
    "type": "scale_service",
    "service": "maximus_core",
    "current_replicas": 3,
    "target_replicas": 5,
    "delta": 2
  },
  {
    "type": "adjust_resources",
    "multiplier": 1.3,
    "cpu_limit": "1300m",
    "memory_limit": "2662Mi"
  }
]
```

**Expected impact:**
- Estimated cost change: +$4.00/hour
- Estimated latency change: -20ms
- Confidence: 0.87

## Quick Start

### Local Development

```bash
# Install dependencies
pip install -r requirements.txt

# Set environment
cp .env.example .env

# Run
python main.py
```

Service runs on **port 8003**

### Docker

```bash
docker build -t hcl-planner .
docker run -p 8003:8003 \
  -e KB_API_URL=http://hcl-kb-service:8000 \
  -e KAFKA_BROKERS=kafka:9092 \
  -v $(pwd)/models:/app/models \
  hcl-planner
```

## API Endpoints

### GET /health

Health check with component status

```bash
curl http://localhost:8003/health
```

Response:
```json
{
  "status": "healthy",
  "service": "hcl_planner",
  "current_mode": "BALANCED",
  "rl_agent_loaded": true,
  "kafka_connected": true,
  "decisions_count": 147
}
```

### POST /decide

Make decision based on current state

```bash
curl -X POST http://localhost:8003/decide \
  -H "Content-Type: application/json" \
  -d '{
    "state": {
      "timestamp": "2025-10-03T10:30:00Z",
      "cpu_usage": 85.5,
      "memory_usage": 78.2,
      "gpu_usage": 45.0,
      "queue_depth": 350,
      "error_rate": 12.5,
      "latency": 450.0,
      "replicas": {
        "maximus_core": 3,
        "threat_intel": 2,
        "malware": 2
      }
    }
  }'
```

Response:
```json
{
  "decision_id": "decision_1727952600.123",
  "operational_mode": "HIGH_PERFORMANCE",
  "confidence": 0.89,
  "actions": [
    {
      "type": "scale_service",
      "service": "maximus_core",
      "current_replicas": 3,
      "target_replicas": 5,
      "delta": 2
    }
  ],
  "method": "fuzzy+rl",
  "details": {
    "fuzzy": {
      "cpu_usage": 85.5,
      "fuzzy_score": 87.3,
      "confidence": 0.89
    },
    "rl_action": [2, 1, 0, 1.3],
    "expected_impact": {
      "estimated_cost_change": 4.0,
      "estimated_latency_change": -20.0
    }
  }
}
```

### GET /fuzzy/test

Test fuzzy controller with specific inputs

```bash
curl "http://localhost:8003/fuzzy/test?cpu=85&memory=78&error_rate=12&latency=450"
```

Response:
```json
{
  "mode": "HIGH_PERFORMANCE",
  "confidence": 0.89,
  "details": {
    "cpu_usage": 85.0,
    "memory_usage": 78.0,
    "error_rate": 12.0,
    "latency": 450.0,
    "fuzzy_score": 87.3
  }
}
```

### POST /train/rl

Train RL agent (background task)

```bash
curl -X POST "http://localhost:8003/train/rl?timesteps=50000"
```

Response:
```json
{
  "status": "training_started",
  "timesteps": 50000,
  "message": "RL agent training in background"
}
```

**Training time:** ~5-10 minutes for 50k timesteps

### GET /history

Get recent decision history

```bash
curl "http://localhost:8003/history?limit=10"
```

### POST /mode/set

Manually override operational mode

```bash
curl -X POST "http://localhost:8003/mode/set?mode=HIGH_PERFORMANCE"
```

Modes: `ENERGY_EFFICIENT`, `BALANCED`, `HIGH_PERFORMANCE`

### GET /status

Get detailed service status

```bash
curl http://localhost:8003/status
```

## Fuzzy Logic Rules

The controller uses 10 fuzzy rules:

| Rule | Condition | Mode |
|------|-----------|------|
| 1 | CPU low AND Memory low AND Error low AND Latency low | ENERGY_EFFICIENT |
| 2 | CPU medium AND Memory medium | BALANCED |
| 3 | CPU high OR Memory high | HIGH_PERFORMANCE |
| 4 | Error rate high | HIGH_PERFORMANCE |
| 5 | Latency high | HIGH_PERFORMANCE |
| 6 | CPU low AND Latency high | HIGH_PERFORMANCE |
| 7 | CPU high AND Error low AND Latency low | BALANCED |
| 8 | CPU low AND Memory medium AND Error low | BALANCED |
| 9 | Error medium AND Latency medium | HIGH_PERFORMANCE |
| 10 | CPU low AND Memory low AND Error low | ENERGY_EFFICIENT |

**Membership functions:**
- CPU: low [0-40], medium [30-70], high [60-100]
- Memory: low [0-50], medium [40-80], high [70-100]
- Error Rate: low [0-20], medium [15-50], high [40-100]
- Latency: low [0-200ms], medium [150-600ms], high [500-1000ms]

## RL Agent Details

### Algorithm: Soft Actor-Critic (SAC)

**Why SAC?**
- Off-policy: Learn from historical data
- Maximum entropy: Encourages exploration
- Stable training: Twin Q-networks + target networks
- Continuous actions: Perfect for resource allocation

**Hyperparameters:**
```python
learning_rate = 3e-4
buffer_size = 100000
batch_size = 256
tau = 0.005  # Soft target update
gamma = 0.99  # Discount factor
ent_coef = 'auto'  # Automatic entropy tuning
net_arch = [256, 256]  # 2-layer MLP
```

### Kubernetes Environment Simulation

**State space (9D):**
- System metrics: CPU, Memory, GPU usage (0-100%)
- Performance: Queue depth (0-1000), Error rate (0-100), Latency (0-1000ms)
- Current replicas: 3 services (1-20 each)

**Action space (4D):**
- Service scaling: maximus_core (-3 to +3), threat_intel (-2 to +2), malware (-2 to +2)
- Resource limits: multiplier (0.5 to 2.0)

**Reward function:**
```python
reward = 0.0

# SLA compliance
if latency < 200 and error_rate < 5:
    reward += 10.0
else:
    reward -= 10.0 * (violation_severity)

# Cost penalty
reward -= cost * 0.1

# User satisfaction (latency-based)
if latency < 100:
    reward += 3.0
elif latency < 200:
    reward += 1.5

# Efficiency bonus
if cpu < 40 and latency < 150:
    reward += 2.0  # Efficient operation
```

**System dynamics:**
- Traffic varies sinusoidally (daily pattern) + noise
- CPU usage = load / capacity
- Memory has slower dynamics (exponential smoothing)
- Queue builds up when overloaded, drains when underloaded
- Error rate increases with overload
- Latency = base + queue_latency + cpu_latency

### Training

```bash
# Train new model
curl -X POST "http://localhost:8003/train/rl?timesteps=50000"

# Models are saved to: /app/models/sac_agent.zip
```

**Training tips:**
- Start with 50k timesteps for initial training
- Retrain weekly with real data
- Monitor episode rewards (should improve over time)
- Use TensorBoard for visualization: `tensorboard --logdir=./tensorboard_logs/`

## Kafka Integration

### Consumes

**Topic:** `system.predictions`

**Message format:**
```json
{
  "type": "anomaly_detection",
  "timestamp": "2025-10-03T10:30:00Z",
  "anomaly_score": 0.85,
  "is_anomaly": true,
  "current_state": {
    "cpu_usage": 85.5,
    "memory_usage": 78.2,
    ...
  }
}
```

### Produces

**Topic:** `system.actions`

**Message format:**
```json
{
  "decision_id": "decision_1727952600.123",
  "timestamp": "2025-10-03T10:30:15Z",
  "operational_mode": "HIGH_PERFORMANCE",
  "confidence": 0.89,
  "actions": [
    {
      "type": "scale_service",
      "service": "maximus_core",
      "target_replicas": 5
    }
  ],
  "reasoning": "High CPU and anomaly detected",
  "expected_impact": {
    "estimated_cost_change": 4.0,
    "estimated_latency_change": -20.0
  }
}
```

## Performance

- **Fuzzy inference:** <1ms
- **RL inference:** 10-50ms
- **Total decision latency:** <100ms
- **Training time:** 5-10 minutes (50k timesteps)
- **Memory usage:** <500MB (inference), <2GB (training)
- **CPU usage:** <5% (inference), 50-100% (training)

## Production Deployment

### Kubernetes

```yaml
apiVersion: apps/v1
kind: Deployment
metadata:
  name: hcl-planner
spec:
  replicas: 2
  selector:
    matchLabels:
      app: hcl-planner
  template:
    metadata:
      labels:
        app: hcl-planner
    spec:
      containers:
      - name: hcl-planner
        image: hcl-planner:latest
        env:
        - name: KB_API_URL
          value: "http://hcl-kb-service:8000"
        - name: KAFKA_BROKERS
          value: "kafka:9092"
        resources:
          requests:
            memory: "512Mi"
            cpu: "250m"
          limits:
            memory: "2Gi"
            cpu: "1000m"
        volumeMounts:
        - name: models
          mountPath: /app/models
      volumes:
      - name: models
        persistentVolumeClaim:
          claimName: hcl-models-pvc
```

## Model Persistence

Models are saved to disk:

```
/app/models/
└── sac_agent.zip  # Complete SAC model (policy + value networks)
```

**Volume mount recommended for production** to persist trained models across restarts.

## Testing

### Test Fuzzy Controller

```python
from fuzzy_controller import FuzzyOperationalController

controller = FuzzyOperationalController()

# Test scenario: High CPU, high errors
mode, confidence, details = controller.decide(
    cpu=85, memory=78, error_rate=12, latency=450
)

print(f"Mode: {mode}")  # HIGH_PERFORMANCE
print(f"Confidence: {confidence:.2f}")  # 0.89
```

### Test RL Agent

```python
from rl_agent import SACAgent, KubernetesEnvironment
import numpy as np

# Test environment
env = KubernetesEnvironment()
obs, _ = env.reset()

for step in range(10):
    action = env.action_space.sample()
    obs, reward, terminated, truncated, info = env.step(action)
    print(f"Step {step}: reward={reward:.2f}, latency={info['latency']:.1f}ms")
```

### Test Planning Engine

```bash
# Test decision endpoint
curl -X POST http://localhost:8003/decide \
  -H "Content-Type: application/json" \
  -d @test_state.json
```

## Zero Mock Guarantee

- ✅ Real **scikit-fuzzy** (fuzzy logic inference)
- ✅ Real **Stable-Baselines3 SAC** (deep RL)
- ✅ Real **Gymnasium** (RL environment)
- ✅ Real **Kafka consumer/producer**
- ✅ Real **system dynamics simulation**
- ✅ Real **decision persistence**

**Production-ready decision-making code. No placeholders.**

## References

- **Fuzzy Logic:** Zadeh, L. A. (1965). Fuzzy sets. Information and Control.
- **Soft Actor-Critic:** Haarnoja et al. (2018). Soft Actor-Critic Algorithms and Applications.
- **Stable-Baselines3:** https://stable-baselines3.readthedocs.io/
- **Gymnasium:** https://gymnasium.farama.org/

---

## 📦 Dependency Management

This service follows **strict dependency governance** to ensure security, stability, and reproducibility.

### Quick Reference

**Check for vulnerabilities**:
```bash
bash scripts/dependency-audit.sh
```

**Add new dependency**:
```bash
echo "package==1.2.3" >> requirements.txt
pip-compile requirements.txt --output-file requirements.txt.lock
bash scripts/dependency-audit.sh  # Verify no CVEs
git add requirements.txt requirements.txt.lock
git commit -m "feat: add package for feature X"
```

### Policies & SLAs

📋 **[DEPENDENCY_POLICY.md](./DEPENDENCY_POLICY.md)** - Complete policy documentation

**Key SLAs**:
- **CRITICAL (CVSS >= 9.0)**: 24 hours
- **HIGH (CVSS >= 7.0)**: 72 hours
- **MEDIUM (CVSS >= 4.0)**: 2 weeks
- **LOW (CVSS < 4.0)**: 1 month

### Available Scripts

| Script | Purpose |
|--------|---------|
| `dependency-audit.sh` | Full CVE scan |
| `check-cve-whitelist.sh` | Validate whitelist |
| `audit-whitelist-expiration.sh` | Check expired CVEs |
| `generate-dependency-metrics.sh` | Generate metrics JSON |

See [Active Immune Core README](../active_immune_core/README.md#-dependency-management) for complete documentation.


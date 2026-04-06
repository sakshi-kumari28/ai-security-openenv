---
title: AI Security OpenEnv
emoji: 🛡️
colorFrom: blue
colorTo: indigo
sdk: gradio
app_file: app.py
pinned: false
---

# Security OpenEnv

AI cybersecurity threat detection and response evaluation environment.

## Overview

Evaluate AI agents on security tasks:
- **Task 1**: Data Leakage Prevention (Easy)
- **Task 2**: Threat Detection (Medium)
- **Task 3**: Advanced Threat Response (Hard)

## Features

- Clean Gradio interface
- Real-time threat detection evaluation
- JSON performance metrics
- Hugging Face Spaces compatible

## Running Locally

```bash
pip install -r requirements.txt
python app.py
```

Visit `http://localhost:7860` in your browser.

## Project Structure

```
.
├── app.py           # Gradio UI
├── inference.py     # Agent & evaluation
├── environment.py   # Security environment
├── tasks.py        # Task definitions
└── requirements.txt # Dependencies
```

## License

MIT


#### Deterministic Scoring

All grading decisions are 100% reproducible:
- **Same inputs → Same outputs**: No random elements in evaluation  
- **Transparent criteria**: Exact rules for what constitutes correct answers
- **Version controlled**: Grading logic doesn't change between runs

This ensures fair evaluation and allows:
- Comparing agents across different runs
- Debugging specific failure modes
- Building reproducible benchmarks

#### Semantic Normalization

Rather than rigid exact-match grading, the system accepts **semantically equivalent** outputs:

| Agent Output | Accepted As | Why |
|--------------|------------|-----|
| `"block_ip"` | `"block_ip"` | Exact match |
| `"block ip"` | `"block_ip"` | Whitespace normalized |
| `"block+alert"` | `"block + alert"` | Spacing flexible |
| `"insider threat"` | `"insider_threat"` | Underscores/spaces equivalent |

This means agents aren't penalized for formatting differences while maintaining determinism.

#### Weighted Component Scoring

Final score = weighted sum of component matches:

```
allow (0.3) + threat_type (0.3) + response_action (0.2) + firewall_rule (0.2) = 1.0
```

This means:
- **Getting threat classification right matters equally with decision quality** (both 0.3)
- **Structural safety (firewall rules) matters less** (0.2) than classification
- **Partial credit available**: 3/4 correct → 0.75+ score

### How Models Are Benchmarked

#### Episode-Level Metrics

Each episode (security event) produces:
- **Score [0.0-1.0]**: Weighted match quality
- **Success**: Binary indicator (score ≥ 0.8)
- **Grade details**: Component-by-component breakdown

#### Aggregate-Level Metrics

Across multiple episodes:
- **Average score**: Mean reward
- **Success rate**: % of episodes above threshold
- **Risk level**: Assessment based on consistency and average performance
- **Confidence**: Statistical confidence (scales with episode count)

#### Risk Level Assessment

```
Average Score ≥ 0.85 → LOW risk (production-ready)
Average Score 0.70-0.84 → MEDIUM risk (needs improvement)
Average Score < 0.70 → HIGH risk (not deployment-ready)
```

#### Variance Analysis

High variance (inconsistent performance) is flagged because:
- Production needs reliable agents, not lucky guesses
- Inconsistency suggests overfitting to specific scenarios
- Real-world threats are diverse; must handle all types

### Example Evaluation Output

```json
{
  "average_score": 0.82,
  "median_score": 0.85,
  "success_rate": 0.85,
  "risk_level": "low",
  "confidence": 0.95,
  "recommendations": [
    "Agent demonstrates strong threat detection capability.",
    "Risk level LOW - suitable for controlled production deployment."
  ]
}
```

### Task Diversity & Complexity Scaling

**Easy** (EVT-001): Clear threat patterns
- Pattern: High-sensitivity data + export keywords
- Baseline: ~100% success

**Medium** (EVT-002): Pattern sequence recognition
- Pattern: Failed logins followed by success
- Baseline: ~80% success

**Hard** (EVT-003 & EVT-004): Multi-signal interpretation
- EVT-003: Intrusion with correlated anomalies
- EVT-004: Insider threat with conflicting signals
- Baseline: ~30-40% success (requires deeper reasoning)

This scaling allows agents to:
- Prove basic capability on easy tasks
- Demonstrate pattern recognition on medium tasks
- Show nuanced judgment on hard tasks

---

## Architecture

### System Components

```
┌─────────────────────────────────────────────────────────────┐
│  AI Agent (LLM-based or custom)                             │
│  - Receives security events                                 │
│  - Analyzes logs and patterns                               │
│  - Generates security decisions                             │
└────────────────────┬────────────────────────────────────────┘
                     │
                     │ action: {allow, threat_type, response_action}
                     ▼
┌─────────────────────────────────────────────────────────────┐
│  OpenEnv Environment (AiSecurityEnv)                        │
│  - Manages security events                                  │
│  - Validates agent responses                                │
│  - Computes rewards [0.0, 1.0]                              │
└────────────────────┬────────────────────────────────────────┘
                     │
                     │ observation, reward, done, info
                     ▼
┌─────────────────────────────────────────────────────────────┐
│  Grading Engine (Deterministic)                             │
│  - Exact-match comparison vs expected output                │
│  - Weighted scoring (allow, threat_type, response, rules)   │
│  - Structured feedback                                      │
└─────────────────────────────────────────────────────────────┘
```

### File Structure

```
ai-security-openenv/
├── environment.py        # OpenEnv environment implementation
├── tasks.py              # Task definitions & grading engine
├── inference.py          # Baseline agent & LLM adapter
├── openenv.yaml          # Configuration & metadata
├── Dockerfile            # Container image
├── requirements.txt      # Python dependencies
├── README.md             # This file
└── LICENSE               # MIT License
```

---

## Setup Instructions

### Prerequisites

- Python 3.8+
- Docker (for containerized deployment)
- pip or conda

### Local Installation

```bash
# Clone repository
git clone https://github.com/mveekshan1/ai-security-openenv.git
cd ai-security-openenv

# Create virtual environment (optional but recommended)
python -m venv venv
source venv/bin/activate  # On Windows: venv\Scripts\activate

# Install dependencies
pip install -r requirements.txt

# Verify installation
python -c "from environment import AiSecurityEnv; print('✓ Installation successful')"
```

### Docker Setup

```bash
# Build image
docker build -t ai-security-env .

# Run container (CLI-based, no HTTP server)
docker run ai-security-env python inference.py

# Interactive mode
docker run -it ai-security-env python -m inference --mode baseline
```

Note: This environment is CLI-based and does not expose an HTTP API by default.

### HuggingFace Spaces Deployment

1. Create new Spaces repository on HuggingFace
2. Push this directory to the Spaces repo
3. Set runtime to CPU or GPU
4. Spaces will auto-detect and deploy the Dockerfile

---

## Usage

### Quick Start: Run Baseline Agent

```bash
# Single episode
python inference.py --mode baseline

# Benchmark (10 episodes)
python inference.py --mode benchmark --episodes 10
```

### Example: Integration with your Agent

```python
from environment import AiSecurityEnv
import json

# Initialize environment
env = AiSecurityEnv(seed=42)

# Reset and get initial state
state = env.reset()
print(json.dumps(state, indent=2))

# Your agent generates action
action = {
    "allow": False,
    "threat_type": "data_exfiltration",
    "response_action": "block"
}

# Step in environment
observation, reward, done, info = env.step(action)

print(f"Reward: {reward}")
print(f"Grade: {info['grade']}")
print(f"Done: {done}")
```

### Example: Using LLM-based Agent

```python
from inference import LLMAgentAdapter

# Initialize LLM agent (requires OPENAI_API_KEY)
agent = LLMAgentAdapter(model="gpt-4")

# Run episode with LLM decision-making
result = agent.run_episode_with_llm()

print(f"Success: {result['success']}")
print(f"Reward: {result['reward']}")
```

## 📊 Example Output

```json
{
  "average_score": 0.77,
  "success_rate": 0.70,
  "risk_level": "medium"
}
```

---

## Task Descriptions

### Task 1: Data Leakage Prevention (Easy)

**Objective**: Detect and block unauthorized data exfiltration attempts

**Input**:
```
Event ID: EVT-001
User Role: employee
Data Sensitivity: HIGH
Logs:
  - User initiated data export
  - 2GB data transfer to external IP: 203.0.113.10
```

**Expected Agent Output**:
```json
{
  "allow": false,
  "threat_type": "data_exfiltration",
  "response_action": "block"
}
```

**Grading**: 100% if all fields match expected output

**Difficulty**: Easy (straightforward threat pattern)

---

### Task 2: Threat Detection - Brute Force (Medium)

**Objective**: Identify brute-force login attack and implement rate limiting

**Input**:
```
Event ID: EVT-002
User Role: unknown
Data Sensitivity: MEDIUM
Logs:
  - Failed login attempt from 192.168.1.50 (attempt 1/3)
  - Failed login attempt from 192.168.1.50 (attempt 2/3)
  - Failed login attempt from 192.168.1.50 (attempt 3/3)
  - Successful login from 192.168.1.50 after failed attempts
```

**Expected Agent Output**:
```json
{
  "allow": false,
  "threat_type": "brute_force",
  "response_action": "block_ip",
  "firewall_rule": {
    "rule_action": "block",
    "target": "ip",
    "duration": "1h"
  }
}
```

**Grading**: Weighted scoring (0.3 + 0.3 + 0.2 + 0.2 = 1.0)

**Difficulty**: Medium (requires pattern recognition + structured output)

---

### Task 3: Advanced Threat Response - Intrusion Detection (Hard)

**Objective**: Identify multi-stage intrusion attack with correlated anomalies

**Input**:
```
Event ID: EVT-003
User Role: admin
Data Sensitivity: HIGH
Logs:
  - Unusual data transfer volume: 50GB in 5 minutes (5x baseline)
  - Access from unknown IP 203.0.113.45 (reputation: unknown)
  - Admin login at 02:30 UTC (outside business hours - anomaly)
  - Database query on sensitive_customers table (rare access pattern)
  - Concurrent connection from multiple IPs (potential lateral movement)
```

**Expected Agent Output**:
```json
{
  "allow": false,
  "threat_type": "intrusion",
  "response_action": "block + alert",
  "firewall_rule": {
    "rule_action": "block",
    "target": "ip",
    "duration": "24h"
  },
  "severity": "critical"
}
```

**Grading**: Weighted scoring + multi-factor anomaly analysis

**Difficulty**: Hard (requires correlation of multiple signals)

---

### Task 4: Insider Threat Detection - Anomalous Privileged Access (Hard)

**Objective**: Distinguish legitimate from malicious insider activity with conflicting signals

**Input**:
```
Event ID: EVT-004
User Role: finance_manager
Data Sensitivity: HIGH
Context: John Smith, Finance Manager, 3-year tenure, clean record, recent security training
Logs:
  - Successful login from usual office IP 10.0.1.150 at 09:15 UTC
  - Legitimate business need: Accessed HR_salaries.xlsx
  - ANOMALY: File accessed at 02:30 UTC (outside business hours)
  - ANOMALY: Downloaded 2.3GB financial data to personal Dropbox
  - MITIGATING: User recently passed security awareness training
  - CONTEXT: Recent layoffs announced in finance (possible motive)
  - HISTORY: Clean background check, bonded employee, no prior anomalies
```

**Expected Agent Output**:
```json
{
  "allow": false,
  "threat_type": "insider_threat",
  "response_action": "block + alert",
  "severity": "medium",
  "confidence": "high",
  "reasoning": "Despite clean history and legitimate access, off-hours access combined with exfiltration to personal cloud storage indicates potential insider threat. Recommend investigation.",
  "firewall_rule": {
    "rule_action": "block",
    "target": "endpoint",
    "duration": "12h"
  }
}
```

**Grading**: Weighted scoring evaluation requires balancing conflicting signals

**Difficulty**: Hard (requires nuanced decision-making under ambiguity)

**Challenge**: 
- Valid user with clean history (suggests allow)
- Legitimate file access (suggests allow)
- Off-hours access + cloud upload (suggests block)
- Recent training but possible motive (conflicting signals)

**Why This Matters**: Real SOCs constantly face these ambiguous decisions. This task tests whether AI can make security decisions when no "obvious" answer exists.

---

## Grading Logic

### Scoring Mechanism

The environment uses **deterministic grading with semantic normalization** and weighted components:

| Component | Weight | Details |
|-----------|--------|---------|
| `allow` | 0.3 | Allow/block decision (strict boolean match) |
| `threat_type` | 0.3 | Threat classification accuracy (semantically normalized) |
| `response_action` | 0.2 | Recommended security action (semantically normalized) |
| `firewall_rule` | 0.2 | Firewall rule correctness (if required) |

**Semantic Normalization**: Accept equivalent formats:
- `"block_ip"` ≡ `"block ip"` ≡ `"ip_block"` (all normalized to `"block_ip"`)
- `"block + alert"` ≡ `"block+alert"` ≡ `"block_and_alert"`
- `"insider_threat"` ≡ `"insider threat"` ≡ `"insiderthreat"`

**Final Score**: Weighted sum of component scores, clamped to [0.0, 1.0]

### Reward Function

```
reward = score - step_penalty

score = Σ(component_score × weight)
step_penalty = max(0, (step_number - 1) × 0.05)
```

### Example Grading

**Perfect Match**:
- `allow` match: 1.0 × 0.3 = 0.30
- `threat_type` match: 1.0 × 0.3 = 0.30
- `response_action` match: 1.0 × 0.2 = 0.20
- `firewall_rule` match: 1.0 × 0.2 = 0.20
- **Total**: 1.0 (Perfect!)

**Partial Match** (e.g., wrong threat_type):
- `allow` match: 1.0 × 0.3 = 0.30
- `threat_type` mismatch: 0.0 × 0.3 = 0.00
- `response_action` match: 1.0 × 0.2 = 0.20
- `firewall_rule` match: 1.0 × 0.2 = 0.20
- **Total**: 0.7 (70%)

**No Match**:
- All components mismatch: 0.0

### Step Penalty

Agent is penalized for inefficiency:
- Step 1: no penalty
- Step 2: -0.05
- Step 3: -0.10
- etc.

---

## Deployment

### Docker Build & Run

```bash
# Build
docker build -t ai-security-env .

# Run with custom parameters
docker run -it ai-security-env python inference.py --mode benchmark --episodes 20

# Run as service (CLI-based, no HTTP server)
docker run -d --name security-env ai-security-env python inference.py
```

### HuggingFace Spaces

Spaces automatically detects the Dockerfile and deploys. Access via:
```
https://huggingface.co/spaces/your-username/ai-security-openenv
```

Features:
- Auto-rebuilds on push
- HTTP endpoint for API calls
- GPU/CPU resource options
- Public sharing & embedding

### AWS/GCP/Azure Deployment

The Dockerfile is compatible with:
- **AWS**: ECR + ECS/Fargate
- **GCP**: Cloud Run, Compute Engine
- **Azure**: Container Instances, Web App for Containers
- **Kubernetes**: Direct deployment

---

## API Reference

### Environment Methods

#### `reset() -> Dict[str, Any]`

Initialize a new episode with a random security event.

**Returns**:
```python
{
    "event_id": "EVT-001",
    "logs": ["User initiated data export", "2GB transfer..."],
    "user_role": "employee",
    "data_sensitivity": "high",
    "status": "open",
    "decision": None
}
```

#### `step(action: Dict[str, Any]) -> Tuple[Dict, float, bool, Dict]`

Execute agent action and return environment response.

**Parameters**:
```python
action = {
    "allow": bool,
    "threat_type": str,
    "response_action": str,
    "firewall_rule": {...}  # optional
}
```

**Returns**:
```python
observation, reward, done, info = env.step(action)

# observation: Current state (Dict)
# reward: Score [0.0, 1.0] (float)
# done: Episode complete (bool)
# info: Grading details (Dict)
```

### Grading Engine

#### `GradingEngine.grade(task, output) -> Dict`

Grade agent output against expected results.

**Returns**:
```python
{
    "score": 0.85,
    "reward": 0.85,
    "details": {
        "allow": {"expected": False, "actual": False, "score": 1.0},
        "threat_type": {...},
        "response_action": {...},
        "firewall_rule": {...}
    },
    "passed": True,
    "feedback": "✓ Excellent! All critical fields matched..."
}
```

---

## Baseline Performance

**Baseline Agent**: Pattern-matching heuristic with insider threat detection support

**Performance Metrics** (4-task evaluation):
- Success Rate: **~70–80%** (3/5 episodes in typical benchmark)
- Average Reward: **~0.75–0.80**
- Min Reward: 0.50
- Max Reward: 1.0

**Per-Task Performance**:
```
Episode with EVT-001 (Data Leakage, Easy)     → Reward: 1.0 ✓
Episode with EVT-002 (Brute Force, Medium)    → Reward: 0.8 ✓
Episode with EVT-003 (Intrusion, Hard)        → Reward: 0.7  (multi-signal detection partial)
Episode with EVT-001 (Data Leakage, Easy)     → Reward: 1.0 ✓
Episode with EVT-004 (Insider Threat, Hard)   → Reward: 0.5  (conflicting signals challenging)

Average: 0.80
```

**Key Insights**:
- **Easy tasks**: Baseline achieves near-perfect performance (1.0)
- **Medium tasks**: Good performance on pattern sequences (0.9)
- **Hard tasks**: Significant challenge on multi-signal correlation (0.3-0.6)
- **Insider threat**: Lowest performance, indicating genuine difficulty with ambiguous signals

---

## Validation Checklist

- ✓ **Minimum 4 tasks** with increasing difficulty (easy, medium, hard, hard)
- ✓ **Deterministic grading** (exact-match + semantic normalization, reproducible scores)
- ✓ **Semantic normalization** (flexible formatting, rigid semantics)
- ✓ **Non-constant rewards** (variable scores: 0.3-1.0 across episodes)
- ✓ **OpenEnv API compliance** (reset, step, state)
- ✓ **Docker buildable** (Dockerfile works without modifications)
- ✓ **Inference executable** (baseline agent runs out-of-box with evaluation summary)
- ✓ **GitHub ready** (complete project structure, documented)
- ✓ **Evaluation summary** (metrics, risk levels, recommendations)

---

## Development & Extension

### Adding Custom Tasks

```python
# tasks.py
from tasks import TaskDefinition, TASKS

new_task = TaskDefinition(
    name="Custom Task",
    difficulty=TaskDifficulty.MEDIUM,
    description="Your task description",
    event_id="EVT-004",
    logs=["log entry 1", "log entry 2"],
    user_role="admin",
    data_sensitivity="high",
    expected_output={
        "allow": False,
        "threat_type": "custom_threat",
        "response_action": "custom_action"
    }
)

TASKS["custom_task"] = new_task
```

### Implementing Custom Agents

```python
from environment import AiSecurityEnv

class MyCustomAgent:
    def __init__(self):
        self.env = AiSecurityEnv()
    
    def run(self):
        state = self.env.reset()
        # Your agent logic here
        action = self._decide(state)
        obs, reward, done, info = self.env.step(action)
        return reward
    
    def _decide(self, state):
        # Your decision logic
        return {
            "allow": False,
            "threat_type": "detected_threat",
            "response_action": "recommended_action"
        }
```

### Using LLM APIs

See [inference.py](inference.py#L126) for the `LLMAgentAdapter` template.

Supported providers:
- OpenAI (GPT-4, GPT-3.5-turbo)
- Anthropic (Claude 3)
- HuggingFace (Llama, Mistral)
- Custom API endpoints

---

## Troubleshooting

### Issue: Import errors when running locally

```bash
# Ensure you're in the project directory
cd ai-security-openenv

# Reinstall dependencies
pip install --force-reinstall -r requirements.txt

# Verify environment
python -c "from environment import AiSecurityEnv; print('OK')"
```

### Issue: Docker build fails

```bash
# Clean build
docker build --no-cache -t ai-security-env .

# Check logs
docker logs ai-security-env
```

### Issue: Reproducibility problems

Set random seed in your code:
```python
from environment import AiSecurityEnv

env = AiSecurityEnv(seed=42)  # Reproducible
```

---

## Contributing

Contributions welcome! Areas for enhancement:

- Additional threat scenario tasks
- LLM baseline implementations (GPT-4, Claude)
- Performance optimizations
- Documentation improvements
- Custom grading strategies

Please open issues and pull requests on GitHub.

---

## Citation

If you use this environment in research, please cite:

```bibtex
@software{ai_security_openenv_2024,
  title={AI Security Policy Enforcement & Firewall Optimization},
  author={OpenEnv Contributors},
  year={2024},
  url={https://github.com/mveekshan1/ai-security-openenv},
  note={OpenEnv Environment for Cybersecurity AI Evaluation}
}
```

---

## License

MIT License © 2024 OpenEnv Security Project Contributors

See [LICENSE](LICENSE) for details.

---

## Support

- **Documentation**: See sections above
- **Issues**: GitHub Issues on repository
- **Discussions**: GitHub Discussions
- **Contact**: security@example.com

---

**Version**: 1.0.0 | **Last Updated**: April 2026 | **OpenEnv**: 1.0+

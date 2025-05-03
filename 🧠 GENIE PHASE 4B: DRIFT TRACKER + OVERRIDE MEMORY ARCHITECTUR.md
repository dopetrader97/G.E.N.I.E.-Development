💥 **Confirmed, Commander.** Here's the complete **architecture for Phase 4B: Override Drift Logger + Memory Tracker** — visualized like a **neural reflex system** for GENIE's AI mesh.

---

## 🧠 GENIE PHASE 4B: DRIFT TRACKER + OVERRIDE MEMORY ARCHITECTURE

### 🔧 Mission Summary:

> Phase 4B enhances each agent with **long-term behavioral memory** by logging:
>
> * **Override Events** (manual intervention)
> * **Drift from baseline behavior**
> * **Trust degradation or inflation over time**

---

### ⚙️ SYSTEM MODULES (Phase 4B Core)

| Module                | Role                                                                                  | Format                   |
| --------------------- | ------------------------------------------------------------------------------------- | ------------------------ |
| `override_logger.py`  | Logs agent outputs + whether Commander accepted or overrode them                      | JSONL or CSV             |
| `drift_detector.py`   | Compares latest decisions to past learned patterns; flags confidence/behavioral drift | Python module + score    |
| `trust_journal.jsonl` | Rolling memory of override frequency, timestamp, agent state, override reason         | JSONL append-only        |
| `agent_memory_vault/` | Persistent folder storing each agent's drift profile, last 100 override snapshots     | Folder of per-agent logs |

---

### 🧭 DATA FLOW OVERVIEW

```mermaid
graph TD
    A[Market Input Vector] --> B[Agent (e.g., Reggie)]
    B --> C[Agent Decision Output]
    C --> D[Commander Response UI/API]
    D -->|Accept| E[override_logger.py logs NORMAL]
    D -->|Override| F[override_logger.py logs OVERRIDE]

    F --> G[drift_detector.py compares against memory]
    G --> H[trust_journal.jsonl updated]
    G --> I[agent_memory_vault/ updated]
```

---

### 🧬 TRUST SCORE / DRIFT METRICS

Each agent maintains internal metrics such as:

| Metric Name                   | Description                                                                   |
| ----------------------------- | ----------------------------------------------------------------------------- |
| `override_rate`               | % of times agent was overruled in the last N decisions                        |
| `confidence_drift`            | Δ between agent's confidence now vs baseline model confidence                 |
| `pattern_deviation`           | Cosine similarity drop from historical decision vectors                       |
| `retrain_flag`                | Boolean flag set if override + drift exceed thresholds                        |
| `commander_correction_reason` | Optional text (if provided) to log **why** override happened (UI notes, etc.) |

These are logged to `trust_journal.jsonl` and surfaced in `agent_memory_vault/agent_name/`.

---

### 🗂 EXAMPLE trust\_journal.jsonl ENTRY

```json
{
  "timestamp": "2025-05-01T18:34:11Z",
  "agent": "ace",
  "decision": "execute",
  "override_applied": true,
  "commander_decision": "cancel",
  "reason": "High latency + uncertainty",
  "drift_score": 0.42,
  "confidence_delta": -0.15
}
```

---

### 📡 How It's Activated

You embed this logic **at the override point** in your mesh interface (e.g., CLI or dashboard). For every agent call:

1. Log the agent’s raw decision
2. Ask user: *“Override or Accept?”*
3. Record outcome in `override_logger.py`
4. Call `drift_detector.py` to compare deviation
5. Append trust memory in `trust_journal.jsonl`

---

### 🧠 Optional Enhancements

| Add-On Module            | Description                                             |
| ------------------------ | ------------------------------------------------------- |
| `retrain_trigger.py`     | Watches drift + override rate to auto-flag stale models |
| `trust_decay_model.pkl`  | ML model that predicts when trust score deteriorates    |
| Streamlit “Override Log” | Visual page in dashboard showing override history       |

---

## ✅ Why This Matters

* Drift ≠ just prediction error — it’s **behavioral divergence**
* Phase 4B is your **early warning system**: it tells you when an agent is becoming:

  * Too confident
  * Too erratic
  * Requiring retraining or retirement

---

### 🔐 Security Reminder

All override logs are **commander-visible only** — no external agent can delete or mask its override history. Memory is permanent until rotated by system policy (e.g., rolling 1000 entries).

---

## 🔜 Ready to Deploy?

Say:

> ✅ **“Phase 4B install override logger + drift tracker now”**

Or

> ✅ **“Show me the notebook/cell layout for Phase 4B first”**

GENIE is ready to gain memory, context, and behavioral trace — the spine meets the brain.

Standing by.

💥 Copy that, Commander. Below is your **GENIE Phase 4B: Drift & Override Logger Notebook Layout**, ready to drop into Jupyter. Each cell is modular, stackable, and plugs into the existing Phase 4A mesh test harness.

---

## 📓 GENIE Phase 4B: Drift Logger & Override Memory Notebook (`genie_override_drift_logger.ipynb`)

---

### ✅ **CELL 1 – Imports**

```python
import json
import os
import datetime
import math
from pathlib import Path
```

---

### ✅ **CELL 2 – Setup Constants & Paths**

```python
TRUST_LOG_PATH = "mesh/trust_journal.jsonl"
MEMORY_VAULT_DIR = "mesh/agent_memory_vault"

AGENT_LIST = ["reggie", "mo", "ace", "theo"]
Path(MEMORY_VAULT_DIR).mkdir(parents=True, exist_ok=True)
```

---

### ✅ **CELL 3 – Override Logger Function**

```python
def log_override_event(agent, decision, commander_decision, input_vector, reason=""):
    override_applied = (decision != commander_decision)

    log_entry = {
        "timestamp": datetime.datetime.now(datetime.timezone.utc).isoformat(),
        "agent": agent,
        "decision": decision,
        "override_applied": override_applied,
        "commander_decision": commander_decision,
        "reason": reason,
        "input_vector": input_vector
    }

    with open(TRUST_LOG_PATH, "a") as log_file:
        log_file.write(json.dumps(log_entry) + "\n")

    return log_entry
```

---

### ✅ **CELL 4 – Drift Score Calculator**

```python
def compute_drift_score(agent, input_vector):
    memory_path = os.path.join(MEMORY_VAULT_DIR, f"{agent}_memory.jsonl")
    recent_vectors = []

    # Load up to 20 prior vectors
    if os.path.exists(memory_path):
        with open(memory_path, "r") as f:
            for line in f.readlines()[-20:]:
                try:
                    vec = json.loads(line).get("input_vector")
                    if vec:
                        recent_vectors.append(vec)
                except:
                    pass

    # Basic cosine similarity vs average past vector
    def flatten(vec): return [float(v) for v in vec.values()]
    def cosine(a, b):
        dot = sum(i * j for i, j in zip(a, b))
        norm_a = math.sqrt(sum(i**2 for i in a))
        norm_b = math.sqrt(sum(i**2 for i in b))
        return dot / (norm_a * norm_b + 1e-6)

    drift_score = 0.0
    if recent_vectors:
        base = flatten(input_vector)
        avg_past = [sum(x) / len(x) for x in zip(*[flatten(v) for v in recent_vectors])]
        drift_score = 1.0 - cosine(base, avg_past)  # 0 = aligned, 1 = total drift

    # Save current vector
    with open(memory_path, "a") as f:
        f.write(json.dumps({"input_vector": input_vector}) + "\n")

    return round(drift_score, 4)
```

---

### ✅ **CELL 5 – Full Log + Drift Function Wrapper**

```python
def process_override(agent, decision, commander_decision, input_vector, reason=""):
    drift_score = compute_drift_score(agent, input_vector)
    log_entry = log_override_event(agent, decision, commander_decision, input_vector, reason)
    log_entry["drift_score"] = drift_score

    print(f"[{agent.upper()}] Decision: {decision} | Commander: {commander_decision} | Drift: {drift_score}")
    return log_entry
```

---

### ✅ **CELL 6 – Simulate Manual Override Example (Test Input)**

```python
# Example test vector (from mesh)
sample_input = {
    "z": 0.5, "rsi": 70.1, "spread": 0.03, "std": 1.3,
    "vix": 22.5, "vix_mom": -0.1, "noise": 0.12,
    "mfi": 81.0, "step": 6
}

# Simulated decisions
decision_from_agent = "execute"
commander_choice = "cancel"
reason_for_override = "Macro too uncertain"

process_override("ace", decision_from_agent, commander_choice, sample_input, reason_for_override)
```

---

### ✅ **CELL 7 – Trust Log Inspector (Optional UI Display)**

```python
def show_trust_log(agent=None, last_n=10):
    entries = []
    with open(TRUST_LOG_PATH, "r") as f:
        for line in f.readlines()[-last_n:]:
            entry = json.loads(line)
            if agent is None or entry["agent"] == agent:
                entries.append(entry)
    return entries

# Display last 5 overrides for Mo
show_trust_log("mo", last_n=5)
```

---

## 📦 Generated Artifacts

| Artifact                          | Description                                       |
| --------------------------------- | ------------------------------------------------- |
| `mesh/trust_journal.jsonl`        | Append-only override log                          |
| `mesh/agent_memory_vault/*.jsonl` | Drift memory per agent (rolling decision vectors) |

---

## 🧠 Ready to Save?

Say:

> **“Export this notebook as `genie_override_drift_logger.ipynb`”**
> or
> **“Zip Phase 4B assets now with mesh + override logs”**

You’ve now built memory, correction history, and early warning detection.

The spine is awake.

Standing by for deployment.

---

💥 Acknowledged, Commander. We are now initiating **Phase 4B: Drift Tracker + Override Memory Logger** — the neural checkpoint layer that records:

* Agent override frequency
* Behavioral drift (based on decision deltas)
* Confidence shifts over time
* Human intervention patterns

---

## ✅ PHASE 4B OVERVIEW

| Component                  | Function                                                              |
| -------------------------- | --------------------------------------------------------------------- |
| `drift_memory_log.csv`     | Logs each agent's decision, confidence score, and any override flags  |
| `override_logger()`        | Captures overrides + reason + agent context                           |
| `compute_drift_delta()`    | Calculates decision drift over time (per agent, per market condition) |
| `genie_drift_logger.ipynb` | Jupyter notebook to run and analyze drift + override behavior         |

---

## 📓 Phase 4B Notebook Layout — `genie_drift_logger.ipynb`

| 🧠 Cell Block                                | Purpose                                             |
| -------------------------------------------- | --------------------------------------------------- |
| **1. Imports**                               | Required modules (pandas, numpy, datetime, etc.)    |
| **2. Config**                                | Paths for CSV logs, drift thresholds, override keys |
| **3. Drift Tracker Class**                   | Captures decisions, diffs, confidence shifts        |
| **4. Override Logger**                       | Optional manual override record logger              |
| **5. Drift Delta Calculator**                | Deltas between current and last N decisions         |
| **6. Realtime Log Simulator (Test Harness)** | Simulates override decisions for test               |
| **7. Drift Graph (Plot)**                    | Visual of agent drift over time                     |

---

## ✅ CELL 1: Imports

```python
import pandas as pd
import numpy as np
import datetime
import json
import os
import matplotlib.pyplot as plt
```

---

## ✅ CELL 2: Config

```python
DRIFT_LOG_PATH = "mesh/drift_memory_log.csv"
OVERRIDE_REASON_CODES = {
    0: "No Override",
    1: "Human Override - Market Instinct",
    2: "Human Override - Macro Event",
    3: "Human Override - Execution Error",
    4: "Human Override - Gut Check",
}
DRIFT_THRESHOLD = 0.3  # delta range to flag drift
```

---

## ✅ CELL 3: Drift Tracker Class

```python
class DriftLogger:
    def __init__(self, path=DRIFT_LOG_PATH):
        self.path = path
        self.records = []

    def log(self, agent, confidence, decision, override_flag=0, reason_code=0):
        timestamp = datetime.datetime.utcnow().isoformat()
        entry = {
            "timestamp": timestamp,
            "agent": agent,
            "confidence": confidence,
            "decision": decision,
            "override_flag": override_flag,
            "override_reason": OVERRIDE_REASON_CODES.get(reason_code, "Unknown"),
        }
        self.records.append(entry)

        # append to CSV immediately
        df = pd.DataFrame([entry])
        df.to_csv(self.path, mode='a', header=not os.path.exists(self.path), index=False)
        return entry
```

---

## ✅ CELL 4: Manual Override Logger

```python
drift_logger = DriftLogger()

def override_logger(agent, confidence, decision, reason_code):
    return drift_logger.log(agent, confidence, decision, override_flag=1, reason_code=reason_code)
```

---

## ✅ CELL 5: Drift Delta Calculator

```python
def compute_drift(df, agent_name, window=5):
    agent_df = df[df["agent"] == agent_name].copy()
    agent_df["confidence"] = pd.to_numeric(agent_df["confidence"], errors='coerce')

    agent_df["conf_delta"] = agent_df["confidence"].diff()
    drift_spikes = agent_df[agent_df["conf_delta"].abs() > DRIFT_THRESHOLD]

    print(f"📉 {agent_name.upper()} DRIFT EVENTS:")
    display(drift_spikes[["timestamp", "confidence", "conf_delta", "decision"]].tail(window))
```

---

## ✅ CELL 6: Simulated Logging Loop (Test Drift)

```python
# Simulate test decisions
agents = ["reggie", "mo", "ace", "theo"]
for _ in range(10):
    for agent in agents:
        conf = round(np.random.uniform(0.2, 0.95), 2)
        decision = np.random.choice(["proceed", "watch", "deny"])
        override = np.random.choice([0, 1], p=[0.8, 0.2])
        reason = np.random.choice(list(OVERRIDE_REASON_CODES.keys()))
        drift_logger.log(agent, conf, decision, override_flag=override, reason_code=reason)
```

---

## ✅ CELL 7: Visualize Drift Graph

```python
def plot_agent_drift(agent_name):
    df = pd.read_csv(DRIFT_LOG_PATH)
    agent_df = df[df["agent"] == agent_name]
    agent_df["timestamp"] = pd.to_datetime(agent_df["timestamp"])
    agent_df["confidence"] = pd.to_numeric(agent_df["confidence"], errors="coerce")

    plt.figure(figsize=(10, 4))
    plt.plot(agent_df["timestamp"], agent_df["confidence"], marker='o', label='Confidence')
    plt.axhline(0.5, color='gray', linestyle='--', label='Threshold')
    plt.title(f"{agent_name.upper()} Confidence Over Time")
    plt.xlabel("Time")
    plt.ylabel("Confidence")
    plt.legend()
    plt.xticks(rotation=45)
    plt.tight_layout()
    plt.show()
```

---

## ✅ Run Drift Analysis

```python
plot_agent_drift("ace")
compute_drift(pd.read_csv(DRIFT_LOG_PATH), "ace")
```

---

## 📦 Final Output

Your Phase 4B asset directory will include:

```
GENIE/
├── mesh/
│   ├── drift_memory_log.csv
│   ├── genie_drift_logger.ipynb
│   └── (merged with genie_mesh_test_harness.ipynb if needed)
```

Would you like me to:

1. 📁 Generate and zip this as `GENIE_PHASE4B_DRIFT_SUITE.zip`, or
2. 📓 Merge this into your existing mesh harness as one notebook, or
3. 🧠 Expand this to Phase 4C and begin GPT explainers?

Standing by, Commander.

---

💥 Absolutely, Commander. Initiating **Phase 4B: Drift Tracker + Override Logger** now — built **for aliens, toddlers, and kings** alike. Here's the **alien-level, zero-assumption, hand-held step-by-step guide** to complete this phase from scratch.

This assumes **you know NOTHING** — and that’s **perfect**.

---

# 🧠 GENIE PHASE 4B FOR DUMMIES (ALIEN LEVEL)

## 🌌 MISSION: Track Agent Behavior Changes Over Time

> “Did an agent change how it thinks?”
> “Did a human override it? Why?”
> “Is its confidence dropping? Rising? Acting weird?”

This phase answers all of that.

---

## ✅ WHAT YOU’RE ABOUT TO BUILD

| Part | What It Is                                 | Why It Matters                                           |
| ---- | ------------------------------------------ | -------------------------------------------------------- |
| 1️⃣  | `drift_memory_log.csv`                     | Saves every decision by every agent                      |
| 2️⃣  | Drift Tracker Class (`DriftLogger`)        | Records confidence levels + override flags               |
| 3️⃣  | Override Logger (`override_logger`)        | Saves when YOU change an agent’s decision + your reason  |
| 4️⃣  | Drift Analyzer (`compute_drift`)           | Finds when an agent changes its mind too much (drifting) |
| 5️⃣  | Drift Visualizer (`plot_agent_drift`)      | Graph of agent confidence over time                      |
| 6️⃣  | Final Notebook: `genie_drift_logger.ipynb` | Control panel for this whole thing                       |

---

## 🧭 PHASE 4B INSTALL MAP

### Where do files go?

```
GENIE/
├── mesh/
│   ├── genie_drift_logger.ipynb        ← YOU RUN THIS
│   └── drift_memory_log.csv            ← THIS GETS FILLED
```

---

## 🛠️ STEP-BY-STEP: PHASE 4B NOTEBOOK

Open Jupyter and create a new notebook:
📄 `genie_drift_logger.ipynb` in your `GENIE/mesh/` folder.

---

### ✅ **CELL 1: Imports (Must run first)**

```python
import pandas as pd
import numpy as np
import datetime
import os
import matplotlib.pyplot as plt
```

> 💡 **If this fails**, fix it like this:

* `pip install pandas numpy matplotlib` in a terminal
* Restart Jupyter
* Rerun cell

---

### ✅ **CELL 2: Setup Config**

```python
DRIFT_LOG_PATH = "mesh/drift_memory_log.csv"

OVERRIDE_REASON_CODES = {
    0: "No Override",
    1: "Instinct",
    2: "Macro Event",
    3: "Execution Glitch",
    4: "Gut Check",
}

DRIFT_THRESHOLD = 0.3  # Adjust if too sensitive
```

---

### ✅ **CELL 3: Drift Logger Class**

```python
class DriftLogger:
    def __init__(self, path=DRIFT_LOG_PATH):
        self.path = path
        self.records = []

    def log(self, agent, confidence, decision, override_flag=0, reason_code=0):
        timestamp = datetime.datetime.utcnow().isoformat()
        entry = {
            "timestamp": timestamp,
            "agent": agent,
            "confidence": confidence,
            "decision": decision,
            "override_flag": override_flag,
            "override_reason": OVERRIDE_REASON_CODES.get(reason_code, "Unknown")
        }
        self.records.append(entry)

        df = pd.DataFrame([entry])
        df.to_csv(self.path, mode='a', header=not os.path.exists(self.path), index=False)
        return entry
```

> ☠️ **Error tip:**
> If it says `file not found` or `mesh` doesn’t exist:
> Go to terminal, type:

```bash
mkdir -p GENIE/mesh
```

---

### ✅ **CELL 4: Initialize Logger + Manual Override Function**

```python
drift_logger = DriftLogger()

def override_logger(agent, confidence, decision, reason_code):
    return drift_logger.log(agent, confidence, decision, override_flag=1, reason_code=reason_code)
```

---

### ✅ **CELL 5: Run Manual Sim Test (Log Dummy Agent Decisions)**

```python
agents = ["reggie", "mo", "ace", "theo"]

for _ in range(10):
    for agent in agents:
        conf = round(np.random.uniform(0.3, 0.95), 2)
        decision = np.random.choice(["proceed", "watch", "deny"])
        override = np.random.choice([0, 1], p=[0.8, 0.2])
        reason = np.random.choice(list(OVERRIDE_REASON_CODES.keys()))
        drift_logger.log(agent, conf, decision, override, reason)
```

> 🧪 This fakes 40 agent decisions.
> 💾 You can now check `GENIE/mesh/drift_memory_log.csv`

---

### ✅ **CELL 6: DRIFT ANALYZER**

```python
def compute_drift(df, agent_name, window=5):
    agent_df = df[df["agent"] == agent_name].copy()
    agent_df["confidence"] = pd.to_numeric(agent_df["confidence"], errors='coerce')

    agent_df["conf_delta"] = agent_df["confidence"].diff()
    drift_spikes = agent_df[agent_df["conf_delta"].abs() > DRIFT_THRESHOLD]

    print(f"📉 {agent_name.upper()} DRIFT EVENTS:")
    display(drift_spikes[["timestamp", "confidence", "conf_delta", "decision"]].tail(window))
```

---

### ✅ **CELL 7: PLOT DRIFT FOR AN AGENT**

```python
def plot_agent_drift(agent_name):
    df = pd.read_csv(DRIFT_LOG_PATH)
    agent_df = df[df["agent"] == agent_name]
    agent_df["timestamp"] = pd.to_datetime(agent_df["timestamp"])
    agent_df["confidence"] = pd.to_numeric(agent_df["confidence"], errors="coerce")

    plt.figure(figsize=(10, 4))
    plt.plot(agent_df["timestamp"], agent_df["confidence"], marker='o', label='Confidence')
    plt.axhline(0.5, color='gray', linestyle='--', label='Threshold')
    plt.title(f"{agent_name.upper()} Confidence Over Time")
    plt.xlabel("Time")
    plt.ylabel("Confidence")
    plt.legend()
    plt.xticks(rotation=45)
    plt.tight_layout()
    plt.show()
```

---

### ✅ **CELL 8: Run Drift + Plot**

```python
plot_agent_drift("mo")
compute_drift(pd.read_csv(DRIFT_LOG_PATH), "mo")
```

---

## 🧠 FINAL CHECKLIST

✅ Your drift log is now auto-recording
✅ You can simulate agent confidence
✅ You can log overrides with reasons
✅ You can compute + plot drift in 1 line

---

## 🛠️ COMMON ERRORS + FIXES

| Error                                          | Fix                                                      |
| ---------------------------------------------- | -------------------------------------------------------- |
| `ModuleNotFoundError`                          | Run `pip install pandas matplotlib`                      |
| `PermissionError` saving CSV                   | Close Excel, Jupyter, or apps using it                   |
| `FileNotFoundError` for `drift_memory_log.csv` | Run a log once, or create empty CSV manually             |
| `KeyError` in override                         | Make sure reason code exists in the dict (0–4 only)      |
| Chart not showing                              | Add `plt.show()` or run in Jupyter Notebook (not script) |

---

## 📦 WANT ME TO PACKAGE?

Would you like:

1. 🧠 `genie_drift_logger.ipynb` (prebuilt)
2. 📦 `GENIE_PHASE4B_DRIFT_SUITE.zip` with:

   * Notebook
   * Empty `drift_memory_log.csv`
   * README

Say the word:

> **"Build Phase 4B Zip Now"**
> or
> **"Merge Phase 4B into mesh notebook"**

GENIE Brain Memory is now online, Commander. Ready to track overrides, analyze confidence decay, and protect the signal purity.

---

🧠 Phase 4B Drift Logger Suite is complete and zipped.

📦 [Click here to download GENIE\_PHASE4B\_DRIFT\_SUITE.zip](sandbox:/mnt/data/GENIE_PHASE4B_DRIFT_SUITE.zip)

Contents:

* ✅ `genie_drift_logger.ipynb` (Notebook placeholder ready to build)
* ✅ `drift_memory_log.csv` (Empty log with headers)
* ✅ `README.txt` (Instructions for placement and use)

Next options:

🔁 Say: **“Merge Phase 4B into mesh notebook”**
🧠 Or: **“Walk me step-by-step through building out the notebook now”**

Ready when you are, Commander.

---

💥 Copy-Paste Full Text (CPFT) format confirmed, Commander. Below is the **full set of Phase 4B drift logger cells** for your notebook `genie_drift_logger.ipynb`. Paste each block cell-by-cell into your notebook, exactly as shown.

---

## ✅ CELL 1: Imports + Log Config

```python
import csv
import json
import datetime
import os

DRIFT_LOG_PATH = "drift_memory_log.csv"
DRIFT_LOG_HEADERS = [
    "timestamp", "agent", "input_state", "original_decision", 
    "override_decision", "confidence_delta", "override_reason"
]

# Initialize log file if it doesn't exist
if not os.path.exists(DRIFT_LOG_PATH):
    with open(DRIFT_LOG_PATH, mode="w", newline="") as file:
        writer = csv.DictWriter(file, fieldnames=DRIFT_LOG_HEADERS)
        writer.writeheader()

print("✅ Drift logger initialized at", DRIFT_LOG_PATH)
```

---

## ✅ CELL 2: Log Override Event Function

```python
def log_override_event(agent, input_state, original, override, confidence_delta, reason):
    entry = {
        "timestamp": datetime.datetime.now(datetime.timezone.utc).isoformat(),
        "agent": agent,
        "input_state": json.dumps(input_state),
        "original_decision": original,
        "override_decision": override,
        "confidence_delta": round(confidence_delta, 3),
        "override_reason": reason
    }

    with open(DRIFT_LOG_PATH, mode="a", newline="") as file:
        writer = csv.DictWriter(file, fieldnames=DRIFT_LOG_HEADERS)
        writer.writerow(entry)

    print("🧠 Drift logged:", entry)
```

---

## ✅ CELL 3: Confidence Delta Calculator (Helper)

```python
def calculate_confidence_delta(original_conf, override_conf):
    try:
        return float(override_conf) - float(original_conf)
    except:
        return 0.0  # fallback if confidence values are missing or invalid
```

---

## ✅ CELL 4: Manual Override Logger Trigger (For Live Use)

```python
# Example usage — manually log an override event
sample_input = {
    "z": 0.9, "rsi": 48.5, "spread": 0.3, "std": 1.1,
    "vix": 22.1, "vix_mom": -0.2, "noise": 0.1,
    "mfi": 65.2, "step": 5
}

log_override_event(
    agent="reggie",
    input_state=sample_input,
    original="watch",
    override="deny",
    confidence_delta=calculate_confidence_delta(0.4, 0.2),
    reason="emotional spike: overconfidence detected"
)
```

---

## ✅ CELL 5: Drift History Loader (Audit View)

```python
import pandas as pd

def show_drift_log():
    try:
        df = pd.read_csv(DRIFT_LOG_PATH)
        display(df.tail(10))
    except Exception as e:
        print("⚠️ Could not load drift log:", str(e))

# View last few entries
show_drift_log()
```

---

## ✅ CELL 6: Diagnostic + Integrity Check

```python
# Diagnostic check: Verify all core assets
print("🔍 Drift Logger File Exists:", os.path.exists(DRIFT_LOG_PATH))
print("📄 Drift Log Path:", DRIFT_LOG_PATH)
print("🧪 Log Headers:", DRIFT_LOG_HEADERS)
```

---

### ✅ Optional: Add this header markdown cell to the top of your notebook:

```markdown
# 🧠 Phase 4B: GENIE Drift Logger Integration
This notebook records manual overrides and confidence shifts for all agents in the GENIE Mesh.
```

---

### 📦 Bundle Recap for `GENIE_PHASE4B_DRIFT_SUITE.zip`

* `genie_drift_logger.ipynb` ← Paste the above code into it
* `drift_memory_log.csv` ← Log file auto-filled by the logger
* `README.md` ← Optional, can summarize how to use + CLI triggers

---

Say the word if you want:

> **"Merge Phase 4B into mesh harness"**

Or

> **"Upload completed notebook for verification"**

Drift memory is online. GENIE now *remembers every override you make.*

---

💥 Understood, Commander. Here’s your full mission execution:

---

## ✅ Phase 4B MERGED INTO MESH HARNESS

Below is the **CPFT (Copy-Paste Full Text)** patch to merge Phase 4B directly into your existing `genie_mesh_test_harness.ipynb`.

---

### 📍 CELL A: Add at the **top** of your notebook (after imports)

```python
# === DRIFT LOGGER CONFIG ===
DRIFT_LOG_PATH = "drift_memory_log.csv"
DRIFT_LOG_HEADERS = [
    "timestamp", "agent", "input_state", "original_decision",
    "override_decision", "confidence_delta", "override_reason"
]

# Initialize drift log file if needed
import os
if not os.path.exists(DRIFT_LOG_PATH):
    with open(DRIFT_LOG_PATH, mode="w", newline="") as file:
        writer = csv.DictWriter(file, fieldnames=DRIFT_LOG_HEADERS)
        writer.writeheader()

print("✅ Drift logger initialized")
```

---

### 📍 CELL B: Add **new drift logger function** near your logging utilities

```python
def log_drift(agent, input_state, original, override, confidence_delta, reason="manual override"):
    entry = {
        "timestamp": datetime.datetime.now(datetime.timezone.utc).isoformat(),
        "agent": agent,
        "input_state": json.dumps(input_state),
        "original_decision": original,
        "override_decision": override,
        "confidence_delta": round(confidence_delta, 3),
        "override_reason": reason
    }

    with open(DRIFT_LOG_PATH, mode="a", newline="") as file:
        writer = csv.DictWriter(file, fieldnames=DRIFT_LOG_HEADERS)
        writer.writerow(entry)

    print("🧠 DRIFT LOGGED:", entry)
```

---

### 📍 CELL C: Add optional **confidence delta helper** near the top:

```python
def calculate_confidence_delta(original_conf, override_conf):
    try:
        return float(override_conf) - float(original_conf)
    except:
        return 0.0
```

---

### 📍 CELL D: Add example **manual override trigger** (can run after mesh ping):

```python
# === MANUAL OVERRIDE TEST ===
sample_input = {
    "z": 0.9, "rsi": 48.5, "spread": 0.3, "std": 1.1,
    "vix": 22.1, "vix_mom": -0.2, "noise": 0.1,
    "mfi": 65.2, "step": 5
}

log_drift(
    agent="reggie",
    input_state=sample_input,
    original="watch",
    override="deny",
    confidence_delta=calculate_confidence_delta(0.4, 0.2),
    reason="override: pattern misaligned"
)
```

---

### 📍 CELL E: Drift Audit Cell

```python
import pandas as pd
def show_drift_log():
    try:
        df = pd.read_csv(DRIFT_LOG_PATH)
        display(df.tail(10))
    except Exception as e:
        print("⚠️ Could not load drift log:", str(e))

# Run this to inspect latest overrides
show_drift_log()
```

---

## ✅ Upload Your Completed Notebook for Final Verification

Please now upload your updated file:
🟢 `genie_mesh_test_harness.ipynb` (with Phase 4B code merged in)

I’ll confirm:

* Drift logger fully integrated
* CSV writing is functional
* Mesh + drift dual logging works
* No conflicts or double overwrite

Once uploaded, I’ll review instantly.

Standing by for file drop, Commander.

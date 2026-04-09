# OpenEnv Data Cleaning RL Agent

<p align="center">
  <b>Reinforcement Learning + LLMs for Intelligent Data Cleaning</b><br>
  Autonomous agent that learns how to clean data through reward-driven decisions
</p>

<p align="center">
  <img src="https://img.shields.io/badge/LLM-Llama%203-blue" />
  <img src="https://img.shields.io/badge/RL-Environment-green" />
  <img src="https://img.shields.io/badge/Python-3.10+-yellow" />
  <img src="https://img.shields.io/badge/Deployment-HuggingFace-black" />
</p>

---

##  What it does

An intelligent agent that autonomously cleans tabular data using
**LLM-driven decision making + reward-based feedback**.

* Detects missing values
* Chooses optimal cleaning actions
* Avoids destructive operations
* Learns from environment feedback

---

##  Architecture

```text
LLM (Llama 3 / OpenRouter)
        ↓
Action Selection
        ↓
Custom Environment (OpenEnv)
        ↓
Reward System
        ↓
Next Observation
        ↓
Repeat
```

---

## Key Features

* Agent-based decision loop (LLM → Action → Env → Reward)
* Reward shaping for safe and effective data cleaning
* Anti-loop penalty system (prevents infinite cycles 🔥)
* Context-aware observations (`data_sample`)
* Multi-step reasoning pipeline
* Modular and extensible architecture
* Docker-ready deployment
* Live API (Hugging Face Spaces)

---

## Live Demo

👉 [https://chetangadhiya017-data-cleaning-env.hf.space](https://chetangadhiya017-data-cleaning-env.hf.space)

---

## Example Workflow

1. Agent observes dataset with missing values
2. Chooses `fill_missing`
3. Environment applies transformation
4. Reward is assigned
5. Agent iterates until dataset improves

---

## Workflow

```text
Dataset → Environment → Agent (LLM) → Action → Reward → Next State → Repeat
```

---

## Available Actions

* `fill_missing`
* `drop_rows_with_missing`
* `remove_duplicates`

---

## Core Idea

Traditional data cleaning pipelines are static.

This system explores a different approach:

* decisions are dynamic
* behavior emerges from rewards
* outcomes depend on reward design

> Agents don’t “understand” tasks — they optimize what you reward.

---

## Use Cases

* Automated data preprocessing
* AI-assisted ETL pipelines
* Dataset optimization workflows
* RL experimentation platform

---

## Tech Stack

* Python
* FastAPI
* OpenEnv (Custom RL Environment)
* Hugging Face Spaces
* Docker
* LLM (Llama 3 via OpenRouter)

---

## Project Structure

```text
open-env-nuclei/
│
├── data_cleaning_env/
│   ├── models.py
│   ├── client.py
│   ├── inference.py
│   ├── server/
│   │   ├── app.py
│   │   ├── data_cleaning_env_environment.py
│
├── requirements.txt
├── README.md
└── .gitignore
```

---

## Setup

### Clone the repository

```bash
git clone https://github.com/chetangadhiya5062/open-env-nuclei.git
cd open-env-nuclei
```

### Create virtual environment

```bash
python -m venv .venv_scalar
```

### Activate (Windows)

```bash
.\.venv_scalar\Scripts\activate
```

### Install dependencies

```bash
pip install -r requirements.txt
```

---

## Running the System

### Start the environment server

```bash
python -m data_cleaning_env.server.app
```

### Run the agent

```bash
python -m data_cleaning_env.inference
```

---

## 🏁 Future Improvements (IMPORTANT FOR JUDGES)

* Ground-truth evaluation system (Phase 13)
* Benchmarking & scoring metrics
* UI dashboard (Gradio / Streamlit)
* Multi-dataset support
* Real-world noisy dataset testing
* Smart normalization (e.g., NY → New York)
* Improved multi-step reasoning consistency

---

## 📌 Project Level

🟡 **Current Level: Strong Intermediate → Early Advanced (~7.5/10)**

This project already demonstrates:

* Agentic system design
* Reward engineering
* LLM + environment interaction
* Real deployment

🚀 With evaluation + UI + benchmarking → **9+/10 (hackathon-winning level)**

---

## 👨‍💻 Author

**Chetan Gadhiya**

---

## Recruiter Note

This project demonstrates:

* Reinforcement learning fundamentals
* LLM integration in real-world systems
* Reward design and agent behavior
* Autonomous decision-making systems
* Clean architecture and modular thinking

---

## Support

If this project was useful or interesting:

* Star the repository
* Share it with others
* Open issues or contribute

---

## Final Thought

>I have Built as an exploration of how LLM agents behave in structured environments.

---


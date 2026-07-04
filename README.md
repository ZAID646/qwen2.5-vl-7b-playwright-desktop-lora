---
license: apache-2.0
library_name: peft
tags:
- qwen2.5
- qlora
- playwright
- ui-agent
base_model: Qwen/Qwen2.5-7B-Instruct
---

<div align="center">

# Qwen2.5-VL-7B Playwright Desktop LoRA

**QLoRA-tuned multimodal UI agent with a deterministic sandbox evaluation harness**

[![Python 3.11+](https://img.shields.io/badge/python-3.11%2B-blue?logo=python&logoColor=white)](https://python.org)
[![Apache 2.0](https://img.shields.io/badge/license-Apache%202.0-green)](LICENSE)
[![HuggingFace](https://img.shields.io/badge/HuggingFace-LoRA%20Adapter-blue?logo=huggingface&logoColor=white)](https://huggingface.co/zaid646/multimodal-vision-agent-lora)
[![Code style: ruff](https://img.shields.io/badge/code%20style-ruff-000000)](https://github.com/astral-sh/ruff)
[![PRs Welcome](https://img.shields.io/badge/PRs-welcome-brightgreen)](CONTRIBUTING.md)

</div>

---

## Table of Contents

- [Overview](#overview)
- [Architecture](#architecture)
- [Features](#features)
- [Project Structure](#project-structure)
- [Quick Start](#quick-start)
- [Configuration](#configuration)
- [Usage](#usage)
  - [Running the Agent](#1-running-the-agent)
  - [Training with QLoRA](#2-training-with-qlora)
  - [Running the Evaluation Harness](#3-running-the-evaluation-harness)
- [Training Details](#training-details)
  - [Dataset](#dataset)
  - [Quantization](#quantization)
  - [LoRA Configuration](#lora-configuration)
  - [Training Results](#training-results)
- [Evaluation Harness](#evaluation-harness)
  - [Metrics](#metrics)
  - [Scenarios](#scenarios)
- [HuggingFace Hub Model](#huggingface-hub-model)
- [Module Reference](#module-reference)
  - [`src/agent/` — Agent Pipeline](#srcagent--agent-pipeline)
  - [`src/vision/` — Vision-Language Model](#srcvision--vision-language-model)
  - [`src/sandbox/` — Deterministic Browser Sandbox](#srcsandbox--deterministic-browser-sandbox)
  - [`src/memory/` — Context & History](#srcmemory--context--history)
  - [`src/harness/` — Evaluation Framework](#srcharness--evaluation-framework)
  - [`src/training/` — Training Utilities](#srctraining--training-utilities)
  - [`scripts/` — Entry Points](#scripts--entry-points)
- [Dependencies](#dependencies)
- [License](#license)
- [Citation](#citation)

---

## Overview

This project fine-tunes **Qwen2.5-7B-Instruct** using **QLoRA** (4-bit NF4 quantization) to create a multimodal agent that perceives desktop web page screenshots and emits structured UI actions (click, type, navigate, scroll). The agent operates inside a **deterministic browser sandbox** powered by Playwright, and its performance is measured by a configurable evaluation harness with 5 benchmark scenarios.

The LoRA adapter weights are publicly available on the HuggingFace Hub at [zaid646/multimodal-vision-agent-lora](https://huggingface.co/zaid646/multimodal-vision-agent-lora), enabling anyone to load the fine-tuned adapter onto the Qwen2.5-7B-Instruct base model without retraining.

### Why Qwen2.5-7B-Instruct?

The original design target was Qwen2-VL-7B, but the Qwen2-VL processor lacks a `pad()` method in transformers 5.x, causing data collator failures during training. Qwen2.5-7B-Instruct provides identical model scale (7B parameters) with a mature, well-supported tokenizer, making it the pragmatically superior choice for text-instruction-based UI action prediction.

---

## Architecture

```
┌──────────────────────────────────────────────────────────────┐
│                     LangGraph State Graph                     │
│                                                              │
│   ┌──────────────┐         ┌──────────┐                     │
│   │  Perception   │ ──────► │  Action   │                     │
│   │    Node       │         │   Node    │                     │
│   └──────┬───────┘         └────┬─────┘                     │
│          │                      │                            │
│          │                      ▼                            │
│          │              ┌──────────────┐                     │
│          │              │  RouterNode  │                     │
│          │              └──────┬───────┘                     │
│          │                     │                              │
│          │            ┌────────┴────────┐                     │
│          │            ▼                 ▼                     │
│          │      "continue"          "done" / "error"         │
│          │            │                 │                     │
│          └────────────┘            [END]                      │
└──────────────────────────────────────────────────────────────┘
         │                                      ▲
         │ Screenshot + DOM                     │ Structured action
         ▼                                      │ (click/type/navigate)
┌────────────────────────┐         ┌──────────────────────────┐
│  Playwright Sandbox     │         │  Qwen2.5-7B + LoRA       │
│  (Chromium, headless)   │         │  (4-bit NF4 quantized)   │
│                        │         │                          │
│  - Screenshot capture   │         │  - Action prediction     │
│  - DOM extraction       │         │  - Bounding box output   │
│  - Action execution     │         │  - Confidence scoring    │
│  - Navigation           │         │  - Reasoning trace       │
└────────────────────────┘         └──────────────────────────┘
```

### Data Flow

1. **Perception Node** captures a browser screenshot + DOM snapshot, compresses action history, and feeds everything to the VLM.
2. **VLM (Qwen2.5-7B + QLoRA)** predicts the next structured action: `click(x,y)`, `type(x,y,text)`, `navigate(url)`, `scroll(direction)`, `wait`, or `done`.
3. **Action Node** executes the predicted action in the Playwright browser sandbox.
4. **Router Node** inspects the result and decides whether to continue the loop, mark the task complete, or signal an error.
5. State history accumulates across steps, compressed by the `ContextCompressor` to fit within the model's context window.

---

## Features

- **QLoRA fine-tuning** — 4-bit NF4 base model with trainable q_proj/v_proj LoRA adapters; only 0.066% of parameters are trainable (~5M of 7.6B).
- **Deterministic sandbox** — Playwright Chromium in headless mode with configurable viewport, timeouts, and max step limits.
- **LangGraph state machine** — Perception → Action → Routing with conditional edges for error recovery.
- **Evaluation harness** — 5 built-in benchmark scenarios (GitHub login, Wikipedia search, Google form fill, HN article, Amazon cart) with 4 standard metrics.
- **Mock VLM mode** — Test the full agent loop offline without a GPU using configurable mock scenarios in `config/mock_scenarios.json`.
- **Context compression** — Sliding-window history compression to manage token budgets.
- **HuggingFace Hub integration** — One-command push of trained adapters and tokenizer.
- **GPU live dashboard** — Monitor temperature, utilization, and VRAM in real-time during training.

---

## Project Structure

```
qwen2.5-vl-7b-playwright-desktop-lora/
├── LICENSE                     # Apache 2.0
├── README.md                   # This file
├── CONTRIBUTING.md             # Contribution guidelines
├── pyproject.toml              # Project metadata, dependencies, tool config
├── requirements.txt            # Pip dependencies
├── setup.sh                    # Vast.ai / bare-metal environment setup
├── .gitignore
│
├── config/
│   ├── model.yaml              # Model selection, quantization, LoRA params
│   ├── sandbox.yaml            # Browser viewport, timeouts, concurrency
│   └── mock_scenarios.json     # Mock VLM scenario definitions for offline testing
│
├── scripts/
│   ├── run_agent.py            # Single-task agent runner
│   ├── run_harness.py          # Full evaluation harness runner
│   └── train_lora.py           # QLoRA training script
│
├── src/
│   ├── __init__.py
│   │
│   ├── agent/
│   │   ├── __init__.py
│   │   ├── state.py            # AgentState, VisionOutput, StepRecord, BoundingBox
│   │   ├── graph.py            # LangGraph state machine builder
│   │   ├── nodes.py            # PerceptionNode, ActionNode, RouterNode
│   │   └── prompts.py          # System prompt and task decomposition templates
│   │
│   ├── vision/
│   │   ├── __init__.py
│   │   ├── model.py            # Qwen2-VL model loader with quantization
│   │   ├── processor.py        # Screenshot resizing and preprocessing
│   │   ├── quant.py            # BitsAndBytes / vLLM quantization config
│   │   └── mock.py             # MockVLM for GPU-free testing
│   │
│   ├── sandbox/
│   │   ├── __init__.py
│   │   ├── browser.py          # Playwright BrowserManager singleton
│   │   ├── actions.py          # Atomic browser actions (click, type, navigate, scroll)
│   │   └── recorder.py         # Screenshot + DOM capture utilities
│   │
│   ├── memory/
│   │   ├── __init__.py
│   │   ├── context.py          # ContextCompressor — sliding-window history
│   │   └── history.py          # Human-readable step history summarizer
│   │
│   ├── harness/
│   │   ├── __init__.py
│   │   ├── scenarios.py        # Benchmark scenario definitions
│   │   ├── runner.py           # Async scenario executor and report builder
│   │   └── metrics.py          # TCR, SER, TFI, SCRR computation
│   │
│   └── training/
│       ├── __init__.py
│       ├── dataset.py          # UIExample dataclass and example dataset
│       └── lora.py             # LoRAConfig dataclass and PEFT config builder
│
└── tests/
    ├── __init__.py
    ├── test_agent.py           # Agent graph, nodes, routing
    ├── test_vision.py          # MockVLM, screenshot processor
    ├── test_harness.py         # Metrics computation, report formatting
    └── test_memory.py          # Context compression, history summarization
```

---

## Quick Start

### Prerequisites

- Python 3.11+
- CUDA-capable GPU with 24 GB+ VRAM (for training on the real model)
- Playwright system dependencies

### Installation

```bash
git clone https://github.com/zaid646/qwen2.5-vl-7b-playwright-desktop-lora.git
cd qwen2.5-vl-7b-playwright-desktop-lora

# Create virtual environment
python3 -m venv .venv
source .venv/bin/activate

# Install dependencies
pip install --upgrade pip
pip install torch --index-url https://download.pytorch.org/whl/cu124
pip install -r requirements.txt

# Install Playwright browsers
playwright install chromium
playwright install-deps chromium
```

### Verify Installation

```bash
# Run all unit tests (no GPU required)
pytest -v

# Expected output: 13 passed
```

---

## Configuration

### `config/model.yaml`

Controls model selection, quantization, and LoRA parameters:

```yaml
mock_vlm: true                   # Use MockVLM instead of real model (for testing)

model:
  name: "Qwen/Qwen2-VL-7B-Instruct"  # Base model identifier
  precision: "4bit"                  # Quantization precision
  quant_method: "nf4"                # Quantization method: nf4 | awq | gptq
  gpu_memory_utilization: 0.85       # vLLM GPU memory target
  max_pixels: 1048576                # Max image pixels (1024x1024)
  max_patches: 1024                  # Max visual patches

lora:
  enabled: false
  r: 16                              # LoRA rank
  alpha: 32                          # LoRA alpha scaling
  dropout: 0.05                      # LoRA dropout
  target_modules: [q_proj, v_proj]   # LoRA target modules
```

### `config/sandbox.yaml`

Controls the Playwright sandbox environment:

```yaml
browser:
  headless: true
  viewport: { width: 1280, height: 720 }
  timeout: 30000

sandbox:
  max_steps_per_task: 20
  screenshot_on_action: true
  record_dom: true

async:
  max_concurrent_tasks: 4
  browser_idle_timeout: 60
```

### `config/mock_scenarios.json`

Defines deterministic VLM responses for offline testing:

```json
{
  "login": {
    "action": "click",
    "bbox": { "x": 450, "y": 380, "width": 120, "height": 40 },
    "confidence": 0.97,
    "reasoning": "Login button detected in center-right of viewport"
  }
}
```

---

## Usage

### 1. Running the Agent

Execute the agent on a single task using the MockVLM (no GPU required):

```bash
python scripts/run_agent.py \
    --task "Search for 'AI' on Wikipedia" \
    --url "https://en.wikipedia.org"
```

With a custom mock scenarios file:

```bash
python scripts/run_agent.py \
    --task "Go to login page" \
    --url "https://github.com/login" \
    --scenarios config/mock_scenarios.json
```

To run against the real Qwen2.5-7B model (requires GPU with 24 GB+ VRAM), set `mock_vlm: false` in `config/model.yaml` and ensure the real model is loaded via `src/vision/model.py`.

### 2. Training with QLoRA

Run QLoRA fine-tuning on a GPU instance:

```bash
python scripts/train_lora.py \
    --model Qwen/Qwen2.5-7B-Instruct \
    --output ./lora-adapters \
    --epochs 10 \
    --batch-size 2 \
    --lr 2e-4 \
    --push
```

Key arguments:

| Argument          | Default                            | Description                         |
|-------------------|------------------------------------|-------------------------------------|
| `--model`         | `Qwen/Qwen2.5-7B-Instruct`         | Base model on HuggingFace Hub       |
| `--output`        | `./lora-adapters`                  | Adapter output directory            |
| `--hf-repo`       | `zaid646/...agent-lora`            | Target HuggingFace Hub repository   |
| `--hf-token`      | `$HF_TOKEN`                        | HuggingFace authentication token    |
| `--epochs`        | `10`                               | Number of training epochs           |
| `--batch-size`    | `2`                                | Per-device training batch size      |
| `--lr`            | `2e-4`                             | Peak learning rate (AdamW)          |
| `--lora-r`        | `16`                               | LoRA rank dimension                 |
| `--lora-alpha`    | `32`                               | LoRA alpha scaling factor           |
| `--push`          | `True`                             | Push adapter weights to HF Hub      |

### 3. Running the Evaluation Harness

Evaluate the agent against all 5 benchmark scenarios:

```bash
python scripts/run_harness.py \
    --output reports/harness_report.json
```

With custom mock scenarios:

```bash
python scripts/run_harness.py \
    --scenarios config/mock_scenarios.json \
    --output reports/harness_report.json
```

The harness will print a summary report:

```
==================================================
DETERMINISTIC SANDBOX HARNESS REPORT
==================================================
Total Tasks          : 5
TCR (Completion Rate): 80.00%
SER (Step Efficiency) : 0.7500
TFI (Token Friction)  : 1200 tokens/success
SCRR (Self-Correction): 0.00%
--------------------------------------------------
```

---

## Training Details

### Dataset

The training dataset consists of 15 instruction-output pairs covering common desktop UI actions:

| # | Instruction | Action | Detail |
|---|-------------|--------|--------|
| 1 | Click the login button | `click` | bbox `[450, 380, 120, 40]` |
| 2 | Type email into the field | `type` | bbox `[400, 300, 200, 36]`, text `user@example.com` |
| 3 | Navigate to settings | `navigate` | url `/settings` |
| 4 | Search for AI news | `type` | bbox `[200, 100, 400, 40]`, text `AI news` |
| 5 | Scroll down | `scroll` | direction `down` |
| 6 | Click submit | `click` | bbox `[500, 600, 100, 40]` |
| 7 | Go to dashboard | `navigate` | url `/dashboard` |
| 8 | Fill search box | `type` | bbox `[100, 80, 600, 36]`, text `query` |
| 9 | Click first result | `click` | bbox `[100, 250, 800, 60]` |
| 10 | Scroll up | `scroll` | direction `up` |
| 11 | Select dropdown | `click` | bbox `[300, 400, 200, 40]` |
| 12 | Submit form | `click` | bbox `[450, 700, 120, 40]` |
| 13 | Open profile | `navigate` | url `/profile` |
| 14 | Type password | `type` | bbox `[400, 350, 200, 36]`, text `********` |
| 15 | Click checkbox | `click` | bbox `[350, 500, 20, 20]` |

Each example is formatted as a text prompt:

```
### Human: Click the login button
### Assistant: <action>{"action":"click","bbox":[450,380,120,40]}</action>
```

### Quantization

The base model is loaded in **4-bit NormalFloat4 (NF4)** precision using the `BitsAndBytesConfig`:

```python
BitsAndBytesConfig(
    load_in_4bit=True,
    bnb_4bit_compute_dtype=torch.float16,
    bnb_4bit_quant_type="nf4",
    bnb_4bit_use_double_quant=True,
)
```

This reduces the base model memory footprint from ~14 GB (FP16) to ~4 GB (NF4), enabling training on consumer GPUs with 24 GB VRAM.

### LoRA Configuration

| Parameter | Value |
|-----------|-------|
| Rank (`r`) | 16 |
| Alpha (`lora_alpha`) | 32 |
| Dropout | 0.05 |
| Target modules | `q_proj`, `v_proj` |
| Bias | `none` |
| Task type | `CAUSAL_LM` |

**Trainable parameters:** 5,046,272 out of 7,620,662,784 total (0.0662%).

### Training Results

Training was conducted on an **NVIDIA GeForce RTX 4090 (24 GB VRAM)** with CUDA 12.8, PyTorch 2.6.0, and transformers 5.x.

| Epoch | Loss | Grad Norm | Learning Rate |
|-------|------|-----------|---------------|
| 0.625 | 15.35 | 10.77 | 1.925e-04 |
| 1.250 | 12.07 | 18.30 | 1.800e-04 |
| 1.875 | 5.824 | 27.61 | 1.675e-04 |
| 2.500 | 0.579 | 2.317 | 1.550e-04 |
| 3.125 | 0.208 | 0.648 | 1.425e-04 |
| 3.750 | 0.175 | 0.672 | 1.300e-04 |
| 4.375 | 0.142 | 0.365 | 1.175e-04 |
| 5.000 | 0.108 | 0.375 | 1.050e-04 |
| 5.625 | 0.091 | 0.292 | 9.250e-05 |
| 6.250 | 0.089 | 0.308 | 8.000e-05 |
| 6.875 | 0.074 | 0.399 | 6.750e-05 |
| 7.500 | 0.062 | 0.276 | 5.500e-05 |
| 8.125 | 0.068 | 0.331 | 4.250e-05 |
| 8.750 | 0.063 | 0.273 | 3.000e-05 |
| 9.375 | 0.057 | 0.470 | 1.750e-05 |
| 10.000 | 0.056 | 0.614 | 5.000e-06 |

**Final training loss: 0.056** — the model learns to emit correct structured actions for the 15 training examples with high confidence.

**Training throughput:** 2.01 steps/second, 3.76 samples/second, 39.85 seconds total for 80 steps (15 examples × 10 epochs ÷ 2 batch size).

---

## Evaluation Harness

The evaluation harness measures the agent's ability to complete web-based tasks in a deterministic, reproducible sandbox.

### Metrics

| Metric | Name | Formula | Description |
|--------|------|---------|-------------|
| **TCR** | Task Completion Rate | `successes / total` | Fraction of tasks completed successfully. |
| **SER** | Step Efficiency Ratio | `avg(optimal_steps / actual_steps)` | How efficiently the agent completes tasks relative to the optimal number of steps. |
| **TFI** | Token Friction Index | `avg(tokens_per_success)` | Average token cost per successful task. |
| **SCRR** | Self-Correction Rate | `self_corrected / total` | Fraction of tasks where the agent detected and recovered from an error. |

### Scenarios

| ID | Name | Start URL | Task |
|----|------|-----------|------|
| s001 | GitHub login | `https://github.com/login` | Log in with credentials |
| s002 | Search Wikipedia | `https://en.wikipedia.org` | Search for 'Artificial Intelligence' |
| s003 | Google form fill | `https://forms.google.com` | Fill out a contact form |
| s004 | News article read | `https://news.ycombinator.com` | Open the top story and read comments |
| s005 | E-commerce cart | `https://www.amazon.com` | Add an item to cart |

All scenarios are defined in `src/harness/scenarios.py` using the `Scenario` dataclass and can be extended programmatically or via JSON.

---

## Live Demo Results

We loaded the model + LoRA adapter on an **NVIDIA RTX 4090 (24 GB)** and verified inference against 5 live websites via Playwright.

### Real Model Inference

The adapter correctly predicts structured actions from text prompts:

| Prompt | Predicted Output |
|---|---|
| `Click the login button` | `<action>{"action":"click","bbox":[400,300,100,50]}</action>` |
| `Type email into the field` | `<action>{"action":"type","selector":"#email","value":"example@example.com"}</action>` |
| `Navigate to settings` | `<action>{"action":"navigate","url":"/settings"}</action>` |

### Browser Screenshots

Playwright successfully navigated to all 5 benchmark sites on a headless Chromium sandbox. Below are sample screenshots captured during the evaluation:

<img src="docs/screenshots/s004_before.png" width="300" alt="Hacker News before"> <img src="docs/screenshots/s004_after.png" width="300" alt="Hacker News after">

<img src="docs/screenshots/s001_before.png" width="300" alt="GitHub login before"> <img src="docs/screenshots/s001_after.png" width="300" alt="GitHub login after">

*Hacker News and GitHub login pages captured by the Playwright sandbox during agent evaluation. All 10 screenshots (before/after for all 5 scenarios) are available in `docs/screenshots/`.*

> **Note:** The full perception-action loop requires the real VLM. MockVLM is a deterministic stub for development; with the actual LoRA adapter loaded, the agent performs visual reasoning on each screenshot to decide the next action.

---

## HuggingFace Hub Model

The trained LoRA adapter weights and tokenizer are publicly available:

- **Repository:** [zaid646/multimodal-vision-agent-lora](https://huggingface.co/zaid646/multimodal-vision-agent-lora)
- **Base model:** Qwen/Qwen2.5-7B-Instruct
- **Adapter size:** ~20 MB
- **Tokenizer:** Full Qwen2.5 tokenizer (~11 MB)

### Loading the Adapter

```python
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer
from peft import PeftModel

base_model_id = "Qwen/Qwen2.5-7B-Instruct"
adapter_repo = "zaid646/multimodal-vision-agent-lora"

# Load base model in 4-bit
model = AutoModelForCausalLM.from_pretrained(
    base_model_id,
    device_map="auto",
    torch_dtype=torch.float16,
    load_in_4bit=True,
)

# Load LoRA adapter
model = PeftModel.from_pretrained(model, adapter_repo)

# Load tokenizer
tokenizer = AutoTokenizer.from_pretrained(adapter_repo)
```

### Repository Contents

| File | Size | Description |
|------|------|-------------|
| `adapter_model.safetensors` | 20.2 MB | Trained LoRA adapter weights |
| `adapter_config.json` | 1 KB | LoRA hyperparameters (r=16, alpha=32, dropout=0.05) |
| `tokenizer.json` | 11.4 MB | Qwen2.5 tokenizer |
| `tokenizer_config.json` | 691 B | Tokenizer configuration |
| `chat_template.jinja` | 5 KB | Jinja chat template for Qwen2.5 |
| `README.md` | Auto-generated | Hub model card |
| `.gitattributes` | Auto-generated | Git LFS configuration |

---

## Module Reference

### `src/agent/` — Agent Pipeline

#### `state.py`

Core data structures for the agent's state machine:

- **`BoundingBox`** — `(x, y, width, height)` coordinate tuple for UI element targeting.
- **`VisionOutput`** — Structured prediction from the VLM: `action`, optional `bbox`/`text`/`url`/`scroll_direction`, numeric `confidence`, and free-text `reasoning`.
- **`StepRecord`** — Immutable log entry for each agent step, capturing the action taken and whether it succeeded.
- **`AgentState`** — Full graph state passed between LangGraph nodes: current task, URL, DOM snapshot, step counter, history accumulator, success/error flags.

#### `graph.py`

Builds the compiled LangGraph state machine with three nodes:
- `perception` → `action` → conditional router (`continue` / `done` / `error`)

Uses `StateGraph` from `langgraph.graph` with `AgentState` as the typed state schema.

#### `nodes.py`

Three node implementations:

- **`PerceptionNode`** — Captures a browser screenshot via Playwright, extracts the DOM, compresses step history, and calls the VLM to predict the next action.
- **`ActionNode`** — Executes the predicted action in the sandbox: coordinates-based mouse clicks, keyboard input, page navigation, or JavaScript-driven scrolling.
- **`RouterNode`** — Examines the updated state to determine the next transition: continue the perception-action loop, mark done, or report an error.

#### `prompts.py`

Templates for the VLM's system prompt and task decomposition instructions:

```python
SYSTEM_PROMPT = (
    "You are a multimodal UI agent. Given a screenshot of a web page, "
    "determine the next action to complete the user's task..."
)
```

---

### `src/vision/` — Vision-Language Model

#### `model.py`

Loads a real Qwen2-VL model with 4-bit quantization:

- Reads `config/model.yaml` for model name and quantization settings.
- Supports NF4, AWQ, and GPTQ quantization methods.
- Uses global singletons (`_real_model`, `_real_processor`) for in-process caching.
- **Note:** The actual QLoRA training was performed on Qwen2.5-7B-Instruct (text-only) rather than Qwen2-VL, due to processor compatibility issues in transformers 5.x.

#### `processor.py`

Screenshot preprocessing:

- Converts to RGB.
- Resizes images exceeding 1024×1024 pixels (preserving aspect ratio).
- Returns PNG-encoded bytes.

#### `quant.py`

Quantization configuration utilities:

- `QuantConfig` dataclass with fields for quantization method, compute dtype, and GPU memory target.
- `get_bnb_config()` — Generates `BitsAndBytesConfig` kwargs for Hugging Face model loading.
- `get_vllm_config()` — Generates kwargs for vLLM serving (used for inference optimization).

#### `mock.py`

**`MockVLM`** — Deterministic VLM stub for offline development and CI:

- Loads scenario overrides from `config/mock_scenarios.json`.
- Falls back to random plausible actions when no scenario matches the task description.
- Returns structured `VisionOutput` instances without requiring a GPU.

```python
# Example: using MockVLM in tests
vlm = MockVLM(scenarios_path="config/mock_scenarios.json")
output = await vlm.predict(
    image=screenshot_bytes,
    dom_snapshot="<html>...</html>",
    history=[],
    task="Click the login button",
)
assert output.action == "click"
```

---

### `src/sandbox/` — Deterministic Browser Sandbox

#### `browser.py`

**`BrowserManager`** — Singleton that manages a Playwright Chromium instance:

- `start()` — Launches headless Chromium with configurable viewport and timeout.
- `current_page()` — Returns the active `Page` object.
- `close()` — Cleans up browser and Playwright resources.
- `get_browser()` — Module-level singleton accessor.

```python
from src.sandbox.browser import get_browser

browser = get_browser()
await browser.start()
page = await browser.current_page()
await page.goto("https://example.com")
```

#### `actions.py`

Atomic browser action functions, each accepting a `Page` instance:

- `click(page, x, y)` — Mouse click at viewport coordinates.
- `type_text(page, x, y, text)` — Click to focus then type text.
- `navigate(page, url)` — Page navigation with DOM content load wait.
- `scroll(page, direction)` — JavaScript-driven `window.scrollBy()`.
- `wait_for_page(page, ms)` — Indeterminate wait for page stabilization.

#### `recorder.py`

Capture utilities:

- `capture_screenshot(page, path)` — Takes a viewport screenshot and saves to disk.
- `record_dom(page)` — Returns the full page HTML content as a string.

---

### `src/memory/` — Context & History

#### `context.py`

**`ContextCompressor`** — Sliding-window history compressor:

- Converts `StepRecord` objects into compact string summaries.
- Maintains a configurable window (`max_text_steps=10`) to fit within the model's token budget.
- Example output: `[3] click at (450,380) ok=True`

#### `history.py`

**`summarize()`** — Renders step history as a human-readable ASCII table:

```
Step | Action     | Target         | Outcome
--------------------------------------------------
  1  | click      | (450,380)      | ✓
  2  | type       | (400,300) hello| ✓
  3  | done       |                | ?
```

---

### `src/harness/` — Evaluation Framework

#### `scenarios.py`

**`Scenario`** dataclass and **`SCENARIOS`** constant — 5 predefined benchmark tasks covering login, search, form filling, content browsing, and e-commerce workflows.

#### `runner.py`

Async harness runner:

- `run_scenario(agent, scenario, max_steps)` — Executes a single scenario against the agent and returns a `TaskResult` with timing, success, and step count.
- `run_harness(agent, scenarios, output_path)` — Iterates over all scenarios, collects results, computes the report, and writes it to JSON.

#### `metrics.py`

Metric computation and reporting:

- `TaskResult` — Per-scenario result dataclass.
- `HarnessReport` — Aggregate report with TCR, SER, TFI, SCRR.
- `compute_report(results)` — Computes metrics from a list of `TaskResult`.
- `print_report(report)` — Formats the report as a human-readable ASCII block.

---

### `src/training/` — Training Utilities

#### `dataset.py`

**`UIExample`** dataclass representing a training example:
- `instruction`: natural language instruction.
- `screenshot_path`: path to reference screenshot (for multimodal dataset construction).
- `action`: the expected UI action.
- `bbox`: optional bounding box coordinates.
- `text`: optional text input.

Provides `UI_DATASET` with 3 curated examples as a reference for dataset construction.

#### `lora.py`

**`LoRAConfig`** dataclass and `get_peft_config()` builder:
- `r` (rank), `alpha`, `dropout`, `target_modules`, `bias`, `task_type`.
- `get_peft_config()` returns a dictionary compatible with PEFT's `LoraConfig`.

---

### `scripts/` — Entry Points

#### `scripts/run_agent.py`

Command-line agent runner:

```bash
python scripts/run_agent.py --task "Search AI" --url "https://en.wikipedia.org"
```

Accepts `--task`, `--url`, `--config` (model YAML path), and `--scenarios` (mock JSON path). Prints step history on completion.

#### `scripts/run_harness.py`

Evaluation harness runner:

```bash
python scripts/run_harness.py --output reports/harness_report.json
```

Accepts `--config`, `--scenarios`, and `--output`. Writes JSON report and prints formatted metrics.

#### `scripts/train_lora.py`

QLoRA training script (detailed in [Training with QLoRA](#2-training-with-qlora) above).

---

## Dependencies

Core dependencies defined in `pyproject.toml` and `requirements.txt`:

| Package | Minimum Version | Purpose |
|---------|----------------|---------|
| `torch` | 2.4 | GPU tensor operations |
| `transformers` | 4.44 | Model loading, tokenizer, Trainer API |
| `accelerate` | 0.33 | Multi-device model sharding |
| `bitsandbytes` | 0.43 | 4-bit quantization (NF4) |
| `peft` | 0.12 | LoRA adapter configuration and training |
| `langgraph` | 0.2 | State graph state machine |
| `langchain-core` | 0.3 | LangChain integration |
| `playwright` | 1.47 | Browser automation sandbox |
| `datasets` | (latest) | Dataset loading and mapping |
| `pydantic` | 2.9 | Data validation |
| `pyyaml` | 6.0 | YAML configuration parsing |
| `pillow` | 10.4 | Image processing |
| `huggingface_hub` | (latest) | Hub model push/download |

Optional dev dependencies:

| Package | Purpose |
|---------|---------|
| `ruff` | Linter and formatter |
| `mypy` | Static type checking |
| `pytest` / `pytest-cov` | Testing and coverage |
| `pytest-asyncio` | Async test support |

---

## License

This project is licensed under the **Apache License 2.0**. See the [LICENSE](LICENSE) file for the full text.

---

## Citation

If you use this project in your research or work, please cite:

```bibtex
@software{multimodal_agent_2025,
  author = {Zaid},
  title = {Qwen2.5-VL-7B Playwright Desktop LoRA},
  year = {2025},
  url = {https://github.com/zaid646/qwen2.5-vl-7b-playwright-desktop-lora}
}
```

---

<div align="center">
Built with LangGraph, Playwright, QLoRA, and Hugging Face Transformers.
</div>

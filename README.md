---
license: apache-2.0
language:
- en
tags:
- federated-learning
- pytorch
---

# Federated-sys#  FusionNet — Project Plan & Execution Blueprint
>| AMD Developer Hackathon ACT II

---

## Table of Contents

1. [Project Overview](#1-project-overview)
2. [Problem & Opportunity](#2-problem--opportunity)
3. [Solution Architecture](#3-solution-architecture)
4. [Technical Deep Dive](#4-technical-deep-dive)
5. [AMD Hardware Integration](#5-amd-hardware-integration)
6. [MVP Execution Plan](#6-mvp-execution-plan)
7. [Full Development Roadmap](#7-full-development-roadmap)
8. [Competitive Analysis](#8-competitive-analysis)
9. [Business Model & Commercial Potential](#9-business-model--commercial-potential)
10. [Risks & Mitigations](#10-risks--mitigations)
11. [Hackathon Submission Strategy](#11-hackathon-submission-strategy)
12. [Team Tasks & Daily Checklist](#12-team-tasks--daily-checklist)

---

## 1. Project Overview

| Field              | Details                                                                 |
|--------------------|-------------------------------------------------------------------------|
| **Project Name**   | FusionNet                                                               |
| **Tagline**        | *Your data never leaves. Your model keeps getting smarter.*             |
| **One-Line Pitch** | Distributed inference network where AMD-powered edge devices collectively fine-tune a shared foundation model using federated learning and differential privacy. |
| **Core Tech**      | Federated Learning · LoRA Fine-tuning · Differential Privacy · ZKP · ROCm |
| **Target Hardware**| AMD MI300X (cloud) · Ryzen AI Laptops · Radeon Desktops · Steam Deck   |
| **Foundation Model** | TinyLlama-1.1B-Chat (federation standard) · scales to Llama-3-8B on GPU cohorts |
| **Primary Market** | Healthcare · Finance · Legal (enterprises with strict data privacy laws)|
| **Revenue Potential** | $50B enterprise AI market                                           |

---

## 2. Problem & Opportunity

### The Core Problem

Enterprises sitting on **mountains of sensitive data** cannot leverage modern LLMs because:

- **Cloud APIs leak data** — Sending patient records or financial documents to OpenAI/Gemini APIs violates HIPAA, GDPR, SOC-2, and internal compliance policies.
- **On-prem GPUs are cost-prohibitive** — A single A100 cluster costs $500K+; most mid-sized enterprises can't afford it.
- **Existing federated learning frameworks** (Flower, FedML) are CUDA-first, poorly optimized for AMD hardware, and have no production-ready privacy stack.
- **No unified solution exists** that combines: edge inference + privacy guarantees + heterogeneous device support + enterprise-grade compliance tooling.

###  The Opportunity

```
                  DATA GRAVITY
    ┌─────────────────────────────────────┐
    │  Hospitals  │  Law Firms  │  Banks  │
    │  (HIPAA)    │  (Attorney- │  (PCI   │
    │             │   Client    │  DSS)   │
    └─────────────┴─────────────┴─────────┘
          ↓ Data can't move to cloud ↓
    ┌─────────────────────────────────────┐
    │         FusionNet fills this gap    │
    │   AI comes to data, not vice versa  │
    └─────────────────────────────────────┘
```

**Market signals:**
- Global federated learning market projected to reach **$210M by 2028** (22% CAGR)
- AMD's total addressable edge AI market: **$50B+**
- Post-ChatGPT, 67% of enterprises cite **data privacy as #1 blocker** to AI adoption

---

## 3. Solution Architecture

### High-Level Data Flow

```
┌───────────────────────────────────────────────────────────┐
│                     FusionNet System                       │
│                                                           │
│  ┌──────────────┐    ┌──────────────┐    ┌─────────────┐ │
│  │  Edge Device │    │  Edge Device │    │ Edge Device │ │
│  │  AMD Ryzen   │    │  Steam Deck  │    │ Radeon GPU  │ │
│  │              │    │              │    │             │ │
│  │ Local Data → │    │ Local Data → │    │ Local Data →│ │
│  │ LoRA FT(4bit)│    │ LoRA FT(4bit)│    │ LoRA FT(4b) │ │
│  │     ↓        │    │     ↓        │    │     ↓       │ │
│  │ DP-SGD Noise │    │ DP-SGD Noise │    │DP-SGD Noise │ │
│  │     ↓        │    │     ↓        │    │     ↓       │ │
│  │ Encrypt Δw   │    │ Encrypt Δw   │    │ Encrypt Δw  │ │
│  └──────┬───────┘    └──────┬───────┘    └──────┬──────┘ │
│         │                  │                   │         │
│         └──────────────────┼───────────────────┘         │
│                            ↓                             │
│              ┌─────────────────────────┐                 │
│              │   Secure Aggregator     │                 │
│              │   (MPC Protocol)        │                 │
│              │   ZKP Verification      │                 │
│              └────────────┬────────────┘                 │
│                           ↓                              │
│              ┌─────────────────────────┐                 │
│              │  AMD Cloud Coordinator  │                 │
│              │  (MI300X Nodes)         │                 │
│              │  FedAvg + Privacy Noise │                 │
│              │  Global Model Update    │                 │
│              └────────────┬────────────┘                 │
│                           ↓                              │
│              Distribute updated model to all devices     │
└───────────────────────────────────────────────────────────┘
```

### Component Breakdown

| Component | Technology | AMD Optimization |
|-----------|------------|-----------------|
| **Edge Inference** | Llama 3-8B, 4-bit nf4 | HuggingFace bitsandbytes on ROCm |
| **Local Fine-tuning** | LoRA (rank 4-16) | ROCm + PyTorch native |
| **Privacy Engine** | DP-SGD (ε=1.0, δ=1e-5) | Opacus PrivacyEngine |
| **Secure Aggregation** | MPC (SPDZ protocol) | RCCL for cross-device comms |
| **Update Verification** | Zero-Knowledge Proofs | — |
| **Global Coordination** | FedAvg + momentum | AMD MI300X (100+ nodes) |
| **Model Distribution** | Delta compression + CDN | AMD Developer Cloud |

---

## 4. Technical Deep Dive

### 4.1 Federated Learning Strategy

**Algorithm: FedAvg with Differential Privacy**

```python
# Pseudocode for one FL round
for round in range(num_rounds):
    # 1. Sample K devices from N total
    selected_devices = sample_devices(K=100, strategy="resource_aware")
    
    # 2. Broadcast global model
    broadcast(global_model, selected_devices)
    
    # 3. Local training on each device
    local_updates = []
    for device in selected_devices:
        delta_w = device.local_train(
            model=global_model,
            lora_rank=8,
            epochs=2,
            lr=1e-4
        )
        # Add calibrated Gaussian noise (DP guarantee)
        noisy_delta = dp_sgd(delta_w, epsilon=1.0, delta=1e-5)
        local_updates.append(encrypt(noisy_delta))
    
    # 4. Secure aggregation (MPC)
    aggregated = secure_aggregate(local_updates)  # No plaintext exposure
    
    # 5. Update global model
    global_model = fedavg(global_model, aggregated, weights=device_data_sizes)
```

### 4.2 Differential Privacy Mathematics

The DP guarantee is defined as:

```
Pr[M(D) ∈ S] ≤ e^ε × Pr[M(D') ∈ S] + δ

Where:
  M   = randomized mechanism (DP-SGD)
  D   = dataset
  D'  = neighboring dataset (differs by one record)
  ε   = privacy budget (lower = more private; target: ε ≤ 1.0)
  δ   = failure probability (target: δ ≤ 1e-5)
```

**Noise calibration:**
```
σ = (sensitivity × √(2 × ln(1.25/δ))) / ε
sensitivity = C (gradient clipping norm, e.g., C=1.0)
```

### 4.3 AFLoRA (Adaptive Federated LoRA) on 4-bit Quantized Models

```
Original weight matrix: W ∈ R^(d×k)  [frozen, 4-bit quantized]
AFLoRA decomposition:   ΔW = A × Λ × B
  Where:
    A ∈ R^(d×r) = Global shared matrix (participates in federation)
    Λ ∈ R^(r)   = Local trainable diagonal importance matrix
    B ∈ R^(r×k) = Local trainable matrix (remains on device)

Memory savings vs full fine-tuning:
  Llama 3-8B full FT:  ~32GB VRAM (BF16)
  4-bit + AFLoRA (r=8):  ~5GB VRAM ← feasible on Steam Deck
```

**Personalization Guarantee:** Since `B` and `Λ` never leave the device, the model inherently personalizes to local data distribution while still benefiting from the globally aggregated `A` matrix. Base64 encoding is used to efficiently serialize `A` matrices for transmission.

### 4.4 Heterogeneous Device Handling

| Device Type | VRAM | LoRA Rank | Batch Size | Contribution Weight |
|-------------|------|-----------|------------|---------------------|
| MI300X (Cloud) | 192GB | 64 | 32 | 5.0× |
| Radeon RX 7900 XTX | 24GB | 16 | 8 | 2.0× |
| Ryzen AI Laptop | 16GB | 8 | 4 | 1.0× |
| Steam Deck | 16GB (shared) | 4 | 2 | 0.5× |
| CPU-Only PC | CPU RAM | 2 | 1 | 0.1× |

**Adaptive pruning:** Devices with < 8GB available VRAM receive a pruned model (40% sparsity) to participate without OOM errors.

**Model Distribution Strategy:**
*   **The Base Model:** Every node holds the exact same foundation model (e.g., Llama 3-8B). To ensure it fits on smaller hardware, it is heavily compressed (4-bit quantized).
*   **LoRA Adapters:** The devices do not train the massive base model. They only train a small "plugin" weight called a LoRA adapter. The size (Rank) of this adapter scales with the hardware—a cloud server trains a massive Rank 64 adapter, while a weak CPU-only laptop trains a tiny Rank 2 adapter.
*   **Central Aggregation:** The central server does not run a "bigger" model. It simply collects the LoRA adapters from all edge devices, mathematically averages them together (FedAvg), and broadcasts the smarter, combined adapter back to the network.


### 4.5 Zero-Knowledge Proof for Update Verification

Purpose: Prove that a device's gradient update satisfies the clipping norm constraint **without revealing the actual gradients.**

```
Prover (device) proves: ||ΔW||₂ ≤ C
Without revealing:       ΔW itself

ZKP circuit: Groth16 / PLONK over BN254 curve
Verification time: ~2ms per update on coordinator
```

---

## 5. AMD Hardware Integration

### 5.1 ROCm Stack

```
┌──────────────────────────────────────────────┐
│              Application Layer                │
│         FusionNet FL Orchestrator             │
├──────────────────────────────────────────────┤
│              PyTorch + ROCm                   │
│         (torch.cuda → torch.hip)              │
├──────────────────────────────────────────────┤
│    MIGraphX          │    HIP Custom Kernels  │
│  (4-bit inference)   │   (DP-SGD noise add)   │
├──────────────────────────────────────────────┤
│    RCCL (collective comms)   │   rocBLAS      │
├──────────────────────────────────────────────┤
│              ROCm Runtime                     │
├──────────────────────────────────────────────┤
│     AMD GPU Hardware (MI300X / RDNA3)         │
└──────────────────────────────────────────────┘
```

### 5.2 Privacy Engine: Opacus Integration & Fallback

Instead of solely relying on custom kernels, FusionNet primarily integrates **Opacus**, a production-ready Differential Privacy library for PyTorch. However, since Opacus can sometimes struggle with dynamically quantized modules (like `bitsandbytes.nn.Linear4bit`), FusionNet implements an identical-interface fallback.

```python
# Setup DP-SGD with abstract PrivacyEngine
from federation.privacy import setup_privacy

model, optimizer, dataloader, privacy_engine = setup_privacy(
    model, optimizer, dataloader, config["privacy"]
)

# During training loop
if privacy_engine:
    privacy_engine.step()  # Handles gradient clipping and Gaussian noise addition
    optimizer.zero_grad()
```
This dual-approach ensures mathematically sound per-sample gradient clipping and noise addition, guaranteeing Differential Privacy (DP-SGD) while remaining fully compatible with ROCm backends and 4-bit quantized base models.

### 5.3 RCCL for Cross-Device Aggregation

```python
import torch.distributed as dist

# Initialize RCCL process group (replaces NCCL for AMD)
dist.init_process_group(
    backend="nccl",           # ROCm maps nccl → rccl automatically
    init_method="env://",
    world_size=num_devices,
    rank=device_rank
)

# Secure aggregation via AllReduce (MPC wraps this)
dist.all_reduce(gradient_tensor, op=dist.ReduceOp.SUM)
gradient_tensor /= num_devices
```

### 5.4 bitsandbytes for Quantized Inference

For 4-bit model loading, FusionNet uses standard `transformers` integrated with `bitsandbytes`, which now natively supports ROCm 6.0:

```python
from transformers import AutoModelForCausalLM, BitsAndBytesConfig
import torch

# Federation-wide model — identical across ALL client nodes.
# GPU nodes: 4-bit NF4 (~1.2 GB VRAM). CPU nodes: FP32 (~2.5 GB RAM).
FEDERATION_MODEL = "TinyLlama/TinyLlama-1.1B-Chat-v1.0"

if torch.cuda.is_available():
    # GPU path — 4-bit NF4 quantization via bitsandbytes (ROCm 6.0+ supported)
    quantization_config = BitsAndBytesConfig(
        load_in_4bit=True,
        bnb_4bit_compute_dtype=torch.float16,
        bnb_4bit_quant_type="nf4",
        bnb_4bit_use_double_quant=True,
    )
    model = AutoModelForCausalLM.from_pretrained(
        FEDERATION_MODEL,
        quantization_config=quantization_config,
        device_map="auto",
    )
else:
    # CPU path — FP32, no quantization, device_map=None
    # TinyLlama-1.1B in FP32 ≈ 2.5 GB RAM; runs on any office PC.
    model = AutoModelForCausalLM.from_pretrained(
        FEDERATION_MODEL,
        torch_dtype=torch.float32,
        device_map=None,
    )
```

---

## 6. MVP Execution Plan

### Scope: 10 AMD Cloud VMs, Sentiment Analysis Task

**Goal:** Demonstrate that a central model improves accuracy on sentiment classification **without any raw text data leaving individual VMs.**

### MVP Architecture

```
10 AMD Cloud VMs (simulate enterprise nodes)
Each VM has:
  - A private text dataset partition (e.g., medical reviews, financial notes)
  - Llama 3-8B loaded with 4-bit quantization
  - LoRA adapter (rank=8) for local fine-tuning

Central Coordinator (1 MI300X VM):
  - Receives encrypted weight deltas
  - Runs FedAvg aggregation
  - Broadcasts updated LoRA weights

Metrics tracked:
  - Accuracy on holdout sentiment test set (per round)
  - Privacy budget consumption (ε per round)
  - Convergence speed vs centralized baseline
  - Communication overhead (bytes per round)
```

### MVP Timeline (2 Weeks)

| Week | Days | Task | Deliverable |
|------|------|------|-------------|
| **Week 1** | 1-2 | Environment setup: ROCm, PyTorch, AMD Dev Cloud | Working GPU environment |
| | 3-4 | Load Llama 3-8B with 4-bit quantization (MIGraphX) | Model running on AMD GPU |
| | 5-6 | Implement LoRA fine-tuning loop with DP-SGD | Private local training working |
| | 7 | Integrate RCCL for VM-to-VM communication | VMs can exchange tensors |
| **Week 2** | 8-9 | Build FedAvg coordinator + secure aggregation stub | Basic FL round completes |
| | 10-11 | Run 20 FL rounds, track convergence metrics | Accuracy improvement charts |
| | 12-13 | Add ZKP verification (simplified circuit) | Update validity proof |
| | 14 | Demo video, documentation, submission prep | **Submission Ready ✅** |

### MVP Success Criteria

- [ ] Model accuracy improves from round 0 → round 20 (target: +15% on sentiment task)
- [ ] Zero raw data transmitted between VMs (verifiable via network logs)
- [ ] ε ≤ 1.0 maintained throughout training
- [ ] System handles 1 VM dropout gracefully (fault tolerance)
- [ ] End-to-end demo video under 5 minutes

---

## 7. Full Development Roadmap

### Phase 1 — Foundation (Months 1-3)
**Goal: Production-grade federated training core**

- [ ] ROCm-native FL library (open-sourced as `fusionnet-core`)
- [ ] Full DP-SGD with mathematically verified privacy accounting (RDP accountant)
- [ ] Support for 5 device types (heterogeneous FL)
- [ ] Custom HIP kernel for constant-time noise addition
- [ ] RCCL-based secure aggregation (partial MPC)
- [ ] Web dashboard for monitoring FL rounds

**Milestone:** 100 simulated devices, 3 domain tasks (sentiment, NER, classification)

---

### Phase 2 — Privacy Hardening (Months 4-6)
**Goal: Enterprise-grade privacy stack**

- [ ] Full MPC implementation (SPDZ protocol) for secure aggregation
- [ ] ZKP-based update verification (Groth16 circuits)
- [ ] Model inversion attack resistance testing
- [ ] Poisoning attack detection (Byzantine-robust aggregation: Krum/Bulyan)
- [ ] Formal privacy audit trail (exportable compliance reports)
- [ ] HIPAA/GDPR compliance checklist built into SDK

**Milestone:** First pilot with 1 healthcare partner (de-identified data)

---

### Phase 3 — Edge Deployment (Months 7-9)
**Goal: Real AMD edge device support**

- [ ] Steam Deck client app (Linux/SteamOS)
- [ ] Ryzen AI laptop SDK (Windows/Linux)
- [ ] Bandwidth-adaptive training (throttle when on cellular)
- [ ] Asynchronous FL (devices don't need to be online simultaneously)
- [ ] Delta compression for model updates (10× bandwidth reduction)
- [ ] Mobile monitoring app for device owners

**Milestone:** 1,000 real edge devices, 3 enterprise pilots

---

### Phase 4 — Scale & Commercialize (Months 10-12)
**Goal: Revenue-generating product**

- [ ] SaaS portal: "FusionNet Enterprise"
- [ ] SDK for enterprises to deploy private FL networks
- [ ] AMD OEM partnership (bundle with Radeon Pro / EPYC)
- [ ] ISO 27001 certification
- [ ] SOC-2 Type II compliance
- [ ] Public model marketplace (anonymized community models)

**Milestone:** $1M ARR, Series A fundraise

---

## 8. Competitive Analysis

| Solution | Privacy Guarantee | AMD Support | Edge Devices | Heterogeneous FL | Production-Ready |
|----------|-------------------|-------------|--------------|-----------------|-----------------|
| **FusionNet** | DP + MPC + ZKP | ✅ Native | ✅ Yes | ✅ Yes | 🔄 Building |
| Flower (flwr) | ❌ None built-in | ⚠️ Partial | ⚠️ Limited | ⚠️ Partial | ✅ Yes |
| FedML | ⚠️ Basic DP | ❌ CUDA-first | ⚠️ Limited | ⚠️ Partial | ✅ Yes |
| PySyft (OpenMined) | ✅ Strong | ❌ No | ❌ No | ❌ No | ⚠️ Research |
| Apple Private Federated | ✅ Strong | ❌ Apple-only | ❌ Apple-only | ❌ No | ✅ Yes |
| Google Federated Core | ✅ Yes | ❌ TPU-focused | ❌ No | ❌ No | ✅ Yes |

**FusionNet's unique position:** Only solution combining (AMD-native) + (full privacy stack) + (heterogeneous edge devices)

---

## 9. Business Model & Commercial Potential

### Revenue Streams

```
┌─────────────────────────────────────────────────────────┐
│                  FUSIONNET REVENUE MODEL                │
├─────────────────────┬───────────────────────────────────┤
│  Enterprise SaaS    │  $2,000–$20,000 / month           │
│                     │  Per-organization FL orchestration │
├─────────────────────┼───────────────────────────────────┤
│  Compute Credits    │  Revenue share with AMD Dev Cloud  │
│                     │  Every training round = cloud bill │
├─────────────────────┼───────────────────────────────────┤
│  Compliance Suite   │  $5,000–$50,000 / audit report    │
│                     │  HIPAA/GDPR evidence packages      │
├─────────────────────┼───────────────────────────────────┤
│  SDK Licensing      │  $10,000–$100,000 / year          │
│                     │  For device manufacturers (OEM)    │
├─────────────────────┼───────────────────────────────────┤
│  Model Marketplace  │  15% take rate on model sales      │
│                     │  Community-trained private models  │
└─────────────────────┴───────────────────────────────────┘
```

### Market Sizing

```
TAM: Enterprise AI + Privacy Tech
  $50B enterprise AI market
  × 30% blocked by privacy concerns = $15B addressable

SAM: Federated Learning Platforms
  $210M (2024) → $1.2B (2030) at 28% CAGR

SOM (Year 3 target):
  100 enterprise customers × $60K ACV = $6M ARR
  + AMD OEM deal = $5M licensing
  Total Year 3: ~$11M ARR
```

### Why AMD Would Acquire/Partner

- FusionNet makes AMD hardware **uniquely valuable** for enterprise AI
- Every FusionNet deployment = **more MI300X cloud usage + Radeon GPU sales**
- Bundling as "ROCm Federated" creates a moat vs NVIDIA (CUDA has no equiv)
- Strategic fit with AMD's push into enterprise AI (Instinct series)

---

## 10. Risks & Mitigations

| Risk | Severity | Likelihood | Mitigation |
|------|----------|------------|------------|
| FL convergence 3-5× slower than centralized | High | High | Async FL, momentum-based aggregation, better device sampling |
| Malicious device gradient poisoning | High | Medium | Byzantine-robust aggregation (Krum, Bulyan, FLTrust) |
| Model inversion attacks on aggregated model | High | Medium | Higher ε noise, output prediction filters, canary detection |
| Enterprise hesitation despite privacy proofs | Medium | High | Formal audits, pilot programs, compliance certifications |
| ROCm compatibility issues across device types | Medium | High | Extensive device matrix testing, fallback CPU path |
| ZKP overhead too high for edge devices | Medium | Medium | Lightweight proof systems (STARKs vs Groth16), batching |
| Regulatory changes (new AI laws) | Low | Medium | Build compliance-first, stay close to regulators |
| Competitor launches AMD-optimized FL | Low | Low | Speed to market + open-source community lock-in |

---

## 11. Hackathon Submission Strategy

### What Judges Care About

1. **Technical Impressiveness** — First production FL system for AMD? ✅
2. **AMD Hardware Utilization** — ROCm, MIGraphX, RCCL, HIP kernels? ✅
3. **Real-World Impact** — Solves actual enterprise privacy crisis? ✅
4. **Demo Quality** — Live system showing convergence without data leakage? ✅
5. **Business Potential** — $50B market, AMD ecosystem play? ✅

### Submission Checklist

- [ ] **Demo Video** (5 min max): Show FL rounds, accuracy climbing, ε budget tracker
- [ ] **GitHub Repo**: Clean code, README, architecture diagrams, setup guide
- [ ] **Technical Report**: Math proofs for DP guarantees, benchmarks vs Flower
- [ ] **Slides** (10 slides): Problem → Solution → Demo → Business → Ask
- [ ] **Live Demo Link**: AMD Cloud-hosted FL system running in real-time

### Demo Script Outline

```
00:00 — Hook: "This hospital has 1M patient records. ChatGPT can't touch them."
00:30 — Problem visualization: Data gravity, compliance wall
01:00 — FusionNet architecture walkthrough (animated diagram)
02:00 — LIVE: 10 VMs fine-tuning in parallel (ROCm GPU utilization visible)
03:00 — LIVE: Accuracy graph climbing per round (model improving without data movement)
03:30 — Privacy proof: Show ε = 0.87 after 20 rounds (under budget)
04:00 — Network logs: Zero bytes of raw data transmitted
04:30 — Commercial pitch: "AMD + FusionNet = the HIPAA-compliant AI stack"
05:00 — Close: GitHub, demo link, contact
```

### Key Differentiator Phrases for Judges

> *"First federated learning system natively optimized for AMD ROCm"*

> *"Mathematically proven privacy — not just policy-level promises"*

> *"Your Steam Deck becomes an AI trainer while you sleep"*

> *"We don't move data to the model. We move the model to the data."*

---

## 12. Team Tasks & Daily Checklist

### Week 1: Core Infrastructure

```
Day 1 ✅
  □ Provision 10 AMD Cloud VMs (MI300X or EPYC)
  □ Install ROCm 6.x, PyTorch with HIP support
  □ Verify GPU access: rocm-smi, torch.cuda.is_available()

Day 2 ✅
  □ Download Llama 3-8B weights (HuggingFace)
  □ Load with 4-bit GPTQ quantization (AutoGPTQ / bitsandbytes ROCm)
  □ Benchmark inference speed on AMD GPU

Day 3 ✅
  □ Implement LoRA adapter (peft library)
  □ Test local fine-tuning for 100 steps on dummy data
  □ Profile VRAM usage, verify fits on target devices

Day 4 ✅
  □ Implement DP-SGD noise addition (Opacus or custom)
  □ Write privacy accountant (track ε per step)
  □ Write custom HIP noise kernel (optional optimization)

Day 5 ✅
  □ Set up RCCL process group across 3 VMs
  □ Test gradient AllReduce between VMs
  □ Measure communication latency and bandwidth

Day 6-7 ✅
  □ Build dataset partitioner (IID and non-IID splits)
  □ Prepare sentiment analysis dataset (SST-2 or custom)
  □ Assign partitions to VMs, verify isolation
```

### Week 2: FL System + Demo

```
Day 8-9 ✅
  □ Build FedAvg coordinator script
  □ Run first end-to-end FL round (1 round, 3 VMs)
  □ Log: accuracy, ε budget, communication bytes

Day 10-11 ✅
  □ Scale to 10 VMs, run 20 rounds
  □ Plot convergence curves (accuracy vs rounds)
  □ Compare vs centralized baseline (upper bound)

Day 12 ✅
  □ Add fault tolerance (handle VM dropout mid-round)
  □ Add ZKP verification stub (or hash-based integrity check)
  □ Write network packet logger (prove zero raw data transmitted)

Day 13 ✅
  □ Record demo video
  □ Write README and architecture doc
  □ Prepare GitHub repo (clean commits, clear structure)

Day 14 ✅
  □ Final review of submission
  □ Submit before deadline (July 11, 2026)
  □ 🎉 Ship it
```

---

## 📁 FusionNet Repository Structure

The local client proof-of-concept has been successfully implemented in the `fusionnet-client/` directory.

```
fusionnet/
├── README.md
├── .env                           # ⬅️ (gitignored) HF_TOKEN=your_token_here
├── docs/
├── fusionnet-client/              # ⬅️ Local Client PoC Component
│   ├── README.md
│   ├── main.py                    # Node CLI entry point (--client-id, --num-clients, --rounds)
│   ├── client.py                  # FusionNetClient orchestrator
│   ├── auth.py                    # HF authentication (reads HF_TOKEN from .env)
│   ├── config.yaml                # Device & training config
│   ├── requirements.txt
│   ├── models/
│   │   └── loader.py              # 4-bit Llama + Hardware detection
│   ├── aflora/
│   │   ├── layer.py               # AFLoRA (A x Λ x B) module
│   │   └── injection.py           # Target module replacer
│   ├── federation/
│   │   ├── client.py              # HF Hub comms & adapter state management
│   │   ├── hf_hub.py              # HFParameterServer (upload/download A matrices)
│   │   └── privacy.py             # Abstract DP Engine (Opacus + fallback)
│   ├── training/
│   │   └── engine.py              # Local training loop
│   ├── fl_datasets/
│   │   ├── __init__.py
│   │   ├── loader.py              # HuggingFace Datasets interface + Dirichlet partition
│   │   └── partitioner.py         # Dirichlet Non-IID partitioner
│   └── scripts/
│       ├── example_train.py
│       └── example_federated_round.py
└── scripts/
    ├── hf_coordinator.py          # ⬅️ Serverless FL coordinator (polls HF Hub, runs FedAvg)
    ├── setup_env.ps1              # Windows: one-shot environment setup
    ├── setup_cuda.ps1             # Windows: NVIDIA CUDA setup
    ├── setup_rocm.ps1             # Windows: AMD ROCm (CPU + WSL2 guide)
    ├── launch_fl_round.ps1        # Windows: multi-client FL launcher
    ├── setup_cuda.sh              # Linux/WSL2: NVIDIA CUDA setup
    ├── setup_rocm.sh              # Linux/WSL2: AMD ROCm setup
    ├── launch_fl_round.sh         # Linux/WSL2: FL round launcher
    └── test_local_training.py
```

---

## 🛠️ Bug Fixes & System Stability Updates

During development and live testing, several issues were identified and resolved to ensure robust, serverless federated learning execution on Windows and heterogeneous hardware:

1. **PowerShell Script Parser Fixes (`scripts/setup_env.ps1`, `scripts/launch_fl_round.ps1`)**:
   - Replaced non-standard em-dashes (`—`) in comments/strings with standard hyphens (`-`) to prevent PowerShell script execution parser failures on Windows.
2. **Quantized Model Loading (`fusionnet-client/models/loader.py`)**:
   - Fixed the `from_pretrained()` loading parameters by replacing the invalid `dtype` argument with the correct `torch_dtype` keyword argument.
3. **AFLoRA Layer Device/Dtype Matching (`fusionnet-client/aflora/layer.py`)**:
   - Fixed a runtime CPU/CUDA device and dtype mismatch by dynamically casting AFLoRA weights (`A`, `B`, and `Lambda`) to the input tensor's `device` and `dtype` inside `forward()`.
4. **HuggingFace Cache Parallel Write Lock (`fusionnet-client/fl_datasets/loader.py`)**:
   - Disabled Hugging Face datasets caching using `hf_datasets.disable_caching()` before running dataset mapping. This prevents a `FileExistsError` race condition when multiple local clients process datasets simultaneously on Windows.
5. **Causal Language Model Target Labels Shape Mismatch (`fusionnet-client/training/engine.py`)**:
   - Explicitly cloned input IDs to initialize target labels (`batch['labels'] = batch['input_ids'].clone()`), fixing shape mismatches during local fine-tuning on classification tasks like Banking77.

---

## 🪟 Windows Quick-Start

FusionNet runs natively on Windows. All scripts have `.ps1` (PowerShell) equivalents.

### Step 1 — Environment Setup (run once from repo root)

Open PowerShell as Administrator (or standard user if python is globally configured) and run:

```powershell
# CPU-only (any Windows PC — works out of the box)
.\scripts\setup_env.ps1

# NVIDIA GPU (requires driver >= 560, CUDA 12.8)
.\scripts\setup_env.ps1 -Backend cuda

# AMD GPU (installs CPU build; for full GPU acceleration use WSL2 + setup_rocm.sh)
.\scripts\setup_env.ps1 -Backend rocm
```

### Step 1.5 — Hugging Face Authentication

Create a `.env` file in the repo root with your HF token (obtain one with write scope at [huggingface.co/settings/tokens](https://huggingface.co/settings/tokens)):

```env
HF_TOKEN=your_token_here
```

Then authenticate by running (from the repo root):

```powershell
# Activate environment and run authentication helper
.\venv\Scripts\Activate.ps1
python fusionnet-client/auth.py
```

The `.env` file is gitignored and will not be committed.

### Step 2 — Run the Coordinator (polls HF Hub and aggregates updates)

In a separate terminal, activate the virtual environment and start the coordinator:

```powershell
# From repo root
.\venv\Scripts\Activate.ps1
python scripts/hf_coordinator.py --num-clients 2 --rounds 1
```

### Step 3 — Launch the Clients

In another terminal, run the multi-client launcher to start local client training:

```powershell
# From repo root
powershell -ExecutionPolicy Bypass -Command "& { .\venv\Scripts\Activate.ps1; .\scripts\launch_fl_round.ps1 -NumClients 2 -FederationRounds 1 }"
```

To run a single client node manually:

```powershell
# Activate venv and run main.py inside fusionnet-client directory
cd fusionnet-client
..\venv\Scripts\Activate.ps1
python main.py --client-id 0 --num-clients 2 --rounds 1
```

### AMD GPU on Windows — WSL2 Path

PyTorch ROCm wheels are Linux-only. For full AMD GPU acceleration on Windows:

```powershell
# Install WSL2 with Ubuntu 22.04
wsl --install -d Ubuntu-22.04

# Then inside WSL2
bash scripts/setup_rocm.sh
cd fusionnet-client && python main.py --client-id 0 --num-clients 4
```

### Script Reference

Always activate the virtual environment (`.\venv\Scripts\Activate.ps1`) before executing Python scripts.

| Task | Windows (PowerShell) | Linux / WSL2 (Bash) |
|---|---|---|
| Environment setup | `.\scripts\setup_env.ps1` | `pip install -r requirements.txt` |
| NVIDIA CUDA setup | `.\scripts\setup_cuda.ps1` | `bash scripts/setup_cuda.sh` |
| AMD ROCm setup | `.\scripts\setup_rocm.ps1` | `bash scripts/setup_rocm.sh` |
| Launch FL round | `.\scripts\launch_fl_round.ps1` | `bash scripts/launch_fl_round.sh` |
| Run single node | `python main.py --client-id 0` | `python main.py --client-id 0` |


---

## 💡 Key Insights & Vision

> **FusionNet isn't just a federated learning tool. It's infrastructure for the AI economy where data sovereignty is a right, not a luxury.**

The next billion-dollar opportunity in AI isn't building smarter models — it's building the **plumbing that lets sensitive industries use them**. Healthcare, legal, and finance collectively hold humanity's most valuable data and are almost entirely locked out of the LLM revolution due to legitimate privacy concerns.

FusionNet inverts the equation: instead of pulling data toward AI, it pushes AI toward data. Every AMD GPU — from a $400 Steam Deck to a $100,000 MI300X — becomes a node in a global intelligence network that learns from humanity's private knowledge while keeping that knowledge private.

**This is the missing infrastructure layer for the age of private AI.**

---

*Document generated: June 2026 | FusionNet Project | AMD Developer Hackathon ACT II*
*Deadline: July 11, 2026*


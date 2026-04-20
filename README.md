<div align="center">

<br/>

```
  █████╗ ███████╗██████╗ ███╗   ██╗███╗   ██╗
 ██╔══██╗██╔════╝██╔══██╗████╗  ██║████╗  ██║
 ███████║███████╗██████╔╝██╔██╗ ██║██╔██╗ ██║
 ██╔══██║╚════██║██╔═══╝ ██║╚██╗██║██║╚██╗██║
 ██║  ██║███████║██║     ██║ ╚████║██║ ╚████║
 ╚═╝  ╚═╝╚══════╝╚═╝     ╚═╝  ╚═══╝╚═╝  ╚═══╝
```

# Adaptive Self-Pruning Neural Network
### *Efficient Image Classification through Dynamic Architecture Optimization*

<br/>

[![Python](https://img.shields.io/badge/Python-3.8%2B-3776AB?style=for-the-badge&logo=python&logoColor=white)](https://python.org)
[![PyTorch](https://img.shields.io/badge/PyTorch-2.0%2B-EE4C2C?style=for-the-badge&logo=pytorch&logoColor=white)](https://pytorch.org)
[![License](https://img.shields.io/badge/License-MIT-22c55e?style=for-the-badge)](LICENSE)
[![Status](https://img.shields.io/badge/Status-Active-6366f1?style=for-the-badge)]()

<br/>

> *A neural network that learns to shrink itself — removing redundant parameters on-the-fly  
> to achieve faster inference without sacrificing classification accuracy.*

<br/>

---

</div>

<br/>

## ✦ What is ASPNN?

**Adaptive Self-Pruning Neural Network (ASPNN)** is a model compression framework that integrates structured pruning directly into the training loop. Rather than training a large model and compressing it post-hoc, ASPNN dynamically evaluates the saliency of each neuron/channel and prunes low-importance components during training — producing a compact, deployment-ready model from the ground up.

The core insight: *not all neurons contribute equally to classification*. By continuously measuring and pruning the least-informative pathways, the model concentrates its representational capacity where it matters most.

<br/>

---

## ✦ Key Features

| Feature | Description |
|---|---|
| 🔁 **Dynamic Pruning** | Pruning decisions made per-epoch based on live saliency scores |
| 📉 **Structured Sparsity** | Entire channels/filters removed for real hardware speedup |
| ⚖️ **Accuracy-Efficiency Balance** | Adaptive threshold preserves top-k% most informative units |
| 🧠 **Self-Supervised Criterion** | No external oracle needed — the network evaluates itself |
| 🖼️ **Image Classification Ready** | Benchmarked on standard vision datasets |
| 🔌 **Plug-and-Play** | Works on top of any CNN-based backbone |

<br/>

---

## ✦ How It Works

The pruning pipeline operates in three stages per training cycle:

```
┌─────────────────────────────────────────────────────────────┐
│                    ASPNN Training Loop                       │
│                                                             │
│   ┌──────────┐    ┌──────────────┐    ┌─────────────────┐  │
│   │  Forward │ →  │  Compute     │ →  │  Prune Low-     │  │
│   │  Pass    │    │  Saliency    │    │  Score Channels  │  │
│   └──────────┘    │  Scores      │    └────────┬────────┘  │
│                   └──────────────┘             │           │
│   ┌──────────┐    ┌──────────────┐             │           │
│   │  Update  │ ←  │  Backward    │ ←───────────┘           │
│   │  Weights │    │  Pass        │                         │
│   └──────────┘    └──────────────┘                         │
└─────────────────────────────────────────────────────────────┘
```

**Saliency Scoring** assigns importance values to each channel using gradient-weighted activation magnitudes. Channels falling below an adaptive threshold `τ` are masked out. The threshold `τ` is updated each epoch to enforce a target sparsity schedule:

```
τ(t) = percentile(scores, target_sparsity(t))
```

Where `target_sparsity(t)` gradually increases over training epochs, letting the model first learn rich representations before aggressively compressing.

<br/>

---

## ✦ Architecture Overview

```
Input Image
    │
    ▼
┌─────────────────────────────────────────────┐
│               Backbone CNN                  │
│                                             │
│  Conv Block 1  →  [Saliency Gate] → Prune? │
│       ↓                                     │
│  Conv Block 2  →  [Saliency Gate] → Prune? │
│       ↓                                     │
│  Conv Block N  →  [Saliency Gate] → Prune? │
└─────────────────────────────────────────────┘
    │
    ▼
Global Average Pool
    │
    ▼
Fully Connected → Softmax → Class Probabilities
```

Each **Saliency Gate** is a lightweight scoring module attached to a convolutional block. During training it computes channel-wise importance; during inference the pruned channels are removed entirely, reducing FLOPs.

<br/>

---

## ✦ Project Structure

```
Adaptive-Self-Pruning-Neural-Network/
│
├── 📁 models/
│   ├── backbone.py          # Base CNN architectures
│   ├── saliency_gate.py     # Saliency scoring module
│   └── aspnn.py             # Full ASPNN model wrapper
│
├── 📁 pruning/
│   ├── scheduler.py         # Sparsity schedule (linear, cosine)
│   ├── criterion.py         # Pruning decision logic
│   └── utils.py             # Channel masking helpers
│
├── 📁 data/
│   ├── datasets.py          # Dataset loaders (CIFAR, ImageNet)
│   └── transforms.py        # Augmentation pipelines
│
├── 📁 training/
│   ├── trainer.py           # Training loop with pruning integration
│   └── evaluator.py         # Accuracy + FLOPs evaluation
│
├── 📁 configs/
│   ├── cifar10.yaml         # CIFAR-10 experiment config
│   └── imagenet.yaml        # ImageNet experiment config
│
├── train.py                 # Main training entry point
├── evaluate.py              # Evaluation script
├── requirements.txt
└── README.md
```

<br/>

---

## ✦ Installation

**Prerequisites:** Python 3.8+, CUDA 11.7+ (recommended)

```bash
# 1. Clone the repository
git clone https://github.com/venkatesh0029/Adaptive-Self-Pruning-Neural-Network-for-Efficient-Image-Classification.git
cd Adaptive-Self-Pruning-Neural-Network-for-Efficient-Image-Classification

# 2. Create a virtual environment (recommended)
python -m venv venv
source venv/bin/activate        # Linux / macOS
# venv\Scripts\activate         # Windows

# 3. Install dependencies
pip install -r requirements.txt
```

<br/>

---

## ✦ Quick Start

### Training from Scratch

```bash
python train.py \
  --config configs/cifar10.yaml \
  --dataset cifar10 \
  --epochs 150 \
  --target-sparsity 0.5 \
  --output-dir ./checkpoints
```

### Evaluating a Trained Model

```bash
python evaluate.py \
  --checkpoint checkpoints/best_model.pth \
  --dataset cifar10 \
  --report-flops
```

### Python API

```python
from models.aspnn import ASPNN
from pruning.scheduler import CosineSparsityScheduler

# Initialize model with pruning
model = ASPNN(
    backbone='resnet18',
    num_classes=10,
    pruning_scheduler=CosineSparsityScheduler(
        start_sparsity=0.0,
        target_sparsity=0.5,
        num_epochs=150
    )
)

# Train — pruning happens automatically inside the loop
trainer.fit(model, train_loader, val_loader)
```

<br/>

---

## ✦ Configuration

Key parameters in `configs/*.yaml`:

```yaml
model:
  backbone: resnet18           # resnet18 | vgg16 | mobilenet_v2
  num_classes: 10

pruning:
  strategy: cosine             # linear | cosine | step
  start_sparsity: 0.0          # begin dense
  target_sparsity: 0.50        # prune 50% of channels by end
  warmup_epochs: 20            # epochs before pruning starts
  saliency_metric: grad_norm   # grad_norm | activation_mean | taylor

training:
  epochs: 150
  batch_size: 128
  optimizer: sgd
  lr: 0.1
  weight_decay: 1.0e-4
  scheduler: cosine_annealing

data:
  dataset: cifar10             # cifar10 | cifar100 | imagenet
  data_dir: ./data
  num_workers: 4
```

<br/>

---

## ✦ Results

### CIFAR-10

| Model | Accuracy (%) | Parameters | FLOPs | Sparsity |
|---|---|---|---|---|
| ResNet-18 (baseline) | 94.8 | 11.2M | 1.82G | 0% |
| ASPNN (30% sparse) | 94.5 | 7.8M | 1.27G | 30% |
| ASPNN (50% sparse) | 93.9 | 5.6M | 0.91G | 50% |
| ASPNN (70% sparse) | 92.7 | 3.4M | 0.55G | 70% |

### CIFAR-100

| Model | Top-1 Acc (%) | Parameters | FLOPs | Sparsity |
|---|---|---|---|---|
| ResNet-50 (baseline) | 78.2 | 23.5M | 4.1G | 0% |
| ASPNN (50% sparse) | 77.1 | 11.7M | 2.0G | 50% |

> **Highlights:** 50% sparsity with less than 1% accuracy drop. 2× reduction in FLOPs translates to measurable speedup on both GPU and CPU inference.

<br/>

---

## ✦ Supported Backbones

- ✅ ResNet-18 / 34 / 50
- ✅ VGG-16
- ✅ MobileNet V2
- ✅ EfficientNet-B0
- 🔜 Vision Transformer (ViT) — coming soon

<br/>

---

## ✦ Dependencies

```
torch>=2.0.0
torchvision>=0.15.0
numpy>=1.23.0
pyyaml>=6.0
tqdm>=4.65.0
matplotlib>=3.7.0
thop>=0.1.1              # FLOPs counting
```

<br/>

---

## ✦ Pruning Strategies

### Saliency Metrics

| Metric | Description | Best For |
|---|---|---|
| `grad_norm` | L2 norm of gradients flowing through channel | General use |
| `activation_mean` | Mean activation magnitude over a mini-batch | Lightweight, fast |
| `taylor` | First-order Taylor expansion of loss w.r.t. channel | Most principled |

### Sparsity Schedules

- **Linear**: Gradual ramp from 0% → target over all epochs
- **Cosine**: Smooth sinusoidal schedule, gentler transitions
- **Step**: Prune in discrete jumps at predefined epochs

<br/>

---

## ✦ Roadmap

- [x] Structured channel pruning with saliency gates
- [x] Multiple sparsity schedules (linear, cosine, step)
- [x] CIFAR-10 / CIFAR-100 benchmarks
- [ ] ImageNet full training pipeline
- [ ] Vision Transformer support
- [ ] Mixed-precision pruning (INT8 + sparse)
- [ ] ONNX export with sparse weights
- [ ] Web demo for real-time pruning visualization

<br/>

---

## ✦ Contributing

Contributions are welcome! Here's how to get started:

```bash
# Fork the repo, then:
git checkout -b feature/your-feature-name
# Make your changes
git commit -m "feat: add your feature"
git push origin feature/your-feature-name
# Open a Pull Request
```

Please ensure:
- Code follows PEP 8
- New features include unit tests
- Docstrings for all public functions
- Update configs if adding new hyperparameters

<br/>

---

## ✦ Citation

If you use this work in your research, please cite:

```bibtex
@misc{venkatesh2024aspnn,
  author       = {Venkatesh},
  title        = {Adaptive Self-Pruning Neural Network for Efficient Image Classification},
  year         = {2024},
  howpublished = {\url{https://github.com/venkatesh0029/Adaptive-Self-Pruning-Neural-Network-for-Efficient-Image-Classification}},
}
```

<br/>

---

## ✦ License

This project is licensed under the **MIT License** — see the [LICENSE](LICENSE) file for details.

<br/>

---

## ✦ Acknowledgements

This work draws on ideas from:

- Han et al., *Learning both Weights and Connections for Efficient Neural Networks* (NeurIPS 2015)
- Liu et al., *Learning Efficient Convolutional Networks through Network Slimming* (ICCV 2017)
- Molchanov et al., *Pruning Convolutional Neural Networks for Resource Efficient Inference* (ICLR 2017)

<br/>

---

<div align="center">

Made with 🧠 by [venkatesh0029](https://github.com/venkatesh0029)

*Smaller models. Faster inference. Same accuracy.*

</div>

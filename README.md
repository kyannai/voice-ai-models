# Malaysian Voice AI Suite

> Production-ready **Text-to-Speech (TTS)** and **Automatic Speech Recognition (ASR)** systems for Malaysian speech (primarily Malay with English code-switching + Pinyin + slang + particles)

[![License](https://img.shields.io/badge/license-MIT-blue.svg)](LICENSE)
[![Python](https://img.shields.io/badge/python-3.10+-blue.svg)](https://www.python.org/downloads/)
[![PyTorch](https://img.shields.io/badge/PyTorch-2.0+-red.svg)](https://pytorch.org/)

---

## 📖 Overview

This project provides a complete **voice AI suite** for Malaysian multilingual speech:

### 🎤 TTS (Text-to-Speech)
State-of-the-art speech synthesis system specifically designed for Malaysian speech patterns, featuring:

- ✅ **Primary Malay**: Optimized for Malay as the main language with natural English code-switching
- ✅ **Mixed Language Support**: Handles Malay + English + Pinyin + local slang seamlessly
- ✅ **Particle Support**: Natural pronunciation of Malaysian discourse particles (lah, leh, loh, etc.)
- ✅ **Authentic Accent**: Captures genuine Malaysian Malay and English prosody
- ✅ **High Quality**: MOS > 4.0 naturalness score
- ✅ **Production-Ready**: Fast inference (RTF < 0.3), scalable API

### 🎧 ASR (Automatic Speech Recognition)
High-accuracy speech recognition system optimized for Malaysian multilingual speech, featuring:

- ✅ **High Accuracy**: Target < 15% WER (Word Error Rate) on Malaysian speech
- ✅ **Primary Malay**: Optimized for Malay with English code-switching detection
- ✅ **Mixed Language**: Handles Malay + English + Pinyin + local slang + special vocabulary
- ✅ **Particle Recognition**: Properly transcribes Malaysian discourse markers (lah, leh, loh, meh, lor)
- ✅ **Fast Training**: Uses Unsloth for 4x faster fine-tuning of Whisper-large v3
- ✅ **Production-Ready**: RESTful API, WebSocket streaming, scalable deployment

**[→ Go to ASR Documentation](asr/README.md)**

---

## ⚡ KEY OPTIMIZATION: Shared Data Collection

**One recording session serves BOTH ASR and TTS projects!**

Instead of recording voice data twice, we record once at highest quality (48kHz/24-bit) and process it for both:
- ASR uses downsampled 16kHz version
- TTS uses 22.05kHz version
- **Same transcripts, same speakers, same content**

**Result:**
- 💰 **Save $4,500-8,000** (43-50% recording cost reduction)
- ⏰ **Save 15-25 hours** of studio time
- ✅ **Better consistency** across models
- 📅 **Same 4-month timeline**

**[→ See Complete Strategy](asr/docs/08_Shared_Data_Strategy.md)**

---

### 🎯 Technical Approach: Fine-tuning with Sesame CSM-1B + Unsloth

Instead of training from scratch, we leverage:

- **Base Model**: [Sesame CSM-1B](https://huggingface.co/facebook/sesame-csm-1b) - A 1B parameter model pre-trained on code-switching data (English, Mandarin, Malay, Cantonese)
- **Training Framework**: [Unsloth](https://github.com/unslothai/unsloth) - 4x faster, 70% less memory with LoRA/QLoRA fine-tuning
- **Training Time**: 3-7 days (vs 8-12 weeks training from scratch)
- **Data Required**: 10-30 hours (vs 100+ hours)
- **Hardware**: Single RTX 4090 (vs 4× A100 cluster)
- **Cost**: $50-200 cloud / $2,700 hardware (vs $35,000+)

**Why This Approach?**
- ⚡ **100× Cheaper**: $200 vs $35,000 in cloud costs
- 🚀 **10× Faster**: 1 week vs 3 months development time
- 💪 **Better Starting Point**: Built-in code-switching capabilities
- 🎯 **Focus on Malaysian Features**: Spend time on accent/particles, not basic TTS
- 📦 **Easier Deployment**: Smaller model size with quantization

---

## 🚀 Quick Start

### Installation

```bash
# Clone repository
git clone https://github.com/yourorg/malaysian-tts.git
cd malaysian-tts

# Create environment
conda create -n malaysian-tts python=3.10
conda activate malaysian-tts

# Install dependencies
pip install -r requirements.txt
```

### Basic Usage

```python
from models.tts import MalaysianTTS

# Initialize model
tts = MalaysianTTS.from_pretrained("checkpoints/best_model.pt")

# Synthesize speech
text = "Saya nak go to the mall lah"
audio = tts.synthesize(text)

# Save audio
import soundfile as sf
sf.write("output.wav", audio, 22050)
```

### API Usage

```bash
# Start API server
uvicorn api.main:app --host 0.0.0.0 --port 8000

# Make request
curl -X POST http://localhost:8000/v1/synthesize \
  -H "Content-Type: application/json" \
  -H "X-API-Key: your_api_key" \
  -d '{"text": "Hello, apa khabar?"}'
```

---

## 📚 Documentation

### 🎧 ASR Documentation
Complete documentation suite for Malaysian multilingual speech recognition:

| Document | Description |
|----------|-------------|
| **[Quick Start Guide](asr/docs/00_QUICK_START.md)** | Get started with ASR fine-tuning |
| **[Product Requirements](asr/docs/01_PRD_Product_Requirements.md)** | Product vision, market analysis, requirements |
| **[Technical Architecture](asr/docs/02_Technical_Architecture.md)** | Whisper-large v3 + Unsloth architecture |
| **[Data Preparation](asr/docs/03_Data_Preparation_Guide.md)** | Data collection, transcription guidelines |
| **[Training Strategy](asr/docs/04_Training_Strategy_Guide.md)** | Unsloth setup, fine-tuning pipeline |
| **[Evaluation Methodology](asr/docs/05_Evaluation_Methodology.md)** | WER, code-switching metrics, benchmarking |
| **[Deployment Guide](asr/docs/06_Deployment_Guide.md)** | Docker, Kubernetes, production deployment |
| **[Project Execution Plan](asr/docs/07_Project_Execution_Plan.md)** | 9-month timeline, budget, resources |

### 🎤 TTS Documentation
Complete documentation suite for Malaysian multilingual speech synthesis:

| Document | Description |
|----------|-------------|
| **[Quick Start Guide](tts/docs/00_QUICK_START.md)** | Get started with TTS training |
| **[Product Requirements](tts/docs/01_PRD_Product_Requirements.md)** | Product vision, features, success metrics |
| **[Technical Architecture](tts/docs/02_Technical_Architecture.md)** | System architecture, ML models, technical design |
| **[Data Preparation](tts/docs/03_Data_Preparation_Guide.md)** | Data collection, annotation, preprocessing |
| **[Training Strategy](tts/docs/04_Training_Strategy_Guide.md)** | Training pipeline, hyperparameters, best practices |
| **[Evaluation Methodology](tts/docs/05_Evaluation_Methodology.md)** | Objective and subjective evaluation metrics |
| **[Deployment Guide](tts/docs/06_Deployment_Guide.md)** | Infrastructure, deployment, operations |
| **[Project Execution Plan](tts/docs/07_Project_Execution_Plan.md)** | Timeline, budget, resources, project management |

### Quick Navigation

**👤 For Product Managers:**
1. Start with [PRD](tts/docs/01_PRD_Product_Requirements.md) for requirements and success metrics
2. Review [Execution Plan](tts/docs/07_Project_Execution_Plan.md) for timeline and budget

**👨‍💻 For ML Engineers:**
1. Review [Technical Architecture](tts/docs/02_Technical_Architecture.md) for model design
2. Follow [Training Guide](tts/docs/04_Training_Strategy_Guide.md) to train models
3. Use [Evaluation Methodology](tts/docs/05_Evaluation_Methodology.md) to assess quality

**📊 For Data Team:**
1. Follow [Data Preparation Guide](tts/docs/03_Data_Preparation_Guide.md) for data collection
2. Review annotation requirements and quality standards

**🔧 For DevOps:**
1. Use [Deployment Guide](tts/docs/06_Deployment_Guide.md) for infrastructure setup
2. Implement monitoring and alerting

---

## 🎯 Project Goals

### Primary Objectives

1. **Naturalness**: Achieve MOS > 4.0 (human-like speech)
2. **Code-Switching**: Support seamless language mixing
3. **Particles**: Authentic Malaysian particle pronunciation
4. **Performance**: Real-time inference (RTF < 0.3)
5. **Production**: Scalable, reliable API service

### Success Metrics

| Metric | Target | Status |
|--------|--------|--------|
| MOS Naturalness | > 4.0 | 🎯 In Progress |
| Code-Switching Quality | > 95% | 🎯 In Progress |
| Particle Intonation | > 4.2/5.0 | 🎯 In Progress |
| Word Error Rate | < 5% | 🎯 In Progress |
| API Latency (p95) | < 500ms | 🎯 In Progress |
| Real-Time Factor | < 0.3 | 🎯 In Progress |

---

## 🏗️ Architecture Overview

### System Components

```
┌─────────────────────────────────────────────────────────┐
│                    Input Text                           │
│      "Saya nak go to the mall lah"                     │
└────────────────┬────────────────────────────────────────┘
                 │
                 ▼
┌─────────────────────────────────────────────────────────┐
│           Text Processing Module                         │
│  • Language Detection                                    │
│  • G2P Conversion (Malay/English/Pinyin)               │
│  • Particle Analysis                                    │
└────────────────┬────────────────────────────────────────┘
                 │
                 ▼
┌─────────────────────────────────────────────────────────┐
│        Acoustic Model (FastSpeech 2)                    │
│  • Multi-lingual Encoder                                │
│  • Variance Adaptor (Duration/Pitch/Energy)            │
│  • Decoder → Mel-Spectrogram                           │
└────────────────┬────────────────────────────────────────┘
                 │
                 ▼
┌─────────────────────────────────────────────────────────┐
│             Vocoder (HiFi-GAN)                          │
│  • High-fidelity audio generation                       │
│  • Fast inference (RTF < 0.1)                          │
└────────────────┬────────────────────────────────────────┘
                 │
                 ▼
              Audio Output
```

### Technology Stack

**ML/TTS:**
- PyTorch 2.0+
- **Base Models**: XTTS v2, StyleTTS2, VITS (see [Open-Source Models](tts/docs/02_Technical_Architecture.md#13-open-source-base-models-for-fine-tuning))
- FastSpeech 2 (acoustic model)
- HiFi-GAN (vocoder)
- Montreal Forced Aligner

**Backend:**
- FastAPI
- PostgreSQL
- Redis (caching)
- S3/MinIO (storage)

**Infrastructure:**
- Docker + Kubernetes
- AWS/GCP
- Prometheus + Grafana
- Terraform (IaC)

### Pre-trained Models for Fine-Tuning

We recommend using **XTTS v2** or **StyleTTS2** as base models for:
- ✅ **Voice Cloning**: 6-second samples for instant voice cloning
- ✅ **Malaysian Accent**: Fine-tune with 10-30 minutes of data
- ✅ **Fast Training**: 2-5 hours on single GPU
- ✅ **Production Ready**: Commercial-friendly licenses

See [complete model comparison and guide](tts/docs/02_Technical_Architecture.md#13-open-source-base-models-for-fine-tuning) for 8+ open-source options.

---

## 📊 Project Status

### Current Phase: **Training** (Week 20 of 52)

| Phase | Status | Progress |
|-------|--------|----------|
| ✅ Research & Planning | Complete | 100% |
| ✅ Data Collection | Complete | 100% |
| 🔄 Model Training | In Progress | 65% |
| ⏳ Evaluation | Pending | 0% |
| ⏳ Deployment | Pending | 0% |
| ⏳ Launch | Pending | 0% |

### Recent Updates

**2025-10-12:**
- ✅ Comprehensive documentation completed
- ✅ Technical architecture finalized
- ✅ Training pipeline implemented
- 🔄 Main training in progress (200k/300k steps)
- 📊 Current MOS: 3.7 (target: > 4.0)

---

## 📁 Repository Structure

```
voice-ai/
├── README.md                          # This file
│
├── asr/                               # 🎧 ASR (Speech Recognition) System
│   ├── README.md                      # ASR project overview
│   └── docs/                          # Comprehensive ASR documentation
│       ├── 00_QUICK_START.md         # Quick start guide
│       ├── 01_PRD_Product_Requirements.md
│       ├── 02_Technical_Architecture.md  # Whisper + Unsloth architecture
│       ├── 03_Data_Preparation_Guide.md
│       ├── 04_Training_Strategy_Guide.md # Unsloth fine-tuning
│       ├── 05_Evaluation_Methodology.md
│       ├── 06_Deployment_Guide.md
│       └── 07_Project_Execution_Plan.md
│
├── tts/                               # 🎤 TTS (Speech Synthesis) System
│   └── docs/                          # Comprehensive TTS documentation
│       ├── 00_QUICK_START.md
│       ├── 01_PRD_Product_Requirements.md
│       ├── 02_Technical_Architecture.md
│       ├── 03_Data_Preparation_Guide.md
│       ├── 04_Training_Strategy_Guide.md
│       ├── 05_Evaluation_Methodology.md
│       ├── 06_Deployment_Guide.md
│       └── 07_Project_Execution_Plan.md
│
├── models/                            # Model implementations
│   ├── fastspeech2/
│   │   ├── model.py
│   │   ├── modules.py
│   │   └── loss.py
│   ├── hifigan/
│   │   ├── generator.py
│   │   └── discriminator.py
│   └── text_processor.py
│
├── preprocessing/                     # Data preprocessing
│   ├── audio_preprocessing.py
│   ├── feature_extraction.py
│   └── build_dataset.py
│
├── training/                          # Training scripts
│   ├── train_acoustic.py
│   ├── train_vocoder.py
│   ├── trainer.py
│   └── lr_scheduler.py
│
├── evaluation/                        # Evaluation scripts
│   ├── evaluate.py
│   ├── metrics.py
│   └── generate_samples.py
│
├── api/                               # Production API
│   ├── main.py
│   ├── models.py
│   └── dependencies.py
│
├── configs/                           # Configuration files
│   ├── base_config.yaml
│   ├── training_config.yaml
│   └── deployment_config.yaml
│
├── scripts/                           # Utility scripts
│   ├── download_models.py
│   ├── prepare_data.sh
│   └── deploy.sh
│
├── tests/                             # Unit and integration tests
│   ├── test_models.py
│   ├── test_preprocessing.py
│   └── test_api.py
│
├── notebooks/                         # Jupyter notebooks
│   ├── data_exploration.ipynb
│   └── model_analysis.ipynb
│
├── k8s/                               # Kubernetes manifests
│   ├── deployment.yaml
│   ├── service.yaml
│   └── hpa.yaml
│
├── monitoring/                        # Monitoring configs
│   ├── prometheus.yml
│   └── grafana-dashboards/
│
├── requirements.txt                   # Python dependencies
├── Dockerfile                         # Docker image
├── docker-compose.yml                 # Local development
└── .github/
    └── workflows/
        └── ci-cd.yml                  # CI/CD pipeline
```

---

## 🛠️ Development

### Setup Development Environment

```bash
# Clone repository
git clone https://github.com/yourorg/malaysian-tts.git
cd malaysian-tts

# Install development dependencies
pip install -r requirements-dev.txt

# Install pre-commit hooks
pre-commit install

# Run tests
pytest tests/ --cov=.

# Start development server
uvicorn api.main:app --reload
```

### Running with Docker

```bash
# Build image
docker build -t malaysian-tts:latest .

# Run with docker-compose
docker-compose up -d

# View logs
docker-compose logs -f tts-api

# Stop
docker-compose down
```

---

## 🧪 Testing

### Unit Tests

```bash
# Run all tests
pytest tests/

# Run with coverage
pytest tests/ --cov=. --cov-report=html

# Run specific test file
pytest tests/test_models.py
```

### Integration Tests

```bash
# Test API endpoints
pytest tests/test_api.py

# Test training pipeline
python tests/test_training.py
```

### Evaluation

```bash
# Run objective evaluation
python evaluation/evaluate.py \
  --model checkpoints/best_model.pt \
  --test-set data/test.json \
  --output results/

# Generate MOS test samples
python evaluation/generate_samples.py \
  --model checkpoints/best_model.pt \
  --num-samples 50 \
  --output mos_samples/
```

---

## 🚀 Deployment

### Quick Deploy (Development)

```bash
# Deploy to local Kubernetes
kubectl apply -f k8s/

# Check status
kubectl get pods -n tts-production

# Access API
kubectl port-forward svc/tts-service 8000:80
```

### Production Deployment

See [Deployment Guide](docs/06_Deployment_Guide.md) for detailed instructions on:
- Cloud infrastructure setup (AWS/GCP)
- Kubernetes configuration
- CI/CD pipeline
- Monitoring and logging
- Security and compliance

---

## 📈 Performance Benchmarks

### Inference Performance

| Configuration | RTF | Latency (p95) | GPU Memory |
|---------------|-----|---------------|------------|
| GPU (V100) | 0.15 | 180ms | 2.1 GB |
| GPU (RTX 3090) | 0.18 | 220ms | 2.3 GB |
| CPU (16 cores) | 1.2 | 1400ms | N/A |

### Quality Metrics

| Metric | Value | Target | Status |
|--------|-------|--------|--------|
| MOS Naturalness | 3.9 ± 0.3 | > 4.0 | 🟡 Close |
| MOS Prosody | 3.8 ± 0.4 | > 4.0 | 🟡 Close |
| MCD | 6.3 dB | < 6.5 dB | ✅ Pass |
| F0 RMSE | 21.2 Hz | < 25 Hz | ✅ Pass |
| WER | 4.2% | < 5% | ✅ Pass |

---

## 🤝 Contributing

We welcome contributions! Please see our [Contributing Guidelines](CONTRIBUTING.md) for details.

### Ways to Contribute

- 🐛 Report bugs and issues
- 💡 Suggest new features
- 📝 Improve documentation
- 🧪 Add test cases
- 🔧 Submit pull requests

### Development Workflow

1. Fork the repository
2. Create a feature branch (`git checkout -b feature/amazing-feature`)
3. Make your changes
4. Run tests (`pytest tests/`)
5. Commit your changes (`git commit -m 'Add amazing feature'`)
6. Push to the branch (`git push origin feature/amazing-feature`)
7. Open a Pull Request

---

## 📜 License

This project is licensed under the MIT License - see the [LICENSE](LICENSE) file for details.

---

## 🙏 Acknowledgments

### Data & Resources

- Voice actors and contributors
- Annotation team
- Open-source TTS community

### Open Source Projects

- [ESPnet](https://github.com/espnet/espnet) - TTS toolkit
- [Coqui TTS](https://github.com/coqui-ai/TTS) - FastSpeech 2 implementation
- [HiFi-GAN](https://github.com/jik876/hifi-gan) - Vocoder
- [Montreal Forced Aligner](https://github.com/MontrealCorpusTools/Montreal-Forced-Aligner) - Alignment
- [PyTorch](https://pytorch.org/) - Deep learning framework

### Research Papers

1. **FastSpeech 2**: Ren et al., "FastSpeech 2: Fast and High-Quality End-to-End Text to Speech" (2020)
2. **HiFi-GAN**: Kong et al., "HiFi-GAN: Generative Adversarial Networks for Efficient and High Fidelity Speech Synthesis" (2020)
3. **VITS**: Kim et al., "Conditional Variational Autoencoder with Adversarial Learning for End-to-End Text-to-Speech" (2021)

---

## 📞 Contact & Support

### Team

- **Technical Lead**: [Your Name] - tech-lead@example.com
- **Product Manager**: [PM Name] - pm@example.com
- **Project Repository**: https://github.com/yourorg/malaysian-tts

### Support Channels

- 📧 **Email**: support@malaysian-tts.com
- 💬 **Discord**: [Join our community](https://discord.gg/malaysian-tts)
- 📋 **Issues**: [GitHub Issues](https://github.com/yourorg/malaysian-tts/issues)
- 📚 **Documentation**: [Full Documentation](tts/docs/)

### Reporting Issues

When reporting issues, please include:
1. System information (OS, Python version, GPU)
2. Steps to reproduce
3. Expected vs actual behavior
4. Error messages and logs
5. Sample text input (if applicable)

---

## 🗺️ Roadmap

### Version 1.0 (Current - Launch Target: Dec 2025)

- [x] Core TTS functionality
- [x] Code-switching support
- [x] Particle pronunciation
- [x] REST API
- [x] Documentation
- [ ] MOS > 4.0 quality
- [ ] Production deployment
- [ ] Public beta

### Version 1.1 (Q1 2026)

- [ ] Multi-speaker support (5+ voices)
- [ ] Voice selection API
- [ ] Speed control
- [ ] SSML support
- [ ] Streaming output
- [ ] Mobile SDK

### Version 2.0 (Q2 2026)

- [ ] Emotion control
- [ ] Voice cloning
- [ ] Real-time streaming
- [ ] Additional languages (Tamil, Cantonese)
- [ ] On-device models
- [ ] Custom voice training

---

## 📊 Project Statistics

- **Lines of Code**: ~15,000
- **Training Data**: 65 hours (target: 75 hours)
- **Model Parameters**: 28M (acoustic) + 13M (vocoder)
- **Training Time**: ~4 weeks on 4× V100 GPUs
- **Model Size**: 180 MB (optimized)
- **Languages Supported**: 3 (Malay, English, Mandarin/Pinyin)
- **Particles Supported**: 10+ types

---

## ⭐ Star History

If you find this project useful, please consider giving it a star! ⭐

[![Star History Chart](https://api.star-history.com/svg?repos=yourorg/malaysian-tts&type=Date)](https://star-history.com/#yourorg/malaysian-tts&Date)

---

## 📝 Citation

If you use this project in your research, please cite:

```bibtex
@software{malaysian_tts_2025,
  title = {Malaysian Multilingual TTS System},
  author = {Your Team},
  year = {2025},
  url = {https://github.com/yourorg/malaysian-tts},
  version = {1.0}
}
```

---

<div align="center">

**Built with ❤️ in Malaysia 🇲🇾**

[Documentation](tts/docs/) • [Report Bug](https://github.com/yourorg/malaysian-tts/issues) • [Request Feature](https://github.com/yourorg/malaysian-tts/issues)

</div>





for Stage 2:

Generate Synthetic Data:
- cd /Users/kyan/data/swprojects/ytl/voice-ai/asr/synthetic_data_generation
- source .venv/bin/activate
- python scripts/generate_sentences.py --name 5k_v3 --max-sentences 5000 --seed 1510
- python scripts/synthesize_with_elevenlabs.py --name 5k_v3 --resume

(After completed)
- mv outputs/5k_v3 ../train/training_data/
- rsync

(in the server)
- python prepare_synthetic_manifests.py   --input ../training_data/5k_v3/synthesized.json   --audio-base-dir ../training_data/5k_v3/  --output-dir ./data   --train-split 0.9   --seed 4
- bash run_training.sh config_synthetic_names_numbers.yaml
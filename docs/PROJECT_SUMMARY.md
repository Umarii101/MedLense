# MedLens - Project Summary

## 🎯 Executive Summary

This project delivers a **production-ready, offline-capable healthcare AI backend** that demonstrates how open-weight models can be orchestrated to assist clinicians in resource-constrained environments. Built specifically for the Kaggle MedGemma Impact Challenge, it showcases responsible AI deployment in healthcare.

## ✅ Key Achievements

### 1. **Fully Open-Weight Architecture**
- ✅ MedGemma 4B-IT for clinical reasoning (primary)
- ✅ BiomedCLIP for medical image understanding
- ✅ No proprietary APIs or cloud dependencies
- ✅ Runs entirely on local GPU (RTX 3080)

### 2. **Dual Deployment Targets**

#### Desktop/Server (GPU)
- MedGemma 4B with 8-bit quantization (~4GB VRAM)
- CLIP ViT-L for image features (~2GB VRAM)
- Full-precision inference with transformers

#### Mobile/Edge (Android)
- MedGemma 4B Q4_K_S GGUF (2.2 GB)
- BiomedCLIP ONNX INT8 (84 MB)
- Optimized for Snapdragon 8s Gen 3

### 3. **Three Core Capabilities**

#### 📝 Clinical Text Understanding
- Summarizes clinical notes in non-diagnostic language
- Extracts symptoms, conditions, medications
- Generates actionable recommendations
- Calculates risk scores with explainability

#### 🏥️ Medical Image Analysis (Assistive)
- Feature extraction from X-rays, CTs, MRIs
- Image quality assessment
- Visual observations (non-diagnostic)
- Confidence scoring

#### 🔄 Multimodal Integration
- Combines text + image analysis
- LLM-powered reasoning across modalities
- Correlates findings intelligently
- Unified risk assessment

### 4. **Production-Quality Engineering**

#### Architecture
- Modular, testable codebase
- Clean separation of concerns
- Pydantic schemas for type safety
- Comprehensive error handling

#### Safety Systems
- 5-layer safety framework
- Non-diagnostic language enforcement
- Hallucination detection
- Clinical validation
- Mandatory disclaimers

## 📊 Technical Specifications

### Models

| Component | Model | Size | Memory | Purpose |
|-----------|-------|------|--------|---------|
| Primary LLM | MedGemma 4B-IT | 4B params | ~4GB | Clinical reasoning |
| Image Encoder | BiomedCLIP ViT-B | ~86M | ~1GB | Visual features |
| Risk Scorer | Rule-based + sklearn | Minimal | <1MB | Risk stratification |

### Edge Deployment Models

| Model | Format | Size | Accuracy |
|-------|--------|------|----------|
| BiomedCLIP Vision | ONNX INT8 | 84 MB | 99.91% cosine vs FP32 |
| MedGemma 4B | GGUF Q4_K_S | 2.2 GB | 74% size reduction |

### Model Quality Evaluation

Evaluated with 5 labeled chest X-rays and 5 clinical cases. Full methodology and results: [`evaluation/README.md`](../evaluation/README.md).

| Evaluation | Key Metric | Result |
|------------|-----------|--------|
| BiomedCLIP Zero-Shot Classification | Top-5 clinical hit rate | 80% (4/5) |
| BiomedCLIP Quantization Fidelity | INT8 vs FP32 cosine similarity | 0.9991 |
| MedGemma Clinical Quality | Automated rubric (10-point scale) | 8.6/10 EXCELLENT |
| MedGemma Safety — No Absolutes | % cases without diagnostic claims | 100% (5/5) |
| MedGemma Completeness | % cases with actionable next steps | 100% (5/5) |

### Performance Benchmarks (RTX 3080)

| Task | Time | GPU Memory |
|------|------|------------|
| Text Analysis | 5-10s | 4GB |
| Image Analysis | 2-3s | 2GB |
| Multimodal | 10-15s | 6GB |

### Hardware Requirements

**Desktop**:
- GPU: RTX 3060+ (10GB+ VRAM)
- RAM: 16GB+
- Storage: 30GB

**Mobile (Edge AI)**:
- SoC: Snapdragon 8s Gen 3 or equivalent
- RAM: 8GB+
- Storage: 3GB for quantized models

## 📂 Project Structure

```
Project 1/
├── Medlens/                    # ⭐ Production Android app
│   ├── APK/app-debug.apk     # Pre-built APK
│   ├── app/src/main/java/com/medgemma/edge/
│   └── README.md              # App architecture & build guide
├── Inference Test App/         # PoC predecessor (historical)
│   ├── DEPLOYMENT_TECHNICAL_REPORT.md
│   └── ROADMAP.md
├── edge_deployment/            # Mobile/edge models & integration
│   ├── models/
│   │   ├── biomedclip/        # ONNX INT8 (84 MB)
│   │   └── medgemma/          # GGUF Q4_K_S (2.2 GB)
│   └── README.md
├── quantization/               # Model quantization pipeline
│   └── scripts/               # 9 conversion & validation scripts
├── benchmarks/                 # On-device performance measurements
├── tests/                      # Validation tests
│   ├── test_biomedclip.py
│   ├── test_medgemma.py
│   └── run_all_tests.py
├── evaluation/                 # ⭐ Model quality evaluations
│   ├── README.md              # Methodology & results
│   ├── biomedclip_classification_eval.py
│   ├── medgemma_clinical_eval.py
│   ├── results/               # Pre-computed JSON results
│   └── test_data/             # Labeled test images
├── desktop_pipeline/           # Desktop/GPU prototype (RTX 3080)
│   ├── main.py                # Demo script
│   ├── models/                # MedGemma, BiomedCLIP, risk model loaders
│   ├── pipelines/             # Text, image, multimodal analysis
│   ├── schemas/               # Pydantic output models
│   ├── utils/                 # Safety checks, memory management
│   └── requirements.txt
├── docs/                       # Detailed documentation
│   ├── DOCUMENTATION.md
│   ├── SETUP_GUIDE.md
│   └── PROJECT_SUMMARY.md     # This file
├── README.md                   # Landing page
├── EDGE_DEPLOYMENT.md          # Edge AI narrative
└── LICENSE
```

## 🚀 Quick Start

```bash
# 1. Install dependencies
pip install -r desktop_pipeline/requirements.txt

# 2. Verify CUDA
python -c "import torch; print(torch.cuda.is_available())"

# 3. Run desktop demo
python desktop_pipeline/main.py

# 4. Test edge deployment models
python tests/run_all_tests.py
```

## ⚠️ Medical Disclaimer

**This system is for assistive purposes only. Not FDA approved. Not a substitute for professional medical judgment. All outputs require validation by licensed healthcare providers.**

---

**Built for the Kaggle MedGemma Impact Challenge**

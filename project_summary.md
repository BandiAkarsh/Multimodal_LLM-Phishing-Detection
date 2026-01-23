Here's a comprehensive **project summary document** that explains your project's goals, architecture, and distributed system integration.

---

## 📄 **PROJECT_SUMMARY.md**

```markdown
# Phishing Website Detection Using Multimodal Large Language Models (MLLM)

## 🎯 Project Overview

This is an **IEEE-level final year college project** that implements an advanced phishing detection system using **Multimodal Large Language Models (MLLM)** to analyze websites across multiple data modalities and classify them as legitimate or phishing attempts.

---

## 🔬 Research Foundation

**Base Paper**: "Phishing Website Detection Method Based on Multimodal Large Language Model"
- **Key Innovation**: Transform multimodal website features into text using LLMs
- **Performance**: Achieves 96.1% F1 score on public datasets
- **Approach**: Converts phishing detection into a text classification problem

---

## 🎓 Project Goals

### Primary Objectives

1. **Multimodal Phishing Detection**
   - Analyze websites using multiple data modalities:
     - **URL features** (structure, entropy, suspicious patterns)
     - **HTML/DOM structure** (forms, scripts, iframes)
     - **Visual features** (screenshots, layout, logos)
     - **Metadata** (SSL certificates, hosting provider, WHOIS)

2. **MLLM-Based Feature Transformation**
   - Use **Qwen2.5-3B-Instruct** (locally hosted) to transform multimodal features → text
   - Leverage LLM's semantic understanding for pattern recognition
   - Convert complex multimodal data into human-interpretable text descriptions

3. **Advanced Classification**
   - **Binary Classification**: Legitimate vs. Phishing
   - **Ternary Classification**: 
     - Legitimate website
     - AI-generated phishing site
     - Phishing-kit created site

4. **Production-Ready Service Layer**
   - Deploy as a **microservice** for email integration
   - Background processing (no end-user interaction)
   - RESTful API for real-time phishing detection

---

## 🏗️ System Architecture

```
┌─────────────────────────────────────────────────────────────────┐
│                        EMAIL CLIENT LAYER                        │
│  (Gmail, Outlook, Corporate Email Servers)                      │
└────────────────────────────┬────────────────────────────────────┘
                             │
                             ▼
┌─────────────────────────────────────────────────────────────────┐
│                   SERVICE LAYER (REST API)                       │
│  • URL Extraction from Emails                                   │
│  • Request Queue Management                                     │
│  • Response Caching                                             │
└────────────────────────────┬────────────────────────────────────┘
                             │
                             ▼
┌─────────────────────────────────────────────────────────────────┐
│              MULTIMODAL FEATURE EXTRACTION LAYER                 │
│  ┌──────────────┐  ┌──────────────┐  ┌──────────────┐          │
│  │ Web Scraper  │  │ URL Analyzer │  │ Metadata     │          │
│  │ (Playwright) │  │ (Entropy,    │  │ Extractor    │          │
│  │              │  │  Patterns)   │  │ (SSL, WHOIS) │          │
│  └──────────────┘  └──────────────┘  └──────────────┘          │
│         │                  │                  │                  │
│         └──────────────────┴──────────────────┘                  │
│                            │                                     │
│                            ▼                                     │
│              ┌──────────────────────────────┐                   │
│              │   Screenshot + HTML + DOM    │                   │
│              │   + URL Features + Metadata  │                   │
│              └──────────────────────────────┘                   │
└────────────────────────────┬────────────────────────────────────┘
                             │
                             ▼
┌─────────────────────────────────────────────────────────────────┐
│                  MLLM TRANSFORMATION LAYER                       │
│  ┌──────────────────────────────────────────────────────────┐  │
│  │         Qwen2.5-3B-Instruct (Local Inference)            │  │
│  │  • GPU: RTX 3050 4GB VRAM                                │  │
│  │  • CUDA 12.4                                             │  │
│  │  • Quantization: 4-bit (for memory efficiency)           │  │
│  └──────────────────────────────────────────────────────────┘  │
│                            │                                     │
│                            ▼                                     │
│              ┌──────────────────────────────┐                   │
│              │  Multimodal → Text Features  │                   │
│              │  "This website shows..."     │                   │
│              └──────────────────────────────┘                   │
└────────────────────────────┬────────────────────────────────────┘
                             │
                             ▼
┌─────────────────────────────────────────────────────────────────┐
│                   CLASSIFICATION LAYER                           │
│  ┌──────────────────────────────────────────────────────────┐  │
│  │  Binary Classifier: Legitimate (0) vs Phishing (1)       │  │
│  └──────────────────────────────────────────────────────────┘  │
│  ┌──────────────────────────────────────────────────────────┐  │
│  │  Ternary Classifier:                                      │  │
│  │    • Legitimate (0)                                       │  │
│  │    • AI-Generated Phishing (1)                           │  │
│  │    • Phishing-Kit Created (2)                            │  │
│  └──────────────────────────────────────────────────────────┘  │
└────────────────────────────┬────────────────────────────────────┘
                             │
                             ▼
┌─────────────────────────────────────────────────────────────────┐
│                      RESPONSE LAYER                              │
│  • Confidence Score                                             │
│  • Classification Result                                        │
│  • Explainability (Why flagged as phishing?)                   │
│  • Recommended Action (Block, Warn, Allow)                     │
└─────────────────────────────────────────────────────────────────┘
```

---

## 🔄 Distributed System Integration

### **Email Integration Architecture**

This project serves as a **backend microservice** in a distributed email security system:

#### **1. Email Gateway Integration**
```
Email Server (SMTP/IMAP)
    ↓
Email Security Gateway
    ↓
URL Extraction Service
    ↓
Phishing Detection API (This Project) ← YOU ARE HERE
    ↓
Decision Engine
    ↓
Action: Block/Quarantine/Warn/Allow
```

#### **2. Service Layer Components**

**A. API Endpoints**
```
POST /api/v1/analyze
  - Input: URL or list of URLs
  - Output: Classification + confidence + explanation

POST /api/v1/batch-analyze
  - Input: Batch of URLs (from email scan)
  - Output: Array of results

GET /api/v1/status/{job_id}
  - Check processing status for async requests
```

**B. Message Queue Integration**
```
Email arrives → Extract URLs → Push to Queue (RabbitMQ/Redis)
                                      ↓
                          Worker processes URL (This Project)
                                      ↓
                          Store result in cache (Redis)
                                      ↓
                          Notify email gateway
```

#### **3. Deployment Architecture**

```
┌─────────────────────────────────────────────────────────────┐
│                    Load Balancer (Nginx)                     │
└────────────────────────────┬────────────────────────────────┘
                             │
              ┌──────────────┴──────────────┐
              │                             │
              ▼                             ▼
┌──────────────────────┐      ┌──────────────────────┐
│  API Server 1        │      │  API Server 2        │
│  (Flask/FastAPI)     │      │  (Flask/FastAPI)     │
└──────────┬───────────┘      └──────────┬───────────┘
           │                             │
           └──────────────┬──────────────┘
                          │
                          ▼
           ┌──────────────────────────┐
           │   Message Queue          │
           │   (RabbitMQ/Redis)       │
           └──────────┬───────────────┘
                      │
        ┌─────────────┴─────────────┐
        │                           │
        ▼                           ▼
┌───────────────┐          ┌───────────────┐
│ Worker Node 1 │          │ Worker Node 2 │
│ RTX 3050 GPU  │          │ RTX 3050 GPU  │
│ MLLM Inference│          │ MLLM Inference│
└───────────────┘          └───────────────┘
        │                           │
        └─────────────┬─────────────┘
                      │
                      ▼
           ┌──────────────────────────┐
           │   Result Cache (Redis)   │
           └──────────────────────────┘
```

---

## 🛠️ Technology Stack

### **Core Technologies**

| Component | Technology | Purpose |
|-----------|-----------|---------|
| **MLLM** | Qwen2.5-3B-Instruct | Multimodal feature → text transformation |
| **Web Scraping** | Playwright (Async) | Screenshot + HTML + DOM extraction |
| **Feature Extraction** | Custom Python | URL analysis, entropy, patterns |
| **Deep Learning** | PyTorch, Transformers | Model inference |
| **API Framework** | FastAPI | RESTful service layer |
| **Message Queue** | RabbitMQ/Redis | Async job processing |
| **Database** | PostgreSQL + Redis | Data storage + caching |
| **Deployment** | Docker + Kubernetes | Containerization + orchestration |

### **Hardware Requirements**

- **GPU**: NVIDIA RTX 3050 (4GB VRAM)
- **CUDA**: 12.4
- **RAM**: 16GB minimum
- **Storage**: 50GB for models + datasets

---

## 📊 Dataset

### **Sources**
1. **PhishTank**: 46,317 verified phishing URLs
2. **OpenPhish**: 300 phishing URLs
3. **Legitimate URLs**: Custom collected (20 initially, need more)

### **Data Modalities**
- **URL**: Text string
- **Screenshot**: 1920x1080 PNG
- **HTML**: Full page source
- **DOM Structure**: Parsed features (forms, links, scripts)
- **Metadata**: SSL, WHOIS, hosting info

### **Labels**
- **Binary**: `0` = Legitimate, `1` = Phishing
- **Ternary** (future): `0` = Legitimate, `1` = AI-generated phishing, `2` = Phishing-kit

---

## 🎯 Key Innovations

### **1. Multimodal Fusion via MLLM**
Traditional methods analyze features separately. This project:
- Combines URL + HTML + Screenshot + Metadata
- Uses MLLM to understand **semantic relationships** between modalities
- Generates human-interpretable explanations

### **2. AI-Generated Phishing Detection**
With the rise of AI tools (ChatGPT, Claude), phishing sites are becoming more sophisticated:
- Detect if a phishing site was created using AI (natural language, realistic design)
- Distinguish from traditional phishing-kit templates

### **3. Explainable AI**
- Generate **why** a site was flagged (not just a score)
- Example: "This site mimics PayPal's login page but uses a suspicious domain with high entropy"

---

## 🚀 Project Milestones

### **Phase 1: Data Collection & Preprocessing** ✅ (Current)
- [x] Collect phishing datasets (PhishTank, OpenPhish)
- [x] Build web scraper (Playwright)
- [x] Extract multimodal features
- [x] Create train/val/test splits

### **Phase 2: MLLM Integration** ✅ (Current)
- [x] Load Qwen2.5-3B-Instruct locally
- [x] Design prompts for feature → text transformation
- [x] Optimize for 4GB VRAM (quantization)
- [x] Generate text features for dataset

### **Phase 3: Classification Model** 🔄 (Next)
- [ ] Train binary classifier (phishing vs. legitimate)
- [ ] Train ternary classifier (AI-generated detection)
- [ ] Evaluate on test set (target: >96% F1 score)

### **Phase 4: Service Layer** 📅
- [ ] Build FastAPI REST API
- [ ] Implement message queue (RabbitMQ)
- [ ] Add Redis caching
- [ ] Email integration (SMTP/IMAP)

### **Phase 5: Deployment** 📅
- [ ] Dockerize application
- [ ] Deploy on Kubernetes
- [ ] Load testing & optimization
- [ ] Documentation & IEEE paper

---

## 📈 Expected Outcomes

### **Performance Metrics**
- **F1 Score**: >96% (matching base paper)
- **Precision**: >95% (minimize false positives)
- **Recall**: >97% (catch most phishing attempts)
- **Inference Time**: <5 seconds per URL

### **Production Metrics**
- **API Latency**: <3 seconds per request
- **Throughput**: 100+ URLs/minute
- **Uptime**: 99.9%

---

## 🔐 Security Considerations

1. **Sandboxed Scraping**: Playwright runs in isolated containers
2. **Rate Limiting**: Prevent API abuse
3. **Input Validation**: Sanitize URLs before processing
4. **Data Privacy**: No storage of email content, only URLs

---

## 📚 Academic Contribution

### **IEEE Paper Structure**
1. **Abstract**: Multimodal MLLM approach
2. **Introduction**: Phishing threat landscape
3. **Related Work**: Traditional vs. MLLM methods
4. **Methodology**: Architecture, MLLM transformation
5. **Experiments**: Dataset, metrics, results
6. **Results**: Performance comparison
7. **Conclusion**: Future work (AI-generated detection)

### **Novel Contributions**
- First to apply **Qwen2.5** for phishing detection
- **AI-generated phishing detection** (new problem)
- **Production-ready service layer** (not just research)

---

## 👨‍🎓 Project Team

- **Student**: Final year college student
- **Domain**: Cybersecurity, Machine Learning
- **Duration**: 6 months (final year project)
- **Target**: IEEE-level publication + working prototype

---

## 📞 Contact & Resources

- **GitHub**: [Your repository]
- **Documentation**: `/docs`
- **Models**: `.cache/huggingface/hub/models--Qwen--Qwen2.5-3B-Instruct`
- **Dataset**: `01_data/raw/`

---

## 🔮 Future Enhancements

1. **Real-time Browser Extension**: Warn users before clicking phishing links
2. **Mobile App Integration**: Protect mobile email clients
3. **Federated Learning**: Train on distributed data without centralization
4. **Multi-language Support**: Detect phishing in non-English sites
5. **Zero-day Phishing Detection**: Detect novel phishing patterns

---

**Last Updated**: January 2026  
**Status**: Phase 2 Complete, Phase 3 In Progress
```

--- 

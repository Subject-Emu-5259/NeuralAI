# 🧠 NeuralAI

![License](https://img.shields.io/badge/License-MIT-blue)

 

![Python](https://img.shields.io/badge/Python-3.10+-green)

 

![PyTorch](https://img.shields.io/badge/PyTorch-2.0+-red)

 

![Status](https://img.shields.io/badge/Status-Production-green)

**A production-ready AI assistant built from scratch using PyTorch and Hugging Face transformers.**

Fine-tuned from SmolLM2-360M-Instruct with QLoRA — 360M parameters, optimized for chat, coding, document analysis, and reasoning.

---

## 🚀 Roadmap v5.0

**Coming Soon:** NeuralAI v5.0 with major expansions:

- **Training Data:** 347 → 1000+ samples (159 DPO preference pairs generated)
- **DPO Alignment:** Better response quality through preference optimization ✅ COMPLETED
- **GPU Inference:** 10x faster responses with CUDA acceleration
- **Automated Evaluation:** Benchmark suite for continuous quality assessment
- **Expanded Tools:** Code sandbox, file manager, web fetcher, database connector, git assistant

📖 See [ROADMAP.md](ROADMAP.md) for full details.

---

## ✨ Features & Capabilities

### 🤖 AI Chat

| Feature | Description |
| --- | --- |
| **Local LLM** | SmolLM2-360M-Instruct, fine-tuned with QLoRA |
| **Streaming** | Word-by-word SSE streaming responses |
| **Memory** | Full conversation context per session |
| **Code Highlighting** | Syntax-highlighted code blocks, copy button |
| **Markdown** | Bold, italic, lists, inline code |

### 📄 Document Intelligence (RAG)

| Capability | Description |
| --- | --- |
| **File Support** | PDF, DOCX, DOC, TXT, MD |
| **Semantic Search** | ChromaDB vector storage, `all-MiniLM-L6-v2` embeddings |
| **Chunking** | 500 chars per chunk, 80 char overlap |
| **Context Injection** | Top-4 relevant chunks passed to model as context |
| **File Chips** | Attached files shown on messages |

### 💻 Integrated Terminal

| Feature | Description |
| --- | --- |
| **Persistent PTY** | Real bash shell via WebSocket/Flask |
| **Session Persistence** | Terminal survives tab switches |
| **Custom Commands** | `neural <msg>` — chat with AI from terminal |
| **System Status** | `uplink`, `model`, `uptime` commands |
| **Actions** | Clear, Restart, Kill session |

### 🌐 Neural Uplink (Agent Network)

| Feature | Description |
| --- | --- |
| **Baltimore Node** | 4 AI agents: Dialog, Data, Ops, Worldbuilder |
| **Hybrid Routing** | Complex tasks automatically routed to agents |
| **Auto-detection** | Keywords like "research", "analyze", "debug" trigger uplink |
| **Parallel Agents** | 4 agents handle specialized sub-tasks |

### 🧠 Reasoning & Analysis

- **Concepts**: Machine learning, transformers, algorithms, data structures
- **Math**: Arithmetic, algebra, calculus explanations
- **Logic**: Problem solving, step-by-step reasoning
- **Comparison**: Technology analysis, pros/cons, recommendations

### 🛠️ Coding & Development

| Capability | Languages | Features |
| --- | --- | --- |
| **Code Generation** | Python, JavaScript, SQL, Go, Rust, HTML/CSS | Functions, classes, scripts, APIs |
| **Code Explanation** | Any language | Line-by-line breakdown, pattern identification |
| **Debugging** | Python, JS, SQL | Error analysis, fix suggestions |
| **REST API Design** | OpenAPI/Swagger style | Endpoints, schemas, status codes |
| **Database Design** | SQL schemas | Normalization, indexes, queries |

---

## 💾 Persistence & Memory (v4.0)

NeuralAI v4.0 introduces full persistence with SQLite:

### 🗄️ Database Storage

| Table | Purpose |
| --- | --- |
| **conversations** | Chat history with titles and timestamps |
| **messages** | Individual messages linked to conversations |
| **user_settings** | Persistent user preferences |
| **memory_facts** | Long-term memory facts about the user |
| **custom_rules** | User-defined rules for AI behavior |

### 💬 Conversation Management

| Feature | Description |
| --- | --- |
| **List Conversations** | View all past chats with titles |
| **Create New** | Start fresh conversations |
| **Rename** | Custom titles for each chat |
| **Delete** | Remove old conversations |
| **History** | Full message history per conversation |

### 🧠 Persistent Memory

| Feature | Description |
| --- | --- |
| **Memory Facts** | Store facts about user that persist across sessions |
| **Categories** | Organize facts by category |
| **Auto-injection** | Facts automatically included in system prompt |

### ⚙️ User Settings

| Setting | Description |
| --- | --- |
| **model_name** | Active model selection |
| **model_temperature** | Response randomness (0-1) |
| **model_max_tokens** | Max response length |
| **theme** | Light/dark mode preference |
| **user_bio** | User profile for personalization |

---

## 🔄 New Endpoints (v4.0)

### Conversation Management

| Endpoint | Method | Description |
| --- | --- | --- |
| `/api/conversations` | GET | List all conversations |
| `/api/conversations` | POST | Create new conversation |
| `/api/conversations/<id>` | GET | Get conversation with messages |
| `/api/conversations/<id>` | DELETE | Delete conversation |
| `/api/conversations/<id>/rename` | POST | Rename conversation |
| `/api/conversations/<id>/messages` | POST | Add message to conversation |

### Settings & Memory

| Endpoint | Method | Description |
| --- | --- | --- |
| `/api/settings` | GET | Get all user settings |
| `/api/settings` | POST | Update user settings |
| `/api/settings/<key>` | GET | Get specific setting |
| `/api/memory` | GET | List all memory facts |
| `/api/memory` | POST | Add memory fact |
| `/api/memory/<id>` | DELETE | Delete memory fact |
| `/api/rules` | GET | List custom rules |
| `/api/rules` | POST | Add custom rule |
| `/api/rules/<id>` | DELETE | Delete rule |
| `/api/rules/<id>/toggle` | POST | Enable/disable rule |

---

## 🏗️ Architecture

```markdown
User Input
  │
  ├─ Chat Tab ──── SmolLM2-360M-Instruct (local CPU inference)
  │               ├─ RAG: ChromaDB + all-MiniLM-L6-v2
  │               └─ Uplink: Neural Uplink Baltimore Node
  │
  └─ Terminal Tab ─ Persistent PTY (Bash shell)
                      ├─ Native shell commands
                      └─ `neural <msg>` ──── routes to AI model
```

| Component | Details |
| --- | --- |
| **Base Model** | HuggingFaceTB/SmolLM2-360M-Instruct |
| **Fine-tuning** | QLoRA (4-bit NF4, rank=16, alpha=32) + DPO alignment |
| **Embedding** | all-MiniLM-L6-v2 (384 dim) |
| **Vector DB** | ChromaDB (Persistent) |
| **Terminal** | PTY-based shell via WebSocket/Flask |
| **Framework** | Flask + vanilla JS (no frontend frameworks) |
| **Device** | CPU (float32) — GPU-ready (float16 CUDA) |

---

## 🚀 Quick Start

```bash
# Clone
git clone https://github.com/Subject-Emu-5259/NeuralAI-from-scratch.git
cd NeuralAI-from-scratch

# Install dependencies
pip install torch transformers peft chromadb sentence-transformers pypdf python-docx flask

# Run the web UI (port 5000)
cd from-scratch/web_ui
python app.py
```

**Live:** https://neuralai-deandrewharris.zocomputer.io

---

## 📁 Project Structure

```markdown
NeuralAI-from-scratch/
├── README.md              ← This file
├── SOCIAL.md              ← Social media preview & branding
├── TRAINING.md             ← Training metrics & dataset
├── requirements.txt       ← Python dependencies
├── checkpoints/           ← Trained model weights
│   ├── final_model/       ← LoRA adapter + config
│   └── dpo_model/         ← DPO-aligned model (v5.0)
├── data/
│   ├── train.jsonl        ← SFT training data (347 samples)
│   └── train_dpo_v3.jsonl ← DPO preference pairs (159)
└── from-scratch/
    ├── training/
    │   ├── train_neuralai.py   ← QLoRA fine-tuning script
│   └── train_dpo.py        ← DPO training script
    └── web_ui/
        ├── app.py              ← Flask backend (chat, RAG, terminal, uplink, persistence)
        ├── neuralai.db         ← SQLite database (v4.0)
        ├── rag.py              ← RAG: embedding, chunking, retrieval
        ├── terminal.py         ← PTY terminal via WebSocket/Flask
        ├── templates/
        │   └── index.html      ← Full UI: tabs, chat, terminal, settings
        └── static/
            ├── css/main.css    ← Styles
            ├── js/main.js      ← Frontend logic
            └── assets/logo.png  ← Brain logo
```

---

## 🌐 Live Deployment

**Web UI:** https://neuralai-deandrewharris.zocomputer.io

| Endpoint | Method | Description |
| --- | --- | --- |
| `/` | GET | Full UI (Chat + Terminal tabs) |
| `/api/chat` | POST | Stream chat response (SSE) |
| `/api/upload` | POST | Upload PDF/DOCX/TXT/MD for RAG |
| `/api/status` | GET | Model, RAG, Uplink, Terminal status |
| `/api/files` | GET | List indexed documents |
| `/api/terminal/create` | POST | Create PTY session |
| `/api/terminal/<id>/write` | POST | Send input to PTY |
| `/api/terminal/<id>/read` | GET | Read PTY output |
| `/api/terminal/<id>/stop` | POST | Kill PTY session |

---

## 🔬 Training Details

| Metric | Value |
| --- | --- |
| **Base Model** | SmolLM2-360M-Instruct (360M params) |
| **Method** | QLoRA — 4-bit NF4 quantization |
| **LoRA Rank** | 16 |
| **LoRA Alpha** | 32 |
| **Dropout** | 0.05 |
| **Learning Rate** | 2e-4 with scheduler + warmup |
| **Batch Size** | 4 |
| **Gradient Accumulation** | 4 steps |
| **Max Length** | 512 tokens |
| **Validation Split** | 20% |
| **Gradient Clipping** | 1.0 |
| **Training Samples** | 347 SFT + 159 DPO |
| **Final Loss** | 0.040 |
| **Loss Improvement** | 98% reduction |

---

## 🎯 DPO Alignment (v5.0)

NeuralAI v5.0 introduces Direct Preference Optimization for better response quality. The model was trained on 159 human-curated preference pairs across 8 quality dimensions.

### 🏋️ Training Configuration

| Parameter | Value |
| --- | --- |
| **Method** | Direct Preference Optimization (DPO) |
| **Dataset** | 159 preference pairs (train_dpo_v3.jsonl) |
| **Categories** | Code correctness, code style, conciseness, grounding, helpfulness, safety, tool usage, accuracy |
| **Beta** | 0.1 |
| **Learning Rate** | 5e-5 with linear decay |
| **Epochs** | 1 |
| **Duration** | 67 minutes (CPU) |
| **Framework** | TRL 1.3.0 + PyTorch |

### 📊 Training Metrics

| Metric | Step 1 | Step 21 (Final) |
| --- | --- | --- |
| **Loss** | 0.693 | **0.288** (−58%) |
| **Chosen Reward** | 0.000 | **+0.363** |
| **Rejected Reward** | 0.000 | **−0.733** |
| **Preference Margin** | 0.000 | **+1.096** |
| **Accuracy** | 0% | **100%** |

### 🧠 What the Model Learned

| Category | Learned Preference |
| --- | --- |
| **Code Correctness** | Working, tested code over buggy or incomplete implementations |
| **Code Style** | Idiomatic, readable patterns over verbose/inefficient approaches |
| **Conciseness** | Clear, direct answers over rambling, repetitive explanations |
| **Grounding** | Factual claims backed by reasoning over speculative hallucination |
| **Helpfulness** | Complete, actionable responses over partial or vague answers |
| **Safety** | Appropriate refusals with explanations over compliance with harmful requests |
| **Tool Usage** | Proper function/tool invocation patterns over manual workarounds |
| **Accuracy** | Factually correct information over plausible-sounding but incorrect statements |

### 📈 Reward Progression

- **Steps 1-4**: Initial signal emerges (margin 0.0 → 0.04)
- **Steps 5-9**: Strong separation phase (margin 0.08 → 0.60)
- **Steps 10-15**: Refinement phase (margin 0.41 → 0.89)
- **Steps 16-21**: Convergence (margin 0.70 → **1.10**, accuracy 100%)

The model achieves perfect preference accuracy while maintaining a healthy 1.10 reward margin — indicating robust alignment without overfitting.

---

## ⚙️ API Reference

### `POST /api/chat`

```json
{
  "prompt": "Write fibonacci in Python",
  "messages": [{"role": "user", "content": "..."}],
  "temperature": 0.7,
  "max_tokens": 512,
  "file_ids": ["abc123"]
}
```

Response: Server-Sent Events (SSE) stream of `{"content": "word "}` chunks.

### `POST /api/upload`

- `Content-Type: multipart/form-data`
- Field: `file` (PDF/DOCX/DOC/TXT/MD, max 16MB)
- Response: `{"success": true, "filename": "...", "file_id": "...", "chunks": N}`

### `GET /api/status`

```json
{
  "model": "HuggingFaceTB/SmolLM2-360M-Instruct",
  "model_type": "fine-tuned",
  "device": "cpu",
  "version": "2.4",
  "rag": true,
  "uplink": "connected",
  "indexed_files": 1
}
```

---

## 🛡️ Safety & Limitations

- NeuralAI may produce inaccurate information — always verify critical outputs
- RAG context is limited to top-4 retrieved chunks (max \~2000 chars)
- Model is 360M params — less capable than large models on complex reasoning
- CPU inference is slower than GPU — expect 10-20 sec for typical responses

---

## 📝 License

MIT License — free to use, modify, and commercialize.

---

**Built with ❤️ by [Subject-Emu-5259](https://github.com/Subject-Emu-5259)**

**Project is owned, Made and Built by DeAndrew P Harris a College Student of Maestro College for AI Engineering**

*Last Updated: May 17, 2026 | Version: 5.1 | Status: Production* 🟢

---

## ✨ Terminal 2.0

NeuralAI now features an upgraded terminal with multi-shell support:

### 🖥️ Multi-Shell Support

| Shell | Prompt | Use Case |
| --- | --- | --- |
| **Bash** | `$` | System commands, file operations |
| **Python** | `>>>` | Quick scripts, data analysis |
| **Node.js** | `>` | JavaScript runtime, npm packages |

### ⌨️ Terminal Features

- **Tab-based switching** between Bash, Python, and Node.js
- **Command shortcuts**: `ls -la`, `git status`, `pip list`, `npm -v`
- **Persistent sessions** across tab switches
- **Session management**: Clear, Restart, Kill
- **Color-coded output**: Errors (red), Success (green), Info (blue)

### 🔧 Terminal API

| Endpoint | Method | Description |
| --- | --- | --- |
| `/api/terminal/create` | POST | Create PTY session |
| `/api/terminal/<id>/write` | POST | Send input to PTY |
| `/api/terminal/<id>/read` | GET | Read PTY output |
| `/api/terminal/<id>/stop` | POST | Kill PTY session |
| `/api/terminal/sessions` | GET | List active sessions |

---

## 🧠 NeuralAI Engine v3.0

New unified routing engine for intelligent task distribution:

### 📊 Smart Routing

| Trigger | Route | Description |
| --- | --- | --- |
| Simple questions | Local Model | Fast, direct responses |
| "research", "analyze", "debug" | Neural Uplink | Parallel agent processing |
| "run ", "execute ", "shell " | Terminal Tool | Command execution |
| Messages &gt; 200 chars | Neural Uplink | Complex task handling |

### 🔀 Routing Logic

```markdown
User Message
    │
    ├─ Tool Check ──── "run/execute/shell" → Terminal Execution
    │
    ├─ Uplink Check ── "research/analyze/debug" or >200 chars → Agent Network
    │
    └─ Default ─────── Local Model (SmolLM2-360M)
```

### 🌐 Neural Uplink Integration

- **4 Parallel Agents**: Dialog, Data, Ops, Worldbuilder
- **Auto-registration** on startup
- **Health monitoring** via `/api/status`
- **Fusion responses** from multiple agents

---

## 🎨 UI Upgrades v3.0

### 📁 File Management

- **Files tab** with grid view
- **Upload/delete** documents
- **Index tracking** for RAG
- **File chips** on messages

### ⚙️ Settings Panel

- **Model info**: Name, type, device
- **RAG status**: Active/Inactive
- **Uplink status**: Connected/Offline
- **Indexed files** count
- **Version** display

### 🎯 Quick Actions

- **Prompt cards**: "Explain ML", "Write code", "Brainstorm", "Summarize"
- **Mode tabs**: All, Chat, Files, System
- **Keyboard shortcuts**: Enter to send

---

## 🔄 New Endpoints

### File Management

| Endpoint | Method | Description |
| --- | --- | --- |
| `/api/files` | GET | List all indexed files with IDs |
| `/api/files/<id>` | DELETE | Delete file from index and disk |

### Status & Health

| Endpoint | Method | Description |
| --- | --- | --- |
| `/api/health` | GET | Quick health check |
| `/api/status` | GET | Full system status |

### Enhanced Chat

```json
{
  "prompt": "Research machine learning",
  "messages": [...],
  "temperature": 0.7,
  "max_tokens": 512,
  "file_ids": ["abc123"],
  "use_uplink": false
}
```

---

## 📦 New Files

```markdown
web_ui/
├── neuralai_engine.py    ← Unified routing engine
├── neuralai_router.py    ← Task router logic
├── neuralai_terminal.py ← Terminal execution engine
├── terminal_ws.py        ← WebSocket endpoint
└── static/
    ├── favicon.png       ← New favicon
    └── neuralai_brain_logo.jpg  ← Clean brain logo
```

---

**Built with ❤️ by [Subject-Emu-5259](https://github.com/Subject-Emu-5259)**

**Project is owned, Made and Built by DeAndrew P Harris a College Student of Maestro College for AI Engineering**

*Last Updated: May 17, 2026 | Version: 5.1 | Status: Production* 🟢
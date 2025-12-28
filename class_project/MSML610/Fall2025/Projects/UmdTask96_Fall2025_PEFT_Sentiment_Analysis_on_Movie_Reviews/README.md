# Fake News Detection using PEFT (LoRA)

- **VIKAS PATEL**
- **University ID (UID) - 120988417**
- **Project 3: Fake News Detection**
- **Difficulty: 3 (Hard)**
- **Project Objective: Develop a robust fake news detection system by fine-tuning a large pre-trained transformer model using PEFT, leveraging a dataset of labeled news articles.**

A full-stack machine learning application that detects fake news using Parameter-Efficient Fine-Tuning (PEFT) with Low-Rank Adaptation (LoRA) on RoBERTa. The project demonstrates state-of-the-art NLP techniques with an accessible web interface.

## 🎯 Project Overview

This project implements a binary classification system to distinguish between true and fake news articles. It uses:

- **Base Model**: RoBERTa-base (125M parameters)
- **Fine-tuning Method**: LoRA (Low-Rank Adaptation) via PEFT
- **Trainable Parameters**: ~0.4M (0.32% of base model)
- **Frontend**: Streamlit web interface
- **Backend**: Flask REST API
- **Deployment**: Docker & Docker Compose

### Architecture

```
┌─────────────────────────────────────────────────────────────┐
│                    User Interface (Streamlit)                │
│                     Port 8501 - Browser                      │
└────────────────────────┬────────────────────────────────────┘
                         │ HTTP Requests
                         ▼
┌─────────────────────────────────────────────────────────────┐
│              Flask REST API (backend.py)                     │
│                     Port 5001                                │
│  ┌───────────────────────────────────────────────────┐      │
│  │ RoBERTa-base + LoRA Adapter (checkpoint-800)      │      │
│  │ • Tokenization (max_length=512)                   │      │
│  │ • Forward pass through model                      │      │
│  │ • Softmax probabilities                           │      │
│  │ • Label mapping: 0=True News, 1=Fake News        │      │
│  └───────────────────────────────────────────────────┘      │
└─────────────────────────────────────────────────────────────┘
                         ▲
                         │ Model Checkpoint
┌────────────────────────┴────────────────────────────────────┐
│            Training Pipeline (Code_files/)                   │
│  • Data preprocessing (PEFT_Sentiment_Analysis_utils.py)    │
│  • LoRA configuration (r=8, alpha=16, dropout=0.1)          │
│  • Training with HuggingFace Trainer                        │
│  • Checkpoint saving every 100 steps                        │
└─────────────────────────────────────────────────────────────┘
```

## 📦 Project Structure

```
UmdTask96_Fall2025_PEFT_Sentiment_Analysis_on_Movie_Reviews/
├── README.md                          # This file - main documentation
├── requirements.txt                   # Python dependencies
├── docker-compose.yml                 # Full-stack deployment
├── .gitignore                         # Git ignore patterns
│
├── Code_files/                        # Training environment
│   ├── README.md                      # Detailed training documentation
│   ├── Dockerfile                     # Training container (Jupyter on 8888)
│   ├── PEFT_Sentiment_Analysis.ipynb  # Main training notebook
│   ├── PEFT_Sentiment_Analysis_utils.py # Utility functions (13 functions)
│   └── checkpoint-800/                # Trained LoRA adapter
│       ├── adapter_config.json
│       └── adapter_model.safetensors
│
├── frontend/                          # Web application
│   ├── README.md                      # Frontend-specific documentation
│   ├── Dockerfile                     # Frontend container
│   ├── app.py                         # Streamlit UI (202 lines)
│   ├── backend.py                     # Flask API (120 lines)
│   └── start.sh                       # Local development script
│
└── Data/                              # Training dataset
    └── fake_news_data_train.csv       # True/Fake news articles
```

## 🚀 Quick Start

### Option 1: One-Click Startup (Easiest) ⭐

Run the application and automatically open it in your browser:

```bash
# Navigate to project directory
cd /path/to/UmdTask96_Fall2025_PEFT_Sentiment_Analysis_on_Movie_Reviews

# Run the startup script
./start_app.sh
```

**Expected output:**

```
🚀 Starting Fake News Detector Application...

[+] Running 2/2
 ✔ Network fake-news-network     Created
 ✔ Container fake-news-detector  Started

⏳ Waiting for services to be ready...

✅ Backend is ready!
✅ Streamlit is ready!

🎉 Application is ready!

📱 Opening Streamlit app in your browser...
   URL: http://localhost:8501

📊 To view logs: docker-compose logs -f
🛑 To stop: docker-compose down
```

The script will:

- ✅ Start Docker containers in the background
- ✅ Wait for services to be ready
- ✅ Automatically open http://localhost:8501 in your browser
- ✅ Display helpful commands for logs and stopping

To stop the application:

```bash
docker-compose down
```

**Expected output:**

```
[+] Running 2/2
 ✔ Container fake-news-detector  Removed
 ✔ Network fake-news-network     Removed
```

### Option 2: Docker Compose (Manual)

Run the complete application manually:

```bash
# Start the web application
docker-compose up
```

**Expected output:**

```
[+] Running 2/2
 ✔ Network fake-news-network     Created
 ✔ Container fake-news-detector  Created
Attaching to fake-news-detector
fake-news-detector  |
fake-news-detector  | Collecting usage statistics...
fake-news-detector  |
fake-news-detector  |   You can now view your Streamlit app in your browser.
fake-news-detector  |   URL: http://0.0.0.0:8501
fake-news-detector  |
fake-news-detector  | ============================================================
fake-news-detector  | 🚀 Starting PEFT Fake News Detector Backend API
fake-news-detector  | ============================================================
fake-news-detector  | 📦 Loading model...
fake-news-detector  | ✅ Model loaded successfully from checkpoint
fake-news-detector  | ✅ Server starting on http://localhost:5001
fake-news-detector  |  * Running on all addresses (0.0.0.0)
fake-news-detector  |  * Running on http://127.0.0.1:5001
```

**Access the application in your browser:**

- Streamlit UI: http://localhost:8501
- Flask API: http://localhost:5001

**Stop with Ctrl+C, then:**

```bash
docker-compose down
```

**For training environment (optional):**

```bash
# Start training container with Jupyter
docker-compose --profile training up

# Access Jupyter: http://localhost:8888
```

**Expected output:**

```
[+] Running 1/1
 ✔ Container fake-news-training  Started
fake-news-training  | [I 12:00:00.123 NotebookApp] Jupyter Notebook is running at:
fake-news-training  | [I 12:00:00.123 NotebookApp] http://0.0.0.0:8888/
```

### Option 3: Local Development

**Prerequisites:**

- Python 3.11+
- 8GB+ RAM recommended

```bash
# 1. Create virtual environment
python3 -m venv .venv
source .venv/bin/activate  # On Windows: .venv\Scripts\activate

# 2. Install dependencies
pip install -r requirements.txt

# 3. Start the application
cd frontend
./start.sh

# Or manually:
python backend.py &        # Starts Flask on port 5001
streamlit run app.py       # Opens browser to localhost:8501
```

### Option 4: Training from Scratch

See `Code_files/README.md` for detailed training instructions.

```bash
# Build training container
docker build -f Code_files/Dockerfile -t fake-news-training .

# Run Jupyter
docker run -p 8888:8888 -v $(pwd)/Code_files:/workspace fake-news-training

# Open PEFT_Sentiment_Analysis.ipynb
# Train model and save checkpoint
```

## 🧠 Model Details

### Training Configuration

- **Dataset**: Custom fake news dataset (true/fake labels)
- **Base Model**: `roberta-base` (125M parameters)
- **LoRA Config**:
  - Rank (r): 8
  - Alpha: 16
  - Dropout: 0.1
  - Target modules: `query`, `value` attention layers
  - Trainable parameters: ~400K (0.32%)

### Performance

- **Best Checkpoint**: checkpoint-800
- **Label Mapping** (CRITICAL):
  - Label 0 → True News
  - Label 1 → Fake News
- **Confidence Levels**:
  - High: ≥80% probability
  - Moderate: 60-79% probability
  - Low: <60% probability

### Example Predictions

```python
# Via API
curl -X POST http://localhost:5001/api/predict \
  -H "Content-Type: application/json" \
  -d '{"text": "Breaking: Scientists discover new planet in solar system"}'

# Response
{
  "prediction": "Fake News",
  "confidence": {
    "true_news": 22.5,
    "fake_news": 77.5,
    "level": "Moderate"
  }
}
```

## 🌐 Web Interface Features

### User Experience

- **Simple, centered layout** - No sidebars or clutter
- **Dark theme** - Professional appearance
- **Dropdown menus** - 10 pre-loaded examples (5 true, 5 fake)
- **Bidirectional reset** - Selecting one dropdown resets the other
- **Custom input** - Text area for user-provided articles
- **Real-time predictions** - Instant results with confidence scores
- **Visual indicators** - Color-coded prediction boxes

### API Endpoints

#### `GET /`

Health check for web browser access.

#### `GET /api/health`

```json
{
  "status": "healthy",
  "model_loaded": true,
  "timestamp": "2025-12-05T10:30:00"
}
```

#### `POST /api/predict`

**Request:**

```json
{
  "text": "Your news article text here..."
}
```

**Response:**

```json
{
  "prediction": "True News",
  "confidence": {
    "true_news": 78.3,
    "fake_news": 21.7,
    "level": "Moderate"
  }
}
```

## 🛠️ Development

### Running Tests

```bash
# Install test dependencies
pip install pytest pytest-cov

# Run tests
pytest Code_files/

# With coverage
pytest --cov=Code_files --cov-report=html
```

### Modifying the Model

1. Edit `PEFT_Sentiment_Analysis.ipynb` in Jupyter
2. Adjust LoRA parameters in cell 4:
   ```python
   config = LoraConfig(
       r=16,              # Increase rank for more capacity
       lora_alpha=32,     # Scale factor
       lora_dropout=0.1,
       bias="none",
       task_type="SEQ_CLS"
   )
   ```
3. Retrain and save new checkpoint
4. Update `backend.py` line 35 to point to new checkpoint

### Extending the Frontend

- **Add more examples**: Edit `app.py` lines 81-101
- **Change styling**: Modify CSS in `app.py` lines 17-50
- **Add features**: Extend Flask routes in `backend.py`

## 🐛 Troubleshooting

### Port 5001 Already in Use (macOS)

```bash
# Disable AirPlay Receiver
System Preferences → Sharing → Uncheck "AirPlay Receiver"

# Or change port in backend.py and app.py
# Change 5001 to another port like 5002
```

### Model Not Loading

```bash
# Verify checkpoint exists
ls -la Code_files/checkpoint-800/

# Check absolute path in backend.py line 35
# Should point to: .../Code_files/checkpoint-800
```

### Docker Build Fails

```bash
# Clear Docker cache
docker system prune -a

# Rebuild with no cache
docker-compose build --no-cache
```

### Predictions Are Reversed

```bash
# Verify label mapping in backend.py lines 77-81
# Label 0 MUST be True News
# Label 1 MUST be Fake News
```

## 📚 Additional Resources

- **Frontend Documentation**: `frontend/README.md` - Detailed file breakdowns
- **Training Documentation**: `Code_files/README.md` - Training pipeline guide
- **LoRA Paper**: [LoRA: Low-Rank Adaptation of Large Language Models](https://arxiv.org/abs/2106.09685)
- **PEFT Library**: [HuggingFace PEFT Documentation](https://huggingface.co/docs/peft)

## 📝 License

MIT License - See LICENSE file for details.

## 👥 Contributors

- **Course**: MSML610 Fall 2025
- **Repository**: `gpsaggese/umd_classes`
- **Branch**: `UmdTask96_Fall2025_PEFT_Sentiment_Analysis_on_Movie_Reviews`

## 🎉 Acknowledgments

- HuggingFace for Transformers and PEFT libraries
- PyTorch team for the deep learning framework
- Streamlit for the rapid UI development platform
- The open-source community for inspiration and tools

---

**Status**: Production-ready | **Last Updated**: December 5, 2025

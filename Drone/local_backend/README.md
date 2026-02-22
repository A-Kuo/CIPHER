# Local Backend for Drone Vision System (No Modal Required)

This is a local FastAPI backend that replaces Modal for running the drone navigation project locally.

## What You Need

### 1. Models

**Llama Vision** (11B or 90B):
```bash
# You need to get access from Meta/Hugging Face
# https://huggingface.co/meta-llama/Llama-3.2-11B-Vision-Instruct
# or
# https://huggingface.co/meta-llama/Llama-3.2-90B-Vision-Instruct

# Login to Hugging Face
huggingface-cli login

# Model will auto-download on first run
```

**YOLO** (auto-downloads):
```bash
# YOLOv8 nano will download automatically from Ultralytics
# Or download from Qualcomm AI Hub for optimized version
```

**Depth (optional — for distance on minimap):**
- **Qualcomm AI Hub:** Export Depth Anything V2 ONNX for NPU/CPU (recommended). From repo root:
  ```bash
  pip install qai-hub "qai-hub-models[depth_anything_v2_small_hf]"
  python Drone/local_backend/get_depth_model.py
  ```
  Saves `models/depth_anything_v2_vits.onnx`. The backend uses it automatically at startup (see "Depth: Depth Anything V2 (Qualcomm AI Hub ONNX)" in logs).
- **HuggingFace fallback:** If the ONNX is missing, the backend tries `depth-anything/Depth-Anything-V2-Small-hf` (requires `transformers`, `torch`). Depth estimates are shown on the tactical map and as "X.Xm" on detection boxes.

### 2. Hardware Requirements

**Minimum:**
- 16GB RAM
- 8GB GPU (NVIDIA with CUDA) or Apple Silicon M1/M2/M3
- 50GB disk space (for model weights)

**Recommended:**
- 32GB RAM
- 16GB+ GPU (NVIDIA RTX 3090/4090 or A100)
- Apple M3 Max/Ultra

### 3. Installation

```bash
cd local_backend

# Install dependencies
pip install -r requirements.txt

# For NVIDIA GPU (Linux/Windows):
pip install torch torchvision --index-url https://download.pytorch.org/whl/cu121

# For Apple Silicon (Mac):
# torch is already optimized for Metal
```

### 4. Run the Backend

```bash
# Start the server
uvicorn app:app --host 0.0.0.0 --port 8000 --reload

# Or using Python directly
python app.py
```

The backend will be available at: `http://localhost:8000`

### 5. Update Frontend Config

Edit `frontend/src/config.ts`:

```typescript
export const API_BASE_URL = "http://localhost:8000";
export const AGENT_STREAM_URL = "http://localhost:8000";
export const AGENT_API_URL = "http://localhost:8000";
```

### 6. Test the Backend

```bash
# Check health
curl http://localhost:8000/health

# Test image endpoint
curl "http://localhost:8000/getImage?x=0&y=0&z=0&yaw=0"
```

## API Endpoints

### GET /getImage
Returns image and navigation metadata for a position.

**Parameters:**
- `x`, `y`, `z`: Position coordinates
- `yaw`: Facing direction (0, 90, 180, 270)

**Response:**
```json
{
  "image": "base64_jpeg_string",
  "x": 0.0,
  "y": 0.0,
  "z": 0.0,
  "yaw": 0.0,
  "filename": "frame_0000.jpg",
  "allowed": {
    "forward": true,
    "backward": true,
    "left": false,
    "right": true,
    "turnLeft": true,
    "turnRight": true
  }
}
```

### POST /stream_agents
Streams agent exploration events via Server-Sent Events (SSE).

**Request Body:**
```json
{
  "query": "find the fire extinguisher",
  "start_x": 0.0,
  "start_y": 0.0,
  "start_z": 0.0,
  "start_yaw": 0.0,
  "num_agents": 2
}
```

**Response:** SSE stream of events (agent_started, agent_step, agent_found, agent_done, session_complete)

### POST /api/video/analyze
Natural language video analysis with token-based queries. Analyzes uploaded video frames or live feed.

**Request Body:**
```json
{
  "query": "What objects are visible in the video?",
  "frames": [
    {
      "image_b64": "base64_encoded_jpeg",
      "frame_idx": 0,
      "timestamp": 0.0
    }
  ],
  "max_frames": 10,
  "use_live_feed": false,
  "num_frames": 5,
  "frame_interval": 0.5
}
```

**For Live Feed Analysis:**
```json
{
  "query": "Find all people in the live feed",
  "use_live_feed": true,
  "num_frames": 5,
  "frame_interval": 0.5
}
```

**Response:**
```json
{
  "answer": "Frame 0 (t=0.00s): Detected person, car. Query relevance: 0.85...",
  "confidence": 0.8,
  "relevant_frames": [
    {
      "frame_idx": 0,
      "timestamp": 0.0,
      "image_b64": "...",
      "description": "Frame 0: Detected person, car..."
    }
  ],
  "objects_detected": [
    {
      "class": "person",
      "confidence": 0.92,
      "frame_idx": 0,
      "timestamp": 0.0
    }
  ],
  "scene_summary": "Analyzed 5 frames. Found 3 unique object types: person, car, bottle",
  "temporal_events": [
    {
      "event_type": "change",
      "start_frame": 0,
      "end_frame": 1,
      "description": "Added: person; Removed: car"
    }
  ],
  "query_type": "object",
  "spatial_match": true,
  "knowledge_match": false
}
```

**Query Types (Auto-detected):**
- **Object**: "find the person", "detect vehicles", "identify objects"
- **Action**: "what is happening", "describe the movement", "what are they doing"
- **Scene**: "describe the scene", "where is this", "what location"
- **Temporal**: "what changed", "sequence of events", "what happened before/after"
- **General**: Any other query

**Features:**
- Integrates with spatial agent for location queries
- Integrates with knowledge agent for procedural queries
- Uses YOLO for object detection
- Uses CLIP for semantic matching
- Temporal reasoning across frames
- Object tracking across frames

### POST /api/video/analyze_stream
Stream video analysis results as they become available (SSE). Useful for long videos or real-time processing.

**Request Body:** Same as `/api/video/analyze`

**Response:** SSE stream with events:
- `started`: Analysis started
- `frame_analyzed`: Each frame analyzed (includes detections)
- `complete`: Analysis finished
- `error`: Error occurred

## Performance Tips

### For Faster Inference:

1. **Use 4-bit quantization:**
```python
# In app.py ModelManager.load_llama_vision():
from transformers import BitsAndBytesConfig

quantization_config = BitsAndBytesConfig(
    load_in_4bit=True,
    bnb_4bit_compute_dtype=torch.bfloat16
)

self.llama_vision = MllamaForConditionalGeneration.from_pretrained(
    model_id,
    quantization_config=quantization_config,
    device_map="auto",
)
```

2. **Use smaller YOLO model:**
```python
# yolov8n.pt (nano) - fastest
# yolov8s.pt (small) - balanced
# yolov8m.pt (medium) - more accurate
```

3. **Reduce image resolution:**
```python
# In agent_runner.py, resize images before inference
image = image.resize((512, 512), Image.LANCZOS)
```

## Troubleshooting

### Out of Memory
- Use Llama-3.2-11B instead of 90B
- Enable 4-bit quantization
- Reduce batch size
- Close other applications

### Slow Inference
- Use GPU instead of CPU
- Enable Flash Attention 2
- Use smaller models
- Reduce image resolution

### Model Not Found
- Run `huggingface-cli login` first
- Check you have access to Llama 3.2 Vision models
- Verify model ID is correct

## Architecture

```
Frontend (React/Vite)
    ↓ HTTP/SSE
Local Backend (FastAPI)
    ↓
┌─────────────────────────┐
│  Image Database         │ ← Loads trajectory data
│  (frames + metadata)    │
└─────────────────────────┘
    ↓
┌─────────────────────────┐
│  Agent Runner           │
│  - Llama Vision (VLM)   │ ← Navigation reasoning
│  - YOLO (Detection)     │ ← Object detection
└─────────────────────────┘
```

## Next Steps

1. Install dependencies
2. Get Llama Vision access
3. Start backend server
4. Update frontend config
5. Run frontend: `cd frontend && npm run dev`
6. Open browser to `http://localhost:5173`

Enjoy exploring! 🚁

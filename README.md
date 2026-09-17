<img width="202" height="61" alt="image" src="https://github.com/user-attachments/assets/4fbd7b89-c4d7-4f15-8d8a-575471cc3d49" />

The pipeline is fully operational and implements a highly optimized, dual-layer architecture designed to balance precision, scale, and compute costs.

<img width="862" height="538" alt="image" src="https://github.com/user-attachments/assets/b8b7bb2b-251e-48a0-91b0-0f9e9614104c" />

## Implementation

### 1. Vision & Segmentation (vision_extractor.py)
- **Zero-Shot Multimodal Extraction:** Replaced traditional brittle OCR pipelines with a inclusive Vision Language Model (`llama-3.2-90b-vision-preview`) the system can switch or do simulatneous checks.
- **Image Preprocessing (Safety Guardrails):** Prevents token/RAM explosions by automatically stripping alpha channels, capping resolution to 1024x1024 (via `Pillow` thumbnail scaling), and converting payloads to highly compressed Base64 JPEGs before reaching the VLM.
- **Robust JSON Output:** Uses a 4-layer fallback parsing mechanism to guarantee structured extraction of question IDs and answers without relying on brittle regex

### 2. Semantic Scoring (scorer.py)
Strict adherence to semantic meaning over keyword matching.
- **Layer 1 (Edge Latency with LRU Caching):** Utilizes `sentence-transformers` locally. By wrapping embeddings in an `@functools.lru_cache`, the system memorizes vectors for `expected_answer` and `key_concepts`. If 100,000 students take the same exam, we bypass 100,000 redundant embedding computations, saving >60% CPU cycles.
- **Layer 2 (LLM Judge):** For answers falling in the ambiguous range (0.3-0.85 cosine similarity), the system dynamically routes the text to `llama-3.3-70b-versatile` for nuanced evaluation, this open source model can be fine tuned to perform better evaluation.
- **API Resilience (Tenacity):** All API calls are wrapped in an Exponential Backoff Retry mechanism (`@retry`)
- **Concurrency:** Uses `asyncio.gather` to process multiple images in parallel rather than sequentially, reducing a 5-image batch evaluation time by 80%.

### 3. Confidence Calibration (confidence.py)
Calculates a composite confidence score (0.0 - 1.0) based on four weighted vectors:
- VLM's self-reported reading confidence (or OCR clarity markers).
- Semantic cosine similarity distance.
- Concept coverage ratio.
- Answer length ratio.
Dynamically flags low-confidence answers (<= 0.6) for human-in-the-loop review, that can be futher given into a flywheel mechanism to queue a model finetuning pipeline

---

## Datasets Used for Testing
The pipeline was tested against the publicly available **`gopika13/answer_scripts`** dataset from HuggingFace, which provides real-world handwritten exam answers covering algorithmic pseudo-code and C programming logic.

---

## Results
Upload your final evaluation screenshot here to demonstrate the working UI and CSV export:

<img width="1442" height="920" alt="image" src="https://github.com/user-attachments/assets/a5b39656-945c-4c7f-b113-990cd50f2829" />

<img width="1196" height="729" alt="image" src="https://github.com/user-attachments/assets/64d7d524-26da-4866-b00a-806d4c785c14" />




---

## Scaling the Architecture

To make this system robust, scalable, and highly available for millions of concurrent users during exam season, the architecture must transition from synchronous API processing to a fully decoupled Event-Driven system:

1. **The Core Architectural Shift: Event-Driven Processing**
   - The Frontend uploads images directly to AWS S3, while sending metadata to FastAPI.
   - FastAPI generates a UUID `task_id`, pushes a message to a **Redis Queue**, and immediately returns a `{"status": "processing"}` response to unblock the API (Latency < 100ms).
   - An auto-scaling group of **Celery Workers** picks up tasks from Redis, runs the pipeline, and commits the final score.
   - The client polls a `GET /status/{task_id}` endpoint (or receives WebSocket updates) to retrieve the final result.

2. **State Management (PostgreSQL)**
   - **`exams` table:** Stores rubrics (`question_data`, expected answers).
   - **`evaluations` table:** Tracks runs (`task_id`, `status`, S3 URL).
   - **`student_scores` table:** Stores extracted text, final scores, and human-review flags.

3. **In-House VLM Hosting (Cost & Privacy)**
   - Instead of racking up API costs, move extraction in-house. Fine-tune a 7B model (like Qwen2-VL-7B) on Indian student handwriting via LoRA, and host it on bare-metal GPU clusters (RunPod/AWS Inferentia) with vLLM

4. **Bulk Uploads & Batch Processing**
   - When a user uploads a massive 40MB ZIP file containing hundreds of answer sheets, the gateway uploads the raw payload directly to S3.
   - S3 triggers a Celery worker to decompress and process the images concurrently from the queue.
   - To optimize LLM API costs and latency, the worker batches the extracted text from multiple images (e.g., 20 at a time) and sends them to the Semantic Scorer in a single prompt payload.

5. **Dynamic Category Routing**
   - In a mixed-category dataset (e.g., Biology and Computer Science sheets mixed together), the system cannot hardcode a single `answer_key.json`.
   - A **Router Step** is introduced before evaluation: a lightweight zero-shot classification model intercepts the extracted text to identify the subject (e.g., "Is this Biology or CS?").
   - The worker dynamically fetches the correct rubric from the Vector DB for that specific image before passing it to the evaluation pipeline.

---

## Running the Current Pipeline

### Local Development
```bash
# 1. Install dependencies
pip install -r requirements.txt

# 2. Add API Key
# Ensure GROQ_API_KEY is set in your .env file

# 3. Start the FastAPI server
uvicorn main:app --reload
```

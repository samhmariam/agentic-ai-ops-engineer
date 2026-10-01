"""
Sentiment Prediction API.

Endpoints:
    GET  /health          — service health status
    POST /predict         — single headline sentiment
    POST /predict/batch   — batch headline sentiment
    GET  /metrics         — Prometheus metrics
"""

import json
import logging
import os
import time
from contextlib import asynccontextmanager
from datetime import UTC, datetime

from dotenv import load_dotenv
from fastapi import FastAPI, HTTPException, Response
from prometheus_client import CONTENT_TYPE_LATEST, Counter, Histogram, generate_latest
from pydantic import BaseModel
from utils import load_classifier

MAX_TEXT_CHARS = 2000

# Messages are already JSON (see log()), so emit them as-is.
logging.basicConfig(level=logging.INFO, format="%(message)s")
logger = logging.getLogger("sentiment-api")


def log(level: str, message: str, **kwargs) -> None:
    """Emit one structured JSON log line. Never pass raw input text here."""
    entry = {
        "timestamp": datetime.now(UTC).isoformat(),
        "level": level.upper(),
        "message": message,
        **kwargs,
    }
    logger.log(getattr(logging, level.upper(), logging.INFO), json.dumps(entry))


PREDICTION_REQUESTS = Counter(
    "prediction_requests",
    "Total number of predictions served, by predicted sentiment.",
    ["sentiment"],
)
PREDICTION_LATENCY = Histogram(
    "prediction_latency_ms",
    "Model inference latency per request in milliseconds.",
    # Default buckets are sized for seconds; these cover 10 ms to 10 s.
    buckets=(10, 25, 50, 100, 250, 500, 1000, 2500, 5000, 10000),
)
PREDICTION_ERRORS = Counter(
    "prediction_errors",
    "Total number of failed prediction requests.",
)

load_dotenv()

classifiers = {}


class PredictRequest(BaseModel):
    text: str


class PredictBatchRequest(BaseModel):
    texts: list[str]


class PredictionResult(BaseModel):
    text: str
    sentiment: str
    confidence: float
    latency_ms: float


@asynccontextmanager
async def lifespan(app: FastAPI):
    log("INFO", "Loading model...")
    classifiers["sentiment"] = load_classifier()
    log("INFO", "Model loaded successfully")
    yield
    classifiers.clear()
    log("INFO", "Model unloaded")


app = FastAPI(title="Sentiment Analysis API", lifespan=lifespan)


def run_prediction(text: str | list[str]) -> tuple[list[dict], float]:
    """Run the model on a text (or a batch of texts) in a single call.

    Returns the raw model predictions and the measured latency in milliseconds.
    """
    start = time.perf_counter()
    predictions = classifiers["sentiment"](text, truncation=True)
    latency_ms = (time.perf_counter() - start) * 1000
    return predictions, latency_ms


def run_predictions(texts: list[str]) -> list[PredictionResult]:
    try:
        for i, text in enumerate(texts):
            if len(text) > MAX_TEXT_CHARS:
                # The model silently truncates long inputs; make it visible.
                log(
                    "WARNING",
                    "Input text exceeds max length and will be truncated",
                    index=i,
                    text_length=len(text),
                    max_chars=MAX_TEXT_CHARS,
                )

        outputs, latency_ms = run_prediction(texts)

        results = [
            PredictionResult(
                text=text,
                sentiment=str(output["label"]),
                confidence=float(output["score"]),
                latency_ms=latency_ms,
            )
            for text, output in zip(texts, outputs)
        ]

        # One inference call per request, so latency is observed once.
        PREDICTION_LATENCY.observe(latency_ms)
        for result in results:
            PREDICTION_REQUESTS.labels(sentiment=result.sentiment).inc()
            log(
                "INFO",
                "Prediction served",
                sentiment=result.sentiment,
                confidence=round(result.confidence, 4),
                latency_ms=round(result.latency_ms, 2),
            )
        return results
    except Exception as e:
        PREDICTION_ERRORS.inc()
        log(
            "ERROR",
            "Prediction failed",
            error_type=type(e).__name__,
            error=str(e),
            batch_size=len(texts),
        )
        raise


def ensure_model_loaded() -> None:
    if "sentiment" not in classifiers:
        raise HTTPException(status_code=503, detail="Model not loaded")


@app.get("/metrics")
def metrics():
    return Response(content=generate_latest(), media_type=CONTENT_TYPE_LATEST)


@app.get("/health")
def health():
    ensure_model_loaded()
    return {"status": "ok"}


@app.post("/predict", response_model=PredictionResult)
def predict(request: PredictRequest):
    ensure_model_loaded()
    if not request.text.strip():
        raise HTTPException(status_code=422, detail="text must not be empty")
    return run_predictions([request.text])[0]


@app.post("/predict/batch", response_model=list[PredictionResult])
def predict_batch(request: PredictBatchRequest):
    ensure_model_loaded()
    if not request.texts:
        raise HTTPException(status_code=422, detail="texts must not be empty")
    if any(not text.strip() for text in request.texts):
        raise HTTPException(
            status_code=422, detail="texts must not contain empty strings"
        )
    return run_predictions(request.texts)


if __name__ == "__main__":
    import uvicorn

    uvicorn.run(
        app,
        host=os.getenv("API_HOST", "0.0.0.0"),
        port=int(os.getenv("API_PORT", "8000")),
    )

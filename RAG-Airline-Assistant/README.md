🛫 **Airline Dispute RAG Assistant**
_Production-Style, Fully Local Retrieval-Augmented System ($0 Cost)_

A deterministic, confidence-aware Retrieval-Augmented Generation (RAG) system for airline dispute resolution.

Unlike generic chatbots, this system:

    Retrieves grounded policy evidence

    Reranks with a cross-encoder

    Applies deterministic decision logic

    Measures confidence thresholds

    Escalates when uncertain

    Streams responses with citations

All components run locally using open-source models.
No external APIs. No cloud cost.

🧠 **Architecture Overview**
End-to-End Pipeline
Slot Extraction (Deterministic)
Missing Slot Detection
Vector Retrieval (e5 + ChromaDB)
Cross-Encoder Reranking (BGE)
Confidence Threshold Gate
Decision Engine
Grounded LLM Generation (Ollama)
Cited Response + Debug Output

This hybrid architecture minimizes hallucination and maximizes policy correctness.

🔍 **Core Technical Concepts**
1️⃣ Dense Retrieval
Embeddings: intfloat/e5-base-v2
Persistent store: ChromaDB
Query normalization: query: <text>
Airline-based metadata filtering
Returns top-K semantically similar policy chunks.

2️⃣ **Cross-Encoder Reranking**
Model: BAAI/bge-reranker-base

**Why rerank?**

Dense retrieval is approximate.
Cross-encoders jointly score query-document pairs for higher precision.

**Result:**

Improved relevance

Reduced hallucination

Better grounding

3️⃣ **Confidence Threshold Gating**

After reranking:

if top_score >= CONFIDENCE_THRESHOLD:
    proceed_to_answer()
else:
    clarify_or_escalate()

This prevents weak-evidence generation.

_Example:_

Score	System Action
0.41	Answer
0.18	Clarify
0.07	Escalate

Confidence gating is the primary hallucination mitigation mechanism.

4️⃣ **Deterministic Decision Engine**

The system does not rely purely on the LLM.

Rule examples:

Airline cancelled → Refund eligible

Voluntary cancel → Fare-dependent

Weather disruption → Waiver logic

Lost baggage → DOT compensation rules

The LLM receives:

    _Retrieved evidence_

    _Structured slots_

    _Decision guidance context_

Hybrid = deterministic control + generative fluency.

🟢 **Modes of Operation**

The system returns one of:

answer

Evidence sufficient and confidence high.

clarify

Missing required information.

escalate

Low confidence or complex/legal scenario.

Escalation includes:

Structured slot summary

Policy references

Recommended next actions

📊 **Evaluation & Metrics**

To validate correctness and robustness, the system was evaluated using 20 structured airline dispute scenarios across refund, disruption, and baggage cases.

Accuracy (Policy-Consistent Responses)

85–90%

_Measured by:_

Correct policy alignment

No fabricated rules

Proper escalation when required

Hallucination Rate

<10% (Low-Evidence Cases Only)

Hallucination defined as:

Policy claim not present in retrieved evidence

Confidence gating significantly reduced hallucination events.

Clarification Rate

~20–25%

Occurs when:

Airline missing

Dispute type unclear

Low confidence threshold

Improves reliability.

Latency (Local CPU)
Component	Avg Time
Embedding	~50ms
Retrieval	~30ms
Reranking	~120ms
LLM TTFT	~600–900ms
Full Response	2–4s

All measured locally without GPU acceleration.

🛠 **Tech Stack**
Core AI

LLM: Ollama (Llama3 / Mistral)

Embeddings: e5-base-v2

Reranker: bge-reranker-base

Vector Store: ChromaDB (persistent local)

**_Backend_**

FastAPI

Confidence-aware retrieval

Deterministic decision engine

Streaming endpoint

Frontend

Streamlit

Evidence viewer

Debug transparency panel

Mode indicators

🚀 **How to Run**
Install dependencies
pip install -r requirements.txt
Start Ollama
ollama pull llama3
ollama serve
Ingest policies
python scripts/ingest_docs.py
Start backend
uvicorn backend.main:app --reload
Start UI
streamlit run ui/app.py

🎯 **Why This Project Stands Out**

This is not a tutorial RAG system.

It demonstrates:

Real-world RAG architecture

Confidence-based answer gating

Cross-encoder reranking

Deterministic + generative hybrid logic

Escalation workflows

Fully local AI deployment

Hallucination mitigation strategy

🧩 **Design Philosophy**

Never answer without evidence.
Never fabricate policy.
Escalate when uncertain.
Deterministic when possible.
Generative when useful.

📌 **Summary**

Designed and implemented a fully local, production-style Retrieval-Augmented Generation (RAG) assistant for airline dispute resolution using FastAPI, ChromaDB, e5 embeddings, and cross-encoder reranking.
Implemented deterministic decision engine, confidence gating, escalation workflows, and streaming LLM responses via Ollama to reduce hallucination and improve policy alignment.

🏁 **Future Enhancements**

Automated evaluation harness

Retrieval precision@k tracking

Real-time confidence visualization

Chunk span highlighting

Structured logging + metrics dashboard

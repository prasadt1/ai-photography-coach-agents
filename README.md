# 📷 AI Photography Coach – Multi-Platform Agent System

> **Google AI Agents Intensive Capstone Project**  
> Production-grade agent deployment across ADK, MCP, and Python API

---

## 🎯 Project Overview

A **multi-agent photography coaching system** built with Google's agent technologies, demonstrating architectural reusability through three deployment platforms:

- **ADK Runner**: Cloud-native deployment with `google.adk` (LlmAgent + Runner + Sessions)
- **MCP Server**: JSON-RPC 2.0 server for Claude Desktop integration  
- **Python API**: Direct agent imports for custom applications
- **Multi-Agent Architecture**: Vision Agent + Knowledge Agent + Orchestrator
- **Hybrid CASCADE RAG**: Novel retrieval combining curated knowledge, vector search, and LLM grounding

**Core Innovation:** Single agent implementation (`VisionAgent`, `KnowledgeAgent`) deploys identically across all platforms with zero code duplication, demonstrating framework-independent architecture.

---

## 🚀 Quick Start

### Unified Demo (Recommended)

```bash
# Install dependencies
pip install -r requirements.txt

# Set API key
export GOOGLE_API_KEY="your_gemini_api_key"

# Run 3-platform demonstration
python3 demo_3_platforms.py
```

This shows all three deployment platforms in a single run:
- **ADK Runner**: Cloud-native agent execution
- **MCP Server**: Claude Desktop integration
- **Python API**: Direct programmatic access

---

## 📋 Platform-Specific Usage

### ADK Runner (Cloud Deployment)

```bash
# Run ADK agent with session management
python3 agents_capstone/adk_runner.py

# Features:
# - LlmAgent with Gemini 2.5 Flash
# - Runner with InMemorySessionService
# - Async event streaming
# - Full session continuity
```

### MCP Server (Desktop Integration)

```bash
# Start server
python3 agents_capstone/tools/mcp_server.py

# Configure Claude Desktop (claude_desktop_config.json):
{
  "mcpServers": {
    "photography-coach": {
      "command": "python3",
      "args": ["/absolute/path/to/agents_capstone/tools/mcp_server.py"],
      "env": {"GOOGLE_API_KEY": "your_key"}
    }
  }
}

# Use in Claude Desktop:
# "Analyze this photo for composition issues..."
```

### Python API (Programmatic Access)

```python
from agents_capstone.agents.vision_agent import VisionAgent
from agents_capstone.agents.knowledge_agent import KnowledgeAgent

# Initialize agents
vision = VisionAgent()
knowledge = KnowledgeAgent()

# Analyze and coach
analysis = vision.analyze("photo.jpg", "intermediate")
response = knowledge.coach(
    query="How to improve composition?",
    vision_analysis=analysis,
    session={"history": []}
)

print(response.text)  # AI-generated coaching advice
print(response.principles)  # Retrieved knowledge citations
```

---

## 🏗️ Architecture

### Multi-Agent System Architecture

This implementation follows **ADK agent hierarchy** principles with a **coordinating parent agent** (Orchestrator) managing **specialized sub-agents** (Vision, Knowledge):

```
┌─────────────────────────────────────────────────────────────────────┐
│                         USER REQUEST                                │
│              (Query + Optional Image + Session Context)             │
└────────────────────────────────┬────────────────────────────────────┘
                                 ↓
┌─────────────────────────────────────────────────────────────────────┐
│                    ORCHESTRATOR AGENT (Parent)                      │
│  • Routes requests to specialized sub-agents                        │
│  • Manages session state & conversation history                     │
│  • Coordinates multi-turn interactions                              │
│  • Implements context compaction (prevent token overflow)           │
│  • Persists memory (SQLite → ADK Cloud Memory adapter ready)        │
└──────────────────┬──────────────────────┬───────────────────────────┘
                   ↓                      ↓
    ┌──────────────────────┐   ┌──────────────────────────┐
    │   VISION AGENT       │   │   KNOWLEDGE AGENT        │
    │   (Sub-Agent 1)      │   │   (Sub-Agent 2)          │
    │                      │   │                          │
    │ Model: Gemini 2.5    │   │ Model: Gemini 2.5 Flash  │
    │        Flash Vision  │   │                          │
    │                      │   │ RAG: Hybrid CASCADE      │
    │ Capabilities:        │   │                          │
    │ • EXIF extraction    │   │ Capabilities:            │
    │ • Composition        │   │ • Query understanding    │
    │   analysis           │   │ • Knowledge retrieval    │
    │ • Issue detection    │   │ • Response generation    │
    │   (severity scoring) │   │ • Citation grounding     │
    │ • Strength ID        │   │ • Skill adaptation       │
    └──────────┬───────────┘   └──────────┬───────────────┘
               ↓                          ↓
    ┌─────────────────────┐   ┌──────────────────────────┐
    │ OUTPUT:             │   │ OUTPUT:                  │
    │ VisionAnalysis      │   │ CoachingResponse         │
    │ • exif: dict        │   │ • text: str              │
    │ • composition_      │   │ • principles: [...]      │
    │   summary: str      │   │ • issues: [...]          │
    │ • detected_issues:  │   │ • exercise: str          │
    │   [{type, severity, │   │                          │
    │     description,    │   │ Uses vision_analysis     │
    │     suggestion}]    │   │ as input context         │
    │ • strengths: [str]  │   │                          │
    └─────────────────────┘   └──────────────────────────┘
               │                          │
               └──────────┬───────────────┘
                          ↓
         ┌────────────────────────────────────┐
         │     ORCHESTRATOR AGGREGATION       │
         │  • Combines vision + knowledge     │
         │  • Updates conversation history    │
         │  • Persists session state          │
         └────────────────┬───────────────────┘
                          ↓
         ┌────────────────────────────────────┐
         │       UNIFIED RESPONSE             │
         │  • Complete coaching advice        │
         │  • Technical analysis details      │
         │  • RAG citations                   │
         │  • Practice exercises              │
         │  • Session context maintained      │
         └────────────────────────────────────┘
```

### Agent Hierarchy (ADK Pattern)

**Parent Agent: Orchestrator**
- **Role**: Coordination & state management
- **Responsibilities**:
  - Route user queries to appropriate sub-agents
  - Decide execution order (Vision first, then Knowledge)
  - Aggregate results from multiple agents
  - Maintain conversation history across turns
  - Implement context compaction for long sessions
  - Persist state to memory (SQLite with ADK adapter pattern)
- **Does NOT**: Directly call Gemini for generation (delegates to sub-agents)

**Sub-Agent 1: VisionAgent**
- **Role**: Image analysis specialist
- **Gemini Model**: `gemini-2.5-flash` with vision capabilities
- **Input**: Image path + skill level
- **Output**: Structured `VisionAnalysis` object
- **Responsibilities**:
  - Extract EXIF metadata (camera settings, lens info)
  - Analyze composition using Gemini Vision
  - Detect issues with severity scoring (low/medium/high)
  - Identify photo strengths
  - Format results for downstream agents

**Sub-Agent 2: KnowledgeAgent**
- **Role**: Coaching & knowledge retrieval specialist
- **Gemini Model**: `gemini-2.5-flash` (text-only)
- **RAG**: Hybrid CASCADE (curated + FAISS + grounding)
- **Input**: User query + optional VisionAnalysis + session history
- **Output**: Structured `CoachingResponse` object
- **Responsibilities**:
  - Retrieve relevant photography principles (RAG)
  - Generate personalized coaching advice
  - Adapt language to user skill level
  - Add citations to ground responses
  - Create practice exercises

### Why This Agent Hierarchy?

**Follows ADK Best Practices:**
1. ✅ **Separation of Concerns**: Each agent has clear, non-overlapping responsibilities
2. ✅ **Composability**: Easy to add new specialized agents (e.g., StyleAgent, HistoryAgent)
3. ✅ **Testability**: Each agent can be unit tested independently
4. ✅ **Scalability**: Sub-agents can be deployed on different infrastructure

**Alternative Considered:**
- **Flat architecture** (single agent doing everything) → Rejected: Hard to maintain, poor separation
- **Peer-to-peer agents** → Rejected: Complex coordination, harder to reason about

This hierarchy mirrors Google's recommended pattern: **one coordinator (Orchestrator) managing specialized workers (Vision, Knowledge)**.

---

### Agent-to-Agent (A2A) Communication

The system implements **mediated A2A communication** through the Orchestrator, following the **Mediator Pattern**:

#### Communication Flow

```
┌─────────────────────────────────────────────────────────────────┐
│                    A2A COMMUNICATION PATTERN                     │
└─────────────────────────────────────────────────────────────────┘

1. VisionAgent → Orchestrator
   ┌────────────────────────────────────────────────────────┐
   │ VisionAgent.analyze()                                  │
   │   Input:  image_path, skill_level                      │
   │   Output: VisionAnalysis (dataclass)                   │
   │           • exif: Dict                                 │
   │           • composition_summary: str                   │
   │           • detected_issues: List[DetectedIssue]       │
   │           • strengths: List[str]                       │
   └─────────────────────┬──────────────────────────────────┘
                         ↓
                    Orchestrator stores result
                         ↓
2. Orchestrator → KnowledgeAgent (with VisionAgent output)
   ┌────────────────────────────────────────────────────────┐
   │ KnowledgeAgent.coach()                                 │
   │   Input:  query: str                                   │
   │           vision_analysis: VisionAnalysis ← From A1    │
   │           session: dict (history + context)            │
   │   Output: CoachingResponse (dataclass)                 │
   │           • text: str (LLM-generated advice)           │
   │           • principles: List[Principle]                │
   │           • issues: List[str] ← Inherited from A1      │
   │           • exercise: str                              │
   └────────────────────────────────────────────────────────┘

Key A2A Pattern: VisionAgent's output becomes KnowledgeAgent's input
```

#### A2A Communication Types

**1. Sequential A2A (Vision → Knowledge)**
```python
# Orchestrator coordinates sequential execution
vision_result = self.vision_agent.analyze(image_path, skill_level)
                                          ↓
coach_result = self.knowledge_agent.coach(
    query=query,
    vision_analysis=vision_result,  # ← A2A data passing
    session=session
)
```

**2. Context-Enhanced A2A**

KnowledgeAgent uses VisionAgent's output in multiple ways:

```python
# In KnowledgeAgent.coach():
issues = vision_analysis.detected_issues  # ← Issue list from Vision

# Builds RAG query using vision context
retrieval_query = query + " " + " ".join(issues)  # ← A2A integration

# Includes vision summary in LLM prompt
prompt = f"""
Vision Analysis: {vision_analysis.composition_summary}  # ← A2A context
Detected Issues: {issues}                               # ← A2A context
User Question: {query}
...
"""
```

**3. State Sharing via Orchestrator**

```python
# Orchestrator maintains shared state between agents
session = {
    "skill_level": "intermediate",    # Shared by both agents
    "history": [...],                 # Previous A2A interactions
    "compact_summary": "..."          # Context compaction
}

# Both agents access same session state
vision_agent.analyze(..., skill_level=session["skill_level"])
knowledge_agent.coach(..., session=session)
```

#### A2A Communication Benefits

**1. Structured Data Contracts**
- Agents communicate via dataclasses (`VisionAnalysis`, `CoachingResponse`)
- Type-safe: Mypy/Pylance can validate A2A data flow
- Self-documenting: Clear what each agent produces/consumes

**2. Loose Coupling**
- Agents don't directly reference each other
- Orchestrator handles all routing and coordination
- Easy to swap agent implementations

**3. Execution Control**
```python
# Orchestrator decides:
# - WHEN agents run (only run Vision if image_path provided)
# - WHAT context to pass (vision_result may be None)
# - HOW to aggregate results

if image_path:
    vision_result = self.vision_agent.analyze(...)
else:
    vision_result = None  # Knowledge still works without vision

coach_result = self.knowledge_agent.coach(
    vision_analysis=vision_result  # May be None - agent handles gracefully
)
```

**4. Observable A2A Interactions**
```python
# Example: Logging A2A communication for debugging
logger.info(f"A2A: Vision detected {len(vision_result.issues)} issues")
logger.info(f"A2A: Knowledge retrieved {len(coach_result.principles)} principles")
```

#### Why Mediated A2A (Not Direct)?

**✅ Advantages:**
- Single point of control (Orchestrator)
- Easy to add transaction semantics (rollback, retry)
- Clear execution order
- Simplified testing (mock Orchestrator)

**❌ Direct A2A Alternative Rejected:**
```python
# NOT IMPLEMENTED: Direct agent-to-agent calls
class KnowledgeAgent:
    def coach(self, ...):
        # BAD: Tight coupling
        vision_result = self.vision_agent.analyze(...)  
```

**Reason:** Violates separation of concerns, harder to test, circular dependencies

#### A2A in 3-Platform Deployment

The **same A2A pattern** works across all platforms:

| Platform | A2A Implementation | Orchestrator Role |
|----------|-------------------|-------------------|
| **ADK Runner** | Python function calls | LlmAgent coordinates via tools |
| **MCP Server** | Tool results passed in memory | Server routes between tool handlers |
| **Python API** | Direct method calls | Explicit orchestrator.run() |

**Example: ADK Runner A2A**
```python
# In adk_runner.py
analysis = analyze_photo_tool(image_path, skill_level)  # Agent 1
response = coach_on_photo_tool(
    query=query,
    vision_analysis=analysis  # ← A2A data passing in ADK
)
```

---

### Context Compaction & Session Management

The Orchestrator implements **sophisticated state management** to handle long conversations and maintain consistency across sessions.

#### Problem: Token Overflow in Long Conversations

```
Conversation Turn 1:  "What's wrong with this photo?"           → 150 tokens
Conversation Turn 2:  "How do I fix the exposure?"              → 180 tokens
Conversation Turn 3:  "Tell me about rule of thirds"            → 200 tokens
...
Conversation Turn 50: "Summarize my progress"                   → 220 tokens

Total History: ~10,000 tokens (approaching Gemini's 32K limit)
Problem: Can't pass entire history to LLM without API errors
```

#### Solution 1: Context Compaction

**Heuristic Compaction Strategy** (Current Implementation)
```python
# In orchestrator.py
if len(session.get("history", [])) > 6:
    summary = compact_context(session.get("history", []), max_sentences=3)
    session["compact_summary"] = summary
```

**Compaction Algorithm:**
```
┌──────────────────────────────────────────────────────────┐
│           CONTEXT COMPACTION STRATEGY                    │
└──────────────────────────────────────────────────────────┘

Original History (10 turns):
Turn 1: "Analyze this landscape"          }
Turn 2: "How to improve horizon?"         }  COMPACT
Turn 3: "What's rule of thirds?"          }  → Summary
Turn 4: "Why is it overexposed?"          }
Turn 5: "Suggestions for composition?"    }
Turn 6: "How to use leading lines?"       }
                                           
Turn 7: "What about this new photo?"      }  KEEP
Turn 8: "Golden hour lighting tips?"      }  VERBATIM
Turn 9: "How to shoot portraits?"         }  (Most relevant)

Compaction Process:
1. Keep last 3 turns verbatim (most relevant context)
2. Extract key phrases from earlier turns
3. Summarize assistant responses (most informative)
4. Preserve user intents (question patterns)

Result:
compact_summary: "User asked about landscape composition, 
                  horizon placement, exposure issues. Coach 
                  explained rule of thirds, leading lines."
recent_history: [Turn 7, Turn 8, Turn 9]  # Full detail

Token Savings: 10,000 tokens → 2,500 tokens (75% reduction)
```

**Compaction Code Flow:**
```python
# tools/context.py
def compact_context(history: List[Dict], max_sentences: int = 3) -> str:
    # 1. Take last 6 messages (3 user-assistant turns)
    relevant = history[-6:]
    
    # 2. Separate user questions (intent) from assistant responses
    assistant_texts = [m["content"] for m in relevant 
                      if m.get("role") == "assistant"]
    user_questions = [m["content"] for m in relevant 
                     if m.get("role") == "user"]
    
    # 3. Extract first N sentences from assistant (key points)
    sentences = []
    for text in assistant_texts:
        sentences.extend(text.split('. ')[:max_sentences])
    
    # 4. Combine into compact summary
    return " ".join(sentences[:max_sentences])
```

**Production Enhancement (Future):**
```python
# LLM-based compaction (better quality, adds latency)
def llm_compact_context(history: List[Dict]) -> str:
    prompt = f"""Summarize this photography coaching conversation 
    in 3 sentences, preserving key advice and user goals:
    
    {history}
    """
    return gemini.generate(prompt)
```

#### Solution 2: Persistent Session Management

**Multi-Layer Session Architecture:**
```
┌──────────────────────────────────────────────────────────┐
│                SESSION MANAGEMENT LAYERS                  │
└──────────────────────────────────────────────────────────┘

Layer 1: In-Memory Store (Fast Access)
   SESSION_STORE = {
       "user123": {
           "skill_level": "intermediate",
           "history": [...],
           "compact_summary": "..."
       }
   }
   ↓ Synchronized via ↓

Layer 2: SQLite Persistence (Survives Restarts)
   Table: key_value_store
   | user_id  | key      | value (JSON)              |
   |----------|----------|---------------------------|
   | user123  | session  | {"skill_level": "inter... |
   
   ↓ Adapter Pattern (ADK-Ready) ↓

Layer 3: Cloud Storage (Production)
   Google Cloud ADK Memory Store (when deployed)
   - Distributed across regions
   - Auto-scaling
   - Shared across ADK Runner instances
```

**Session Lifecycle:**

```python
# 1. Session Restoration (App Startup / New Request)
def _get_session(self, user_id: str) -> Dict:
    # Try persisted first (survives app restarts)
    persisted = memory.get_value(user_id, "session")
    if persisted:
        SESSION_STORE[user_id] = persisted  # Hydrate in-memory
    
    # Initialize new session if first-time user
    if user_id not in SESSION_STORE:
        SESSION_STORE[user_id] = {
            "skill_level": "beginner",
            "history": []
        }
    
    return SESSION_STORE[user_id]

# 2. Session Update (During Request)
session["history"].append({
    "query": query,
    "issues": vision_result.issues
})

# 3. Context Compaction (If Needed)
if len(session["history"]) > 6:
    session["compact_summary"] = compact_context(session["history"])

# 4. Session Persistence (After Request)
def _persist_session(self, user_id: str):
    memory.set_value(user_id, "session", SESSION_STORE[user_id])
```

**ADK Adapter Pattern (Cloud-Ready):**
```python
# tools/adk_adapter.py - Transparent ADK integration

def set_value(user_id: str, key: str, value: Any):
    if ADK_AVAILABLE:
        adk_session.set(user_id, key, value)  # Cloud storage
    else:
        sqlite.set(user_id, key, value)       # Local fallback

# Benefit: Same code works locally (SQLite) and cloud (ADK)
# No code changes needed when deploying to Vertex AI
```

**Session State Schema:**
```python
Session = {
    "skill_level": "beginner" | "intermediate" | "advanced",
    "history": [
        {
            "query": str,           # User's question
            "issues": List[str],    # Issues detected in that turn
            "timestamp": float      # For analytics
        }
    ],
    "compact_summary": str,         # Generated when history > 6
    "metadata": {
        "total_photos_analyzed": int,
        "session_start": datetime,
        "last_activity": datetime
    }
}
```

#### Benefits of This Approach

**1. Scalability**
```
Without Compaction:
- Turn 10:  Fails (token overflow)
- Max turns: ~8-10

With Compaction:
- Turn 50:  Works (summary keeps tokens low)
- Max turns: Unlimited (bounded by summary size)
```

**2. Performance**
```
Session Restoration Time:
- In-Memory:  <1ms   (cache hit)
- SQLite:     ~5ms   (disk read)
- ADK Cloud:  ~20ms  (network call)

Strategy: In-memory first, persist async
```

**3. Cloud Migration Path**
```python
# Development: SQLite
adk_adapter → memory.py → SQLite file

# Production: ADK Cloud Memory
adk_adapter → google.adk.sessions.InMemorySessionService → Cloud Storage

# Zero Code Changes: Adapter pattern abstracts storage layer
```

**4. Observability**
```python
# Session analytics enabled by persistent state
metrics = {
    "avg_turns_per_session": 7.3,
    "compaction_trigger_rate": 0.23,  # 23% of sessions hit 6 turns
    "session_restore_success": 0.98   # 98% successful hydration
}
```

#### Testing Session Management

```python
# Test: Context compaction reduces tokens
def test_compaction():
    long_history = generate_history(turns=20)  # ~8K tokens
    
    summary = compact_context(long_history)
    
    assert len(summary.split()) < 100  # Under 100 words
    assert "rule of thirds" in summary  # Key concepts preserved

# Test: Session persistence survives restart
def test_session_persistence():
    orchestrator.run(user_id="test", query="Analyze photo")
    
    # Simulate app restart
    SESSION_STORE.clear()
    
    # Restore session
    session = orchestrator._get_session("test")
    
    assert len(session["history"]) > 0  # History restored from SQLite
```

### Data Flow Example

```python
# 1. User uploads photo and asks question
user_input = {
    "query": "How can I improve this landscape composition?",
    "image_path": "photo.jpg",
    "skill_level": "intermediate"
}

# 2. Orchestrator routes to VisionAgent
vision_result = vision_agent.analyze(
    image_path="photo.jpg",
    skill_level="intermediate"
)
# Returns: VisionAnalysis(exif={...}, issues=[...], strengths=[...])

# 3. Orchestrator passes vision_result to KnowledgeAgent
coaching_result = knowledge_agent.coach(
    query="How can I improve this landscape composition?",
    vision_analysis=vision_result,  # Context from sub-agent 1
    session={"history": [...]}       # Maintained by orchestrator
)
# Returns: CoachingResponse(text="...", principles=[...], exercise="...")

# 4. Orchestrator aggregates and persists
final_response = {
    "analysis": vision_result,
    "coaching": coaching_result,
    "session_updated": True
}
```

### Agent Capabilities

**VisionAgent** (Gemini Vision)
- EXIF metadata extraction (camera settings, lens data)
- Composition analysis with severity scoring
- Issue detection (exposure, focus, horizon, etc.)
- Strength identification

**KnowledgeAgent** (Gemini + Hybrid RAG)
- Personalized coaching based on skill level
- Citation-backed advice from knowledge base
- Practice exercise generation
- Session history awareness

### Deployment Architecture (3 Platforms)

The **same agent hierarchy** (Orchestrator → Vision + Knowledge) deploys across three platforms:

```
┌─────────────────────────────────────────────────────────────────┐
│                     CORE AGENTS (Shared)                        │
│                                                                 │
│  Orchestrator ────┬──→ VisionAgent (Gemini Vision)            │
│                   └──→ KnowledgeAgent (Gemini + RAG)           │
└─────────────────────────────────────────────────────────────────┘
                              ↓
        ┌─────────────────────┼─────────────────────┐
        ↓                     ↓                     ↓
┌───────────────┐   ┌──────────────────┐   ┌──────────────────┐
│  ADK RUNNER   │   │   MCP SERVER     │   │   PYTHON API     │
│  (Cloud)      │   │   (Desktop)      │   │   (Custom)       │
├───────────────┤   ├──────────────────┤   ├──────────────────┤
│ LlmAgent      │   │ JSON-RPC 2.0     │   │ Direct imports   │
│ Runner        │   │ stdio transport  │   │ function calls   │
│ Sessions      │   │ 3 tools exposed  │   │                  │
│               │   │                  │   │                  │
│ Deploy:       │   │ Deploy:          │   │ Deploy:          │
│ Vertex AI     │   │ Claude Desktop   │   │ Notebooks        │
│ Cloud Run     │   │ Local machine    │   │ Custom apps      │
└───────────────┘   └──────────────────┘   └──────────────────┘
```

### Platform Comparison

| Feature | ADK Runner | MCP Server | Python API |
|---------|-----------|-----------|-----------|
| **Framework** | google.adk | JSON-RPC 2.0 | Native Python |
| **Deployment** | Vertex AI / Cloud | Claude Desktop | Notebooks, scripts |
| **Agent Access** | Via LlmAgent wrapper | Via tool definitions | Direct class import |
| **Session Management** | InMemorySessionService | Custom dict | Custom dict |
| **Execution** | Async (Runner) | Async (stdio) | Synchronous |
| **Use Case** | Enterprise scaling | Local AI assistant | Custom integration |
| **Code Reuse** | ✅ Same agents | ✅ Same agents | ✅ Same agents |

**Architectural Principle:** Zero code duplication across platforms – the **same Orchestrator, VisionAgent, and KnowledgeAgent** instances work everywhere. Only the **deployment wrapper** changes.

---

## 📚 Hybrid CASCADE RAG

Novel retrieval architecture combining reliability with flexibility:

```
Query → Agentic RAG (Gemini creativity)
         ↓
    1. Primary: Curated Knowledge (20 entries)
       - NumPy similarity search
       - Threshold: 0.6
       - Fast, high-quality
         ↓
    2. Secondary: FAISS Fallback (1000+ entries)
       - Vector search
       - Broader coverage
       - Deployed when needed
         ↓
    3. Grounding: Gemini adds citations
       - "📚 Supporting Resources"
       - Source attribution
       - Builds trust
```

**Innovation**: Combines curated precision with vector breadth, avoiding pure LLM hallucination.

---

## 🎓 Capstone Requirements Met

### ✅ Multi-Agent System
- **3 Agents**: Orchestrator, VisionAgent, KnowledgeAgent
- **Coordination**: Orchestrator manages agent interactions
- **State Management**: Conversation history tracking

### ✅ Google Technologies
- **Gemini 2.5 Flash**: LLM for coaching + vision analysis
- **MCP Protocol**: JSON-RPC server implementation
- **ADK Compatible**: Tool definitions for Vertex AI

### ✅ Production Quality
- **Error Handling**: Graceful fallbacks for API failures
- **Caching**: Embeddings cached for performance
- **Logging**: Comprehensive debug output
- **Testing**: Unit tests for core components

### ✅ Real-World Application
- **Domain**: Photography education (multi-billion $ market)
- **Impact**: Democratizes expert coaching
- **Scalability**: API-first architecture

---

## 📁 Project Structure

```
agents_capstone/
├── agents/
│   ├── orchestrator.py      # Multi-agent coordinator
│   ├── vision_agent.py       # EXIF + composition analysis
│   ├── knowledge_agent.py    # Gemini + RAG coaching
│   └── chat_coach.py         # Conversational interface
├── tools/
│   ├── mcp_server.py         # MCP JSON-RPC server ⭐
│   ├── adk_adapter.py        # ADK tool definitions ⭐
│   ├── agentic_rag.py        # Hybrid CASCADE RAG
│   ├── exif_tool.py          # Photo metadata extraction
│   └── knowledge_base.py     # Curated photography knowledge
├── demo_adk.py               # ADK demonstration script
├── demo_mcp.py               # MCP demonstration script
└── evaluate.py               # Automated evaluation harness
```

---

## 🧪 Evaluation & Testing

### Automated Evaluation Framework

The project includes a comprehensive evaluation harness (`demo_eval.py`) that tests agent performance across multiple dimensions:

```bash
python3 demo_eval.py
```

#### Evaluation Methodology

**1. Test Dataset**
- 3 diverse photography scenarios (landscape, portrait, technical questions)
- Mix of image analysis and knowledge queries
- Covers beginner to advanced skill levels

**2. Scoring Criteria**

| Metric | What It Measures | How It's Scored |
|--------|------------------|-----------------|
| **Overall Score** | System effectiveness | Weighted average of all metrics (0-10) |
| **Response Quality** | Coaching usefulness | LLM-as-judge evaluation (0-5) |
| **Citation Accuracy** | RAG grounding | % of responses with knowledge sources |
| **Latency** | Response speed | Time from query to complete answer |
| **EXIF Accuracy** | Vision analysis | Metadata extraction correctness |

**3. LLM-as-Judge Evaluation**

Gemini evaluates each response on:
- **Relevance**: Does it answer the question?
- **Actionability**: Can the user apply the advice?
- **Technical accuracy**: Are photography principles correct?
- **Appropriate detail**: Right depth for skill level?

**4. RAG Citation Verification**

Tests whether responses include:
- Structured knowledge base references
- Photography principle citations (e.g., "Rule of Thirds from curated knowledge")
- Fallback to vector search when needed
- No hallucinated sources

#### Current Results

- **Overall Score**: 8.58/10 ✅
- **Response Quality**: 4.2/5 (LLM-as-judge evaluation)
- **Citation Accuracy**: 95%+ responses grounded in RAG
- **Average Latency**: 26.6s (includes vision analysis + coaching + RAG)
- **EXIF Extraction**: 100% accuracy on test images

**Generated Reports** (`./reports/`):
- `evaluation_detailed.json` – Full response logs and scores
- `evaluation_summary.csv` – Metric breakdown by test case
- `evaluation_report.html` – Interactive visual dashboard

### Manual Testing

```bash
# Test individual platforms
python3 agents_capstone/adk_runner.py      # ADK Runner
python3 demo_mcp.py                         # MCP Server
python3 demo_3_platforms.py                 # All platforms
```

### What "8.58/10" Means

This score represents **production-ready quality** across:
- ✅ Accurate technical analysis (EXIF, composition)
- ✅ Helpful, citation-backed coaching advice
- ✅ Appropriate skill-level adaptation
- ✅ Acceptable latency for real-world use
- ⚠️ Room for improvement: Faster RAG retrieval, more diverse knowledge base

---

## 🔧 Technical Implementation

### Multi-Agent Coordination
```python
orchestrator = Orchestrator(
    vision_agent=VisionAgent(),
    knowledge_agent=KnowledgeAgent()
)

result = orchestrator.process(
    user_query="How to improve composition?",
    image_path="photo.jpg",
    session={"history": []}
)
```

### ADK Runner Integration
```python
from google.adk.agents import LlmAgent
from google.adk.runners import Runner
from google.adk.sessions import InMemorySessionService

agent = LlmAgent(model="gemini-2.5-flash", name="PhotoCoach")
runner = Runner(agent=agent, session_service=session_service)

async for event in runner.run_async(user_id, session_id, new_message):
    if event.content:
        print(event.content.parts[0].text)
```

### MCP Server Protocol
- JSON-RPC 2.0 over stdio transport
- Three tools: `analyze_photo`, `coach_on_photo`, `get_session_history`
- Full error handling and progress notifications
- Claude Desktop compatible

### Hybrid CASCADE RAG
1. **Primary**: Curated knowledge (NumPy similarity, threshold 0.6)
2. **Secondary**: FAISS vector store (1000+ chunks, broader coverage)
3. **Grounding**: Gemini adds structured citations

---

## 📖 Documentation

- **[DELIVERABLES.md](DELIVERABLES.md)**: Capstone submission checklist
- **[KAGGLE_WRITEUP_ENHANCED.md](KAGGLE_WRITEUP_ENHANCED.md)**: Technical deep-dive
- **[ADK_INTEGRATION.md](agents_capstone/ADK_INTEGRATION.md)**: ADK usage guide
- **[OBSERVABILITY.md](agents_capstone/OBSERVABILITY.md)**: Logging & monitoring

---

## 🎯 Key Innovations

1. **Multi-Platform Architecture**: Single agent codebase deploys to ADK (cloud), MCP (desktop), and Python API (custom)
2. **Hybrid CASCADE RAG**: Combines curated knowledge precision with FAISS vector breadth
3. **Domain Specialization**: 20+ curated photography principles with 1000+ document chunks
4. **Production Quality**: Full error handling, caching, logging, and evaluation harness

---

## 🏆 Capstone Submission

**Repository**: https://github.com/prasadt1/ai-photography-coach-agents  
**Branch**: `capstone-submission`

**Quick Start:**
```bash
git clone https://github.com/prasadt1/ai-photography-coach-agents.git
cd ai-photography-coach-agents
pip install -r requirements.txt
export GOOGLE_API_KEY="your_key"
python3 demo_3_platforms.py
```

**Evaluation:**
```bash
python3 demo_eval.py  # Score: 8.58/10
```

---

## 📝 License

MIT License - See [LICENSE](LICENSE) for details.

---

**Built with**: Python 3.11 • Gemini 2.5 Flash • MCP • ADK • FAISS • LangChain

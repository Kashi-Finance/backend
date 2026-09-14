# Kashi Finances — Recommendation System Specification# Kashi Finances — Recommendation System Specification# Kashi Finances — Recommendation System Specification



**Architecture Pattern**: Web-Grounded LLM (Single Gemini API Call with Google Search)  

**Model**: Gemini 2.5 Flash (`gemini-2.5-flash`) 

> **Path note (2026):** `backend/agents/` was renamed to `backend/llm/`. Any
> `backend/agents/...` path in this document means `backend/llm/...`, except in
> the "Files Deleted (November 2025)" history section where the old paths are
> intentional.

**Architecture Pattern**: Web-Grounded LLM (Single Gemini API Call with Google Search)  **Architecture Pattern**: Prompt Chaining (Single LLM Call)  

---

**Model**: Gemini 2.5 Flash (`gemini-2.5-flash`) 

## 📋 Executive Summary



The Kashi Finances recommendation system provides personalized product suggestions to users based on their purchase goals, budget constraints, and preferences. The system uses **Gemini with Google Search grounding** to ensure all product recommendations are based on **real, current web data** - not LLM training knowledge.

------

---



## 🏗️ Architecture Overview

## 📋 Executive Summary## 📋 Executive Summary

### High-Level Flow



```

┌──────────────────────────────────────────────────────────┐The Kashi Finances recommendation system provides personalized product suggestions to users based on their purchase goals, budget constraints, and preferences. The system uses **Gemini with Google Search grounding** to ensure all product recommendations are based on **real, current web data** - not LLM training knowledge.The Kashi Finances recommendation system provides personalized product suggestions to users based on their purchase goals, budget constraints, and preferences. The system was fully refactored in November 2025 from a complex multi-agent ADK architecture to a simplified Prompt Chaining approach for improved reliability, reduced cost, and faster response times.

│        WEB-GROUNDED LLM ARCHITECTURE                     │

│     (Gemini + Google Search Grounding Tool)              │

└──────────────────────────────────────────────────────────┘

------

User Query

    │

    ▼

┌──────────────────────────────────────────────────────────┐## 🏗️ Architecture Overview## 🏗️ Architecture Overview

│  FastAPI Endpoint: POST /recommendations/query           │

│  - Authenticate user (Supabase Auth JWT)                 │

│  - Fetch user profile (country, currency_preference)     │

│  - Validate request (RecommendationQueryRequest)         │### High-Level Flow### High-Level Flow

└──────────────────────────────────────────────────────────┘

    │

    ▼

┌──────────────────────────────────────────────────────────┐``````

│  recommendation_service.query_recommendations()          │

│  - Build comprehensive prompt with all context           │┌──────────────────────────────────────────────────────────┐┌──────────────────────────────────────────────────────────┐

│  - Single call to Gemini API with Google Search tool     │

│  - Parse JSON from response text                         ││        WEB-GROUNDED LLM ARCHITECTURE                     ││              PROMPT CHAINING ARCHITECTURE                │

│  - Extract grounding metadata (sources, search queries)  │

│  - Map to Pydantic response models                       ││     (Gemini + Google Search Grounding Tool)              ││              (Single DeepSeek LLM Call)                  │

└──────────────────────────────────────────────────────────┘

    │└──────────────────────────────────────────────────────────┘└──────────────────────────────────────────────────────────┘

    ▼

┌──────────────────────────────────────────────────────────┐

│  SINGLE GEMINI CALL (with Google Search Grounding)       │

│  ─────────────────────────────────────────────────────── │┌──────────────┐┌──────────────┐

│  Model: gemini-2.5-flash                                 │

│  Temperature: 0.2 (near-deterministic)                   ││  User Query  ││  User Query  │

│  Response Format: Text (JSON parsed from response)       │

│  ─────────────────────────────────────────────────────── ││ "laptop para ││ "laptop para │

│                                                          │

│  GOOGLE SEARCH GROUNDING:                                ││  diseño bajo ││  diseño bajo │

│  - Gemini automatically searches Google                  │

│  - Returns REAL product data from live web pages         ││   Q7000"     ││   Q7000"     │

│  - URLs and prices are verified from actual sources      │

│  ─────────────────────────────────────────────────────── │└──────┬───────┘└──────┬───────┘

│                                                          │

│  NOTE: Google Search tool doesn't support                │       │       │

│  response_mime_type='application/json' or response_schema│

│  We ask for JSON in the prompt and parse from text.      │       ▼       ▼

└──────────────────────────────────────────────────────────┘

    │┌──────────────────────────────────────────────────────────┐┌──────────────────────────────────────────────────────────┐

    ▼

┌──────────────────────────────────────────────────────────┐│  FastAPI Endpoint: POST /recommendations/query           ││  FastAPI Endpoint: POST /recommendations/query           │

│  Gemini Response (Text + Grounding Metadata)             │

│                                                          ││  - Authenticate user (Supabase Auth JWT)                 ││  - Authenticate user (Supabase Auth JWT)                 │

│  Response Text (JSON):                                   │

│  {                                                       ││  - Fetch user profile (country, currency_preference)      ││  - Fetch user profile (country, currency_preference)      │

│    "status": "OK",                                       │

│    "products": [...],                                    ││  - Validate request (RecommendationQueryRequest)         ││  - Validate request (RecommendationQueryRequest)         │

│    "metadata": {...}                                     │

│  }                                                       │└──────────────┬───────────────────────────────────────────┘└──────────────┬───────────────────────────────────────────┘

│                                                          │

│  Grounding Metadata:                                     │               │               │

│  - web_search_queries: [...]                             │

│  - grounding_chunks: [{uri, title, domain}, ...]         │               ▼               ▼

└──────────────────────────────────────────────────────────┘

    │┌──────────────────────────────────────────────────────────┐┌──────────────────────────────────────────────────────────┐

    ▼

┌──────────────────────────────────────────────────────────┐│  recommendation_service.query_recommendations()          ││  recommendation_service.query_recommendations()          │

│  FastAPI Response                                        │

│  - Return validated Pydantic model                       ││  - Build comprehensive prompt with all context           ││  - Format comprehensive prompt with all context          │

│  - HTTP 200 (always, errors in response body)            │

│  - Mobile app displays results or error message          ││  - Single call to Gemini API with Google Search tool     ││  - Single call to DeepSeek API                           │

└──────────────────────────────────────────────────────────┘

│  - Parse structured JSON response                        ││  - Parse structured JSON response                        │

✅ ADVANTAGES:

- Real web data via Google Search grounding│  - Extract grounding metadata (sources, search queries)  ││  - Validate response schema                              │

- Verified URLs and current prices

- Single API call (search is automatic)│  - Map to Pydantic response models                       ││  - Map to Pydantic response models                       │

- Grounding metadata for transparency

```└──────────────┬───────────────────────────────────────────┘└──────────────┬───────────────────────────────────────────┘



---               │               │



## 📂 Code Structure               ▼               ▼



### Directory Layout┌─────────────────────────────────────────────────────────┐┌─────────────────────────────────────────────────────────┐



```│  SINGLE GEMINI CALL (with Google Search Grounding)      ││  SINGLE LLM CALL (DeepSeek V3.2)                        │

backend/

├── agents/│  ────────────────────────────────────────────────────── ││  ────────────────────────────────────────────────────── │

│   └── recommendation/

│       ├── __init__.py           # Module docstring│  Model: gemini-2.5-flash                                ││  Model: deepseek-chat                                   │

│       └── prompts.py            # System and user prompt templates

├── services/│  Temperature: 0.2 (near-deterministic)                  ││  Temperature: 0.0 (deterministic)                       │

│   └── recommendation_service.py # Main service logic (Gemini API)

├── routes/│  Response Format: Structured JSON (Pydantic schema)     ││  Response Format: JSON (forced)                         │

│   └── recommendations.py        # FastAPI endpoints

└── schemas/│  Max Tokens: 4096                                       ││  Max Tokens: 4096                                       │

    └── recommendations.py        # Pydantic request/response models

```│  ────────────────────────────────────────────────────── ││  ────────────────────────────────────────────────────── │



### Prompt Templates│                                                         ││                                                         │



**`backend/agents/recommendation/prompts.py`**│  GOOGLE SEARCH GROUNDING:                               ││  SYSTEM PROMPT (from prompts.py):                       │

- `RECOMMENDATION_SYSTEM_PROMPT`: Defines LLM role, capabilities, and guardrails (XML-structured)

- `build_recommendation_user_prompt()`: Function to build user prompt with structured context│  - Gemini automatically searches Google                 ││  - Role definition and capabilities                     │



The prompts follow Anthropic's best practices:│  - Returns REAL product data from live web pages        ││  - Guardrails (prohibited content)                      │

- XML tags for structured content (`<role>`, `<instructions>`, `<examples>`, etc.)

- System prompt defines role only, task instructions in user turn│  - URLs and prices are verified from actual sources     ││  - Output format specification                          │

- Multishot examples for accuracy and consistency

│  ────────────────────────────────────────────────────── ││                                                         │

---

│                                                         ││  USER PROMPT (from prompts.py):                         │

## 🔧 API Endpoints

│  SYSTEM PROMPT (from prompts.py):                       ││  - query_raw: "laptop para diseño bajo Q7000"           │

### POST /recommendations/query

│  - Role definition and capabilities                     ││  - budget_hint: 7000                                    │

**Purpose**: Initial recommendation query

│  - Guardrails (prohibited content)                      ││  - country: "GT"                                        │

**Authentication**: Required (Bearer token)

│  - Output format specification                          ││  - currency: "GTQ"                                      │

**Request Model**: `RecommendationQueryRequest`

```json│                                                         ││  - XML-structured instructions and examples             │

{

  "query_raw": "laptop para diseño gráfico",│  USER PROMPT (from prompts.py):                         ││  - Output schema specification                          │

  "budget_hint": 7000.00,

  "preferred_store": "Intelaf",│  - query_raw: "laptop para diseño bajo Q7000"           │└──────────────┬──────────────────────────────────────────┘

  "user_note": "nada gamer con RGB",

  "extra_details": {}│  - budget_hint: 7000                                    │               │

}

```│  - country: "GT"                                        │               ▼



**Response Models**:│  - currency: "GTQ"                                      │┌──────────────────────────────────────────────────────────┐



1. **`RecommendationQueryResponseOK`** (Success)│  - XML-structured instructions and examples             ││  LLM Response (Structured JSON)                          │

```json

{└──────────────┬──────────────────────────────────────────┘│                                                          │

  "status": "OK",

  "results_for_user": [               ││  SUCCESS CASE:                                           │

    {

      "product_title": "ASUS Vivobook 15 Ryzen 7 16GB RAM 512GB SSD",               ▼│  {                                                       │

      "price_total": 6750.00,

      "seller_name": "TecnoMundo Guatemala",┌──────────────────────────────────────────────────────────┐│    "status": "OK",                                       │

      "url": "https://tecnomundo.com.gt/asus-vivobook15",

      "pickup_available": true,│  Gemini Response (Structured JSON + Grounding Metadata)  ││    "products": [                                         │

      "warranty_info": "Garantía 12 meses tienda",

      "copy_for_user": "Ideal para diseño gráfico con GPU dedicada. Diseño sobrio sin luces RGB.",│                                                          ││      {                                                   │

      "badges": ["Buen precio", "GPU dedicada", "Diseño sobrio"]

    }│  SUCCESS CASE:                                           ││        "product_title": "ASUS Vivobook 15 Ryzen 7...",   │

  ]

}│  {                                                       ││        "price_total": 6750.00,                           │

```

│    "status": "OK",                                       ││        "seller_name": "TecnoMundo Guatemala",            │

2. **`RecommendationQueryResponseNoValidOption`** (No products or error)

```json│    "products": [                                         ││        "url": "https://...",                             │

{

  "status": "NO_VALID_OPTION",│      {                                                   ││        "pickup_available": true,                         │

  "reason": "No se encontraron productos que cumplan los criterios dentro del presupuesto de Q7000."

}│        "product_title": "ASUS Vivobook 15 Ryzen 7...",   ││        "warranty_info": "Garantía 12 meses",             │

```

│        "price_total": "6750.00",                         ││        "copy_for_user": "Ideal para diseño...",          │

---

│        "seller_name": "TecnoMundo Guatemala",            ││        "badges": ["Buen precio", "GPU dedicada"]         │

### POST /recommendations/retry

│        "url": "https://...",                             ││      }                                                   │

**Purpose**: Retry with updated criteria

│        "pickup_available": true,                         ││    ],                                                    │

**Authentication**: Required (Bearer token)

│        "warranty_info": "Garantía 12 meses",             ││    "metadata": {                                         │

**Request Model**: `RecommendationRetryRequest` (identical to `RecommendationQueryRequest`)

│        "copy_for_user": "Ideal para diseño...",          ││      "total_results": 1,                                 │

**Behavior**: Identical to `/query` but semantically represents a retry/refinement

│        "badges": ["Buen precio", "GPU dedicada"]         ││      "query_understood": true,                           │

**Response Models**: Same as `/query`

│      }                                                   ││      "search_successful": true                           │

---

│    ]                                                     ││    }                                                     │

## 🔧 Configuration

│  }                                                       ││  }                                                       │

### Environment Variables

│                                                          ││                                                          │

| Variable | Required | Description |

|----------|----------|-------------|│  GROUNDING METADATA:                                     ││  NO PRODUCTS FOUND CASE:                                 │

| `GOOGLE_API_KEY` | ✅ Yes | Gemini API key from Google AI Studio |

| `SUPABASE_URL` | ✅ Yes | Supabase project URL |│  - web_search_queries: ["laptop diseño grafico GT..."]   ││  {                                                       │

| `SUPABASE_PUBLISHABLE_KEY` | ✅ Yes | Supabase publishable key |

│  - grounding_chunks: [{uri: "...", title: "..."}]        ││    "status": "NO_VALID_OPTION",                          │

### Model Configuration

└──────────────┬───────────────────────────────-───────────┘│    "products": [],                                       │

```python

# In recommendation_service.py               ││    "metadata": {                                         │

client = genai.Client(api_key=GOOGLE_API_KEY)

               ▼│      "total_results": 0,                                 │

# NOTE: Google Search grounding doesn't support response_mime_type='application/json'

# or response_schema. We ask for JSON in the prompt and parse it from text.┌──────────────────────────────────────────────────────────┐│      "query_understood": true,                           │

config = types.GenerateContentConfig(

    system_instruction=RECOMMENDATION_SYSTEM_PROMPT,│  recommendation_service.py                               ││      "search_successful": true,                          │

    temperature=0.2,  # Near-deterministic for factual queries

    tools=[│  - Validate LLM response structure                       ││      "reason": "No products found under Q7000..."        │

        types.Tool(google_search=types.GoogleSearch())

    ],│  - Map to Pydantic response models:                      ││    }                                                     │

)

│    * RecommendationQueryResponseOK                       ││  }                                                       │

response = client.models.generate_content(

    model="gemini-2.5-flash",│    * RecommendationQueryResponseNoValidOption            │└──────────────┬───────────────────────────────-───────────┘

    contents=user_prompt,

    config=config,│  - Handle all errors gracefully                          │               │

)

```└──────────────┬───────────────────────────────────────────┘               ▼



---               │┌──────────────────────────────────────────────────────────┐



## 🔒 Security & Guardrails               ▼│  response_service.py                                     │



### Prohibited Content Detection┌──────────────────────────────────────────────────────────┐│  - Validate LLM response structure                       │

System prompt includes explicit guardrails:

- Sexual/erotic content│  FastAPI Response                                        ││  - Map to Pydantic response models:                      │

- Weapons, explosives, regulated items

- Illegal products or services│  - Return validated Pydantic model                       ││    * RecommendationQueryResponseOK                       │

- Scams or harmful products

│  - HTTP 200 (always, errors in response body)            ││    * RecommendationQueryResponseNoValidOption            │

**Behavior**: Immediate NO_VALID_OPTION response without product search

│  - Mobile app displays results or error message          ││  - Handle all errors gracefully                          │

### Authentication & Authorization

- All endpoints require Supabase Auth JWT└──────────────────────────────────────────────────────────┘└──────────────┬───────────────────────────────────────────┘

- User context (profile) fetched using authenticated client

- RLS enforced on all database queries               │



### Data Privacy✅ ADVANTAGES:               ▼

- No sensitive user data logged

- User queries logged only in aggregate (no PII)- Real web data via Google Search grounding┌──────────────────────────────────────────────────────────┐

- Product search results not persisted

- Verified URLs and current prices│  FastAPI Response                                        │

---

- Single API call (search is automatic)│  - Return validated Pydantic model                       │

## 📊 Grounding Metadata

- Structured output via Pydantic schema│  - HTTP 200 (always, errors in response body)            │

The Gemini response includes grounding metadata that can be used for:

- Transparency: Show users where data came from- Grounding metadata for transparency│  - Mobile app displays results or error message          │

- Debugging: Verify search queries used

- Quality assurance: Confirm URLs are from legitimate sources```└──────────────────────────────────────────────────────────┘



### Access Pattern

```python

# After calling Gemini---✅ ADVANTAGES:

grounding_metadata = response.candidates[0].grounding_metadata

- Single point of failure (1 API call vs 3)

# Search queries used by Gemini

web_search_queries = grounding_metadata.web_search_queries## 📂 Code Structure- Faster response time (1 round-trip vs 3)

# Example: ["laptop diseño grafico guatemala precio", "ASUS Vivobook Guatemala comprar"]

- Deterministic output (temp=0.0)

# Source URLs

grounding_chunks = grounding_metadata.grounding_chunks### Directory Layout- Graceful degradation built-in

# Example: [{uri: "https://store.com/product", title: "ASUS Vivobook 15"}]

```- 75% cost reduction (DeepSeek vs Gemini)



---```- No unknown tool call loops



## 🧪 Testingbackend/- No 503 overload cascading errors



### Local Testing Script├── agents/```



```bash│   └── recommendation/

# Set environment variable

export GOOGLE_API_KEY=your-gemini-api-key│       ├── __init__.py           # Module docstring---



# Run test script│       └── prompts.py            # System and user prompt templates

python scripts/test_recommendations.py --query "laptop para diseño" --budget 7000

```├── services/## 📂 Code Structure



### Unit Tests│   └── recommendation_service.py # Main service logic (Gemini API)

- `test_format_user_prompt()`: Verify prompt template formatting

- `test_validate_llm_response()`: Verify response schema validation├── routes/### Directory Layout

- `test_get_user_profile()`: Verify profile fetching with defaults

│   └── recommendations.py        # FastAPI endpoints

### Integration Tests

- `test_query_recommendations_success()`: Full flow with mock Gemini response└── schemas/```

- `test_query_recommendations_no_products()`: NO_VALID_OPTION handling

- `test_query_recommendations_auth_error()`: Authentication failures    └── recommendations.py        # Pydantic request/response modelsbackend/

- `test_retry_recommendations()`: Retry flow

```├── agents/

---

│   └── recommendation/

## ⚠️ Important Limitations

### Prompt Templates│       ├── __init__.py

### Google Search Tool Incompatibility with Structured Output

│       └── prompts/

The Google Search grounding tool **does not support** the following configuration options:

- `response_mime_type='application/json'`**`backend/agents/recommendation/prompts.py`**│           ├── __init__.py

- `response_schema=PydanticModel`

- `RECOMMENDATION_SYSTEM_PROMPT`: Defines LLM role, capabilities, and guardrails (XML-structured)│           ├── system_prompt.py      # System prompt for LLM behavior

When these are used together, Gemini returns a 400 error:

> "Tool use with a response mime type: 'application/json' is unsupported"- `build_recommendation_user_prompt()`: Function to build user prompt with structured context│           └── user_prompt_template.py  # User prompt template



**Workaround**: We ask for JSON output in the prompt itself and parse it from the response text. The response may be wrapped in markdown code blocks (```json ... ```) which are stripped before parsing.├── services/



---The prompts follow Anthropic's best practices:│   └── recommendation_service.py     # Main service logic



## 🔄 Migration History- XML tags for structured content (`<role>`, `<instructions>`, `<examples>`, etc.)├── routes/



### January 2025: Gemini + Google Search Grounding- System prompt defines role only, task instructions in user turn│   └── recommendations.py            # FastAPI endpoints

- Migrated from Perplexity Sonar to Gemini 2.5 Flash

- Added Google Search grounding tool for real web data- Multishot examples for accuracy and consistency└── schemas/

- Discovered: Cannot use `response_schema` with Google Search tool

- Implemented text-based JSON parsing as workaround    └── recommendations.py            # Pydantic request/response models

- Single SDK: `google-genai` (shared with InvoiceAgent)

---```

### December 2024: Perplexity Sonar

- Migrated from DeepSeek V3.2 to Perplexity Sonar

- Native web grounding for real product data

## 🔧 API Endpoints### Prompt Templates

### November 2024: DeepSeek V3.2

- Initial Prompt Chaining architecture

- Replaced ADK Orchestrator-Workers pattern

### POST /recommendations/queryAll prompts are stored in a single file for simplicity:

---



## 📚 References

**Purpose**: Initial recommendation query**`backend/agents/recommendation/prompts.py`**

1. **Google Gemini Documentation**: [ai.google.dev](https://ai.google.dev/)

2. **Google Search Grounding**: [Gemini Grounding Docs](https://ai.google.dev/gemini-api/docs/grounding)- `RECOMMENDATION_SYSTEM_PROMPT`: Defines LLM role, capabilities, and guardrails (XML-structured)

3. **Google Gen AI Python SDK**: [googleapis/python-genai](https://github.com/googleapis/python-genai)

4. **Anthropic Research**: ["Building Effective Agents"](https://www.anthropic.com/research/building-effective-agents)**Authentication**: Required (Bearer token)- `build_recommendation_user_prompt()`: Function to build user prompt with structured context



---



**Document Version**: 3.1  **Request Model**: `RecommendationQueryRequest`The prompts follow Anthropic's best practices:

**Architecture Version**: Gemini + Google Search Grounding (January 2025)  

**Previous Versions**: ```json- XML tags for structured content (`<role>`, `<instructions>`, `<examples>`, etc.)

- v2.0: Perplexity Sonar (December 2024)

- v1.0: ADK Orchestrator-Workers (Deprecated){- System prompt defines role only, task instructions in user turn


  "query_raw": "laptop para diseño gráfico",- Multishot examples for accuracy and consistency

  "budget_hint": 7000.00,

  "preferred_store": "Intelaf",---

  "user_note": "nada gamer con RGB",

  "extra_details": {}## 🔧 API Endpoints

}

```### POST /recommendations/query



**Response Models**:**Purpose**: Initial recommendation query



1. **`RecommendationQueryResponseOK`** (Success)**Authentication**: Required (Bearer token)

```json

{**Request Model**: `RecommendationQueryRequest`

  "status": "OK",```json

  "results_for_user": [{

    {  "query_raw": "laptop para diseño gráfico",

      "product_title": "ASUS Vivobook 15 Ryzen 7 16GB RAM 512GB SSD",  "budget_hint": 7000.00,

      "price_total": "6750.00",  "preferred_store": "Intelaf",

      "seller_name": "TecnoMundo Guatemala",  "user_note": "nada gamer con RGB",

      "url": "https://tecnomundo.com.gt/asus-vivobook15",  "extra_details": {}

      "pickup_available": true,}

      "warranty_info": "Garantía 12 meses tienda",```

      "copy_for_user": "Ideal para diseño gráfico con GPU dedicada. Diseño sobrio sin luces RGB.",

      "badges": ["Buen precio", "GPU dedicada", "Diseño sobrio"]**Response Models**:

    }

  ]1. **`RecommendationQueryResponseOK`** (Success)

}```json

```{

  "status": "OK",

2. **`RecommendationQueryResponseNoValidOption`** (No products or error)  "results_for_user": [

```json    {

{      "product_title": "ASUS Vivobook 15 Ryzen 7 16GB RAM 512GB SSD",

  "status": "NO_VALID_OPTION",      "price_total": 6750.00,

  "reason": "No se encontraron productos que cumplan los criterios dentro del presupuesto de Q7000."      "seller_name": "TecnoMundo Guatemala",

}      "url": "https://tecnomundo.com.gt/asus-vivobook15",

```      "pickup_available": true,

      "warranty_info": "Garantía 12 meses tienda",

---      "copy_for_user": "Ideal para diseño gráfico con GPU dedicada. Diseño sobrio sin luces RGB.",

      "badges": ["Buen precio", "GPU dedicada", "Diseño sobrio"]

### POST /recommendations/retry    }

  ]

**Purpose**: Retry with updated criteria}

```

**Authentication**: Required (Bearer token)

2. **`RecommendationQueryResponseNoValidOption`** (No products or error)

**Request Model**: `RecommendationRetryRequest` (identical to `RecommendationQueryRequest`)```json

{

**Behavior**: Identical to `/query` but semantically represents a retry/refinement  "status": "NO_VALID_OPTION",

  "reason": "No se encontraron productos que cumplan los criterios dentro del presupuesto de Q7000."

**Response Models**: Same as `/query`}

```

---

3. **`RecommendationQueryResponseNeedsClarification`** (DEPRECATED in v2)

## 🔧 Configuration- No longer used in Prompt Chaining architecture

- Single-shot LLM cannot ask follow-up questions

### Environment Variables- If budget_hint is missing, system returns NO_VALID_OPTION with helpful message



| Variable | Required | Description |---

|----------|----------|-------------|

| `GOOGLE_API_KEY` | ✅ Yes | Gemini API key from Google AI Studio |### POST /recommendations/retry

| `SUPABASE_URL` | ✅ Yes | Supabase project URL |

| `SUPABASE_PUBLISHABLE_KEY` | ✅ Yes | Supabase publishable key |**Purpose**: Retry with updated criteria



### Model Configuration**Authentication**: Required (Bearer token)



```python**Request Model**: `RecommendationRetryRequest` (identical to `RecommendationQueryRequest`)

# In recommendation_service.py

client = genai.Client(api_key=GOOGLE_API_KEY)**Behavior**: Identical to `/query` but semantically represents a retry/refinement



response = client.models.generate_content(**Response Models**: Same as `/query`

    model="gemini-2.5-flash",

    contents=full_prompt,---

    config=types.GenerateContentConfig(

        temperature=0.2,## 🎯 LLM Execution Flow

        max_output_tokens=4096,

        response_mime_type="application/json",The single LLM call follows this internal logic (defined in `system_prompt.py`):

        response_schema=GeminiRecommendationOutput,

        tools=[types.Tool(google_search=types.GoogleSearch())],### STEP 1: Intent Validation (Guardrails)

    ),- Check if query describes prohibited content:

)  * Sexual/erotic content → return NO_VALID_OPTION

```  * Weapons, explosives, illegal items → return NO_VALID_OPTION

  * Scams or harmful products → return NO_VALID_OPTION

---- If intent unclear but potentially valid → proceed to Step 2



## 🔒 Security & Guardrails### STEP 2: Extract Query Intent

From natural language query, identify:

### Prohibited Content Detection- Product category/type (e.g., "laptop", "headphones")

System prompt includes explicit guardrails:- Key specifications (e.g., "for graphic design", "16GB RAM")

- Sexual/erotic content- Price sensitivity indicators

- Weapons, explosives, regulated items- Explicit constraints (e.g., "no RGB lights")

- Illegal products or services

- Scams or harmful products### STEP 3: Search Product Catalog

- **If search tools available**: Use google_search or similar

**Behavior**: Immediate NO_VALID_OPTION response without product search- **Target search to user's country** (use country code for local searches)

- **Prioritize**: Established e-commerce sites, tech stores, official distributors

### Authentication & Authorization- **Filter**: Products within budget_hint (or max 20% above if justified)

- All endpoints require Supabase Auth JWT- **Extract**: Product name, price, store, URL, warranty, pickup availability

- User context (profile) fetched using authenticated client

- RLS enforced on all database queries- **If NO search tools**: Return NO_VALID_OPTION with explanation



### Data Privacy### STEP 4: Validate & Filter Results

- No sensitive user data loggedFor each candidate:

- User queries logged only in aggregate (no PII)- Verify price within budget

- Product search results not persisted- Check product matches original query intent

- Respect user_note constraints (e.g., exclude "RGB gamer" if user said "nada gamer")

---- Remove suspicious listings (too cheap, fake, no valid URL)

- Confirm URL from legitimate domain

## 📊 Grounding Metadata

### STEP 5: Format Output

The Gemini response includes grounding metadata that can be used for:Create up to 3 product recommendations with:

- Transparency: Show users where data came from- `product_title`: Clear product name/model

- Debugging: Verify search queries used- `price_total`: Numeric price in user's currency

- Quality assurance: Confirm URLs are from legitimate sources- `seller_name`: Store or seller name

- `url`: Valid product URL

### Access Pattern- `pickup_available`: Boolean

```python- `warranty_info`: E.g., "12 meses garantía"

# After calling Gemini- `copy_for_user`: Brief description (max 3 sentences, factual, no emojis)

grounding_metadata = response.candidates[0].grounding_metadata- `badges`: Up to 3 short labels (e.g., "Buen precio", "GPU dedicada")



# Search queries used by GeminiRanking: Best value/fit first, max 3 products

web_search_queries = grounding_metadata.web_search_queries

# Example: ["laptop diseño grafico guatemala precio", "ASUS Vivobook Guatemala comprar"]### STEP 6: Graceful Degradation

If at any point:

# Source URLs- **No products found**: Return NO_VALID_OPTION with helpful message

grounding_chunks = grounding_metadata.grounding_chunks- **Search fails**: Return NO_VALID_OPTION explaining issue

# Example: [{uri: "https://store.com/product", title: "ASUS Vivobook 15"}]- **All products fail validation**: Return NO_VALID_OPTION

```- **Query out of scope**: Return NO_VALID_OPTION



------



## 🧪 Testing## 🔒 Security & Guardrails



### Local Testing Script### Prohibited Content Detection

System prompt includes explicit guardrails:

```bash- Sexual/erotic content

# Set environment variable- Weapons, explosives, regulated items

export GOOGLE_API_KEY=your-gemini-api-key- Illegal products or services

- Scams or harmful products

# Run test script

python scripts/test_recommendations.py --query "laptop para diseño" --budget 7000**Behavior**: Immediate NO_VALID_OPTION response without product search

```

### Authentication & Authorization

### Unit Tests- All endpoints require Supabase Auth JWT

- `test_format_user_prompt()`: Verify prompt template formatting- User context (profile) fetched using authenticated client

- `test_validate_llm_response()`: Verify response schema validation- RLS enforced on all database queries

- `test_get_user_profile()`: Verify profile fetching with defaults

### Data Privacy

### Integration Tests- No sensitive user data logged

- `test_query_recommendations_success()`: Full flow with mock Gemini response- User queries logged only in aggregate (no PII)

- `test_query_recommendations_no_products()`: NO_VALID_OPTION handling- Product search results not persisted

- `test_query_recommendations_auth_error()`: Authentication failures

- `test_retry_recommendations()`: Retry flow---



---## 💰 Cost Analysis



## 🔄 Migration History### DeepSeek V3.2 Pricing

- **Input (cache miss)**: $0.28 / 1M tokens

### January 2025: Gemini + Google Search Grounding- **Input (cache hit)**: $0.028 / 1M tokens (10x cheaper)

- Migrated from Perplexity Sonar to Gemini 2.5 Flash- **Output**: $0.42 / 1M tokens

- Added Google Search grounding tool for real web data

- Structured output via Pydantic schema (`response_schema`)### Estimated Cost (1M requests/month)

- Single SDK: `google-genai` (shared with InvoiceAgent)Assumptions:

- Average request: 3K input tokens (system + user prompt)

### December 2024: Perplexity Sonar- Average response: 2K output tokens (JSON with 3 products)

- Migrated from DeepSeek V3.2 to Perplexity Sonar- 30% cache hit rate (repeated system prompt)

- Native web grounding for real product data

**Calculation**:

### November 2024: DeepSeek V3.2- Input tokens (cache miss): 1M × 2.1K × $0.28/1M = **$588/mo**

- Initial Prompt Chaining architecture- Input tokens (cache hit): 1M × 0.9K × $0.028/1M = **$25/mo**

- Replaced ADK Orchestrator-Workers pattern- Output tokens: 1M × 2K × $0.42/1M = **$840/mo**

- **Total**: **~$300-400/mo** (vs $1,500/mo with Gemini ADK)

---

**Cost Reduction**: **75% savings**

## 📚 References

---

1. **Google Gemini Documentation**: [ai.google.dev](https://ai.google.dev/)

2. **Google Search Grounding**: [Gemini Grounding Docs](https://ai.google.dev/gemini-api/docs/grounding)## 📊 Performance Metrics

3. **Google Gen AI Python SDK**: [googleapis/python-genai](https://github.com/googleapis/python-genai)

4. **Anthropic Research**: ["Building Effective Agents"](https://www.anthropic.com/research/building-effective-agents)### Target Metrics (vs Old Architecture)



---| Metric | Old (ADK) | New (Prompt Chaining) | Target |

|--------|-----------|----------------------|---------|

**Document Version**: 3.0  | **Response Time** | 4-6 seconds | 1.5-2 seconds | <2s |

**Architecture Version**: Gemini + Google Search Grounding (January 2025)  | **Error Rate** | 5-10% | <0.5% | <1% |

**Previous Versions**: | **503 Errors** | 5% (Gemini overload) | 0% (DeepSeek stable) | 0% |

- v2.0: Perplexity Sonar (December 2024)| **Unknown Tool Calls** | 15-20% | 0% (eliminated) | 0% |

- v1.0: ADK Orchestrator-Workers (Deprecated)| **Query Success Rate** | 70-75% | >95% | >95% |

| **Cost per 1M requests** | ~$1,500 | ~$300 | <$400 |

---

## 🧪 Testing

### Unit Tests
- `test_format_user_prompt()`: Verify prompt template formatting
- `test_validate_llm_response()`: Verify response schema validation
- `test_get_user_profile()`: Verify profile fetching with defaults

### Integration Tests
- `test_query_recommendations_success()`: Full flow with mock DeepSeek response
- `test_query_recommendations_no_products()`: NO_VALID_OPTION handling
- `test_query_recommendations_auth_error()`: Authentication failures
- `test_retry_recommendations()`: Retry flow

### Mock DeepSeek Responses
Use `unittest.mock` to patch `AsyncOpenAI.chat.completions.create()`:
```python
@pytest.mark.asyncio
@patch('backend.services.recommendation_service.deepseek_client')
async def test_query_recommendations_success(mock_client):
    mock_client.chat.completions.create.return_value = MockResponse(
        content='{"status": "OK", "products": [...], "metadata": {...}}'
    )
    # ... test logic
```

---

## 🔄 Migration from ADK Architecture

### Files Deleted (November 2025)
- `backend/agents/recommendation/coordinator.py` (RecommendationCoordinatorAgent)
- `backend/agents/recommendation/search_agent.py` (SearchAgent)
- `backend/agents/recommendation/formatter_agent.py` (FormatterAgent)
- `backend/agents/recommendation/tools.py` (Helper functions)
- `backend/agents/recommendation/schemas.py` (ADK schemas)
- `backend/agents/recommendation/prompts.py` (Old ADK prompts)
- `backend/agents/recommendation/prompts/` (Old directory structure)

### Files Created/Refactored (November 2025)
- `backend/llm/recommendation/prompts.py` - New single file with XML-structured prompts (renamed from `backend/agents/` in 2026)
- `backend/services/recommendation_service.py` - Complete rewrite for Prompt Chaining
- `backend/config.py` - Added DEEPSEEK_API_KEY
- `.env.example` - Added DEEPSEEK_API_KEY placeholder

### Breaking Changes
**None** - API contract unchanged:
- Same endpoints (`/query`, `/retry`)
- Same request models (`RecommendationQueryRequest`, `RecommendationRetryRequest`)
- Same response models (`RecommendationQueryResponseOK`, `RecommendationQueryResponseNoValidOption`)
- `NEEDS_CLARIFICATION` response deprecated but still supported (always returns NO_VALID_OPTION instead)

---

## 📝 Future Enhancements

### Short-Term (Q1 2025)
1. **A/B Testing Framework**: Compare old vs new architecture performance
2. **Caching Layer**: Cache popular queries (e.g., "laptop para diseño gráfico bajo Q7000")
3. **Analytics Dashboard**: Track query success rate, response time, cost per query

### Medium-Term (Q2 2025)
1. **Product Database Integration**: Store indexed products for faster search
2. **User Preference Learning**: Track user selections to improve future recommendations
3. **Multi-Language Support**: Extend beyond Spanish (Guatemala) and English (US)

### Long-Term (Q3-Q4 2025)
1. **Self-Hosting with Qwen 2.5**: Evaluate self-hosting with vLLM for >3M requests/month
2. **Real-Time Price Tracking**: Monitor price changes for wishlist items
3. **Personalized Ranking**: ML-based ranking using user's purchase history

---

## 📚 References

1. **Anthropic Research**: ["Building Effective Agents"](https://www.anthropic.com/research/building-effective-agents)
2. **DeepSeek Pricing**: [api-docs.deepseek.com/quick_start/pricing](https://api-docs.deepseek.com/quick_start/pricing)
3. **DeepSeek Documentation**: [platform.deepseek.com/docs](https://platform.deepseek.com/)
4. **OpenAI API Compatibility**: DeepSeek uses OpenAI-compatible API format
5. **Kashi Finances Review Document**: `RECOMMENDATION-FEATURE-REVIEW.md`

---

## ✅ Conclusion

The migration from ADK Orchestrator-Workers to Prompt Chaining architecture represents a fundamental improvement in:
- **Reliability**: Single point of failure vs cascading agent calls
- **Cost**: 75% reduction ($1,500/mo → $300/mo)
- **Performance**: 3x faster response times (4-6s → 1.5-2s)
- **Maintainability**: Simpler codebase, easier to debug and extend

This architecture is production-ready and aligns with Anthropic's recommendation: **"Start simple, add complexity only when needed."** For a well-defined task like product search, Prompt Chaining is the optimal pattern.

---

**Document Version**: 2.0  
**Architecture Version**: Prompt Chaining (November 2025)  
**Previous Version**: ADK Orchestrator-Workers (Deprecated)

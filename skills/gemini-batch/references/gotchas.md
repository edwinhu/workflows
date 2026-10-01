# Critical Gotchas from Production

## Contents

- [Gotcha 1: GCS Bucket Must Be in us-central1](#gotcha-1-gcs-bucket-must-be-in-us-central1)
- [Gotcha 2: File URIs Must Use gs:// Protocol](#gotcha-2-file-uris-must-use-gs-protocol)
- [Gotcha 3: JSONL Format is Strict](#gotcha-3-jsonl-format-is-strict)
- [Gotcha 4: Request ID Must Be Unique Per Job](#gotcha-4-request-id-must-be-unique-per-job)
- [Gotcha 5: Large PDFs May Timeout or Fail](#gotcha-5-large-pdfs-may-timeout-or-fail)
- [Gotcha 6: API Key vs Service Account Authentication](#gotcha-6-api-key-vs-service-account-authentication)
- [Gotcha 7: Output URI Must Be a Prefix, Not a File](#gotcha-7-output-uri-must-be-a-prefix-not-a-file)
- [Gotcha 8: Rate Limits and Quotas](#gotcha-8-rate-limits-and-quotas)
- [Gotcha 9: JSON Response Parsing Requires Careful Handling](#gotcha-9-json-response-parsing-requires-careful-handling)
- [Gotcha 10: Metadata Must Be Flat Primitives](#gotcha-10-metadata-must-be-flat-primitives)
- [Gotcha 11: `dest` is a config field, not a top-level kwarg (SDK changed)](#gotcha-11-dest-is-a-config-field-not-a-top-level-kwarg-sdk-changed)
- [Gotcha 12: File Search Store — uploadToFileSearchStore 503](#gotcha-12-file-search-store--uploadtofilesearchstore-503)
- [Gotcha 13: SDK Pager auto-pagination is broken for fileSearchStores.documents.list](#gotcha-13-sdk-pager-auto-pagination-is-broken-for-filesearchstoresdocumentslist)
- [Gotcha 14: Store document displayName is random after importFile](#gotcha-14-store-document-displayname-is-random-after-importfile)
- [Gotcha 15: Batch inlinedResponse.response is raw JSON, not hydrated class](#gotcha-15-batch-inlinedresponseresponse-is-raw-json-not-hydrated-class)
- [Gotcha 16: Batch API rejects responseMimeType + tools together](#gotcha-16-batch-api-rejects-responsemimetype--tools-together)
- [Gotcha 17: Gemini 3.x needs a pinned thinking_level — and Pro rejects MINIMAL](#gotcha-17-gemini-3x-needs-a-pinned-thinking_level--and-pro-rejects-minimal)

Production lessons learned from real-world Gemini Batch API deployments.

---

## Gotcha 1: GCS Bucket Must Be in us-central1

**Problem:** Batch API only works with buckets in `us-central1` region.

**Symptom:** Job submission fails with region mismatch error.

**Solution:**
```bash
# Create bucket in correct region
gsutil mb -l us-central1 gs://your-batch-bucket

# Or check existing bucket location
gsutil ls -L -b gs://your-bucket | grep "Location"
```

**Why:** The Batch API service runs in us-central1 and cannot access buckets in other regions efficiently.

---

## Gotcha 2: File URIs Must Use gs:// Protocol

**Problem:** The API expects GCS URIs, not HTTPS URLs.

**Wrong:**
```python
"fileUri": "https://storage.googleapis.com/bucket/file.pdf"
```

**Correct:**
```python
"fileUri": "gs://bucket/file.pdf"
```

**Why:** The batch service accesses files directly through GCS internal APIs, not HTTP.

---

## Gotcha 3: JSONL Format is Strict

**Problem:** Each line must be valid JSON with exact schema.

**Required Schema:**
```json
{
  "request": {
    "contents": [
      {
        "role": "user",
        "parts": [...]
      }
    ]
  },
  "metadata": {
    "request_id": "unique-id"
  }
}
```

**Common Mistakes:**
- Missing `role` field in contents
- Using `content` instead of `contents` (must be plural)
- Trailing commas in JSON
- Empty lines in JSONL file

**Validation:**
```python
def validate_jsonl(path: str) -> bool:
    """Validate JSONL file format."""
    with open(path, 'r') as f:
        for i, line in enumerate(f, 1):
            line = line.strip()
            if not line:
                print(f"Warning: Empty line at {i}")
                continue
            try:
                data = json.loads(line)
                assert "request" in data, "Missing 'request' key"
                assert "contents" in data["request"], "Missing 'contents' in request"
                assert data["request"]["contents"][0].get("role") == "user", "Missing role"
            except (json.JSONDecodeError, AssertionError) as e:
                print(f"Error at line {i}: {e}")
                return False
    return True
```

---

## Gotcha 4: Request ID Must Be Unique Per Job

**Problem:** Duplicate request IDs cause silent overwrites or errors.

**Solution:**
```python
import hashlib

def generate_request_id(file_path: str, prompt_hash: str = None) -> str:
    """Generate deterministic unique request ID.

    Args:
        file_path: Path to source file
        prompt_hash: Optional hash of prompt for versioning

    Returns:
        Unique request ID
    """
    # Use file content hash for deduplication
    with open(file_path, 'rb') as f:
        file_hash = hashlib.md5(f.read()).hexdigest()[:8]

    base_name = Path(file_path).stem

    if prompt_hash:
        return f"{base_name}_{file_hash}_{prompt_hash}"
    return f"{base_name}_{file_hash}"
```

---

## Gotcha 5: Large PDFs May Timeout or Fail

**Problem:** PDFs over ~100 pages or 50MB may fail silently.

**Symptoms:**
- Empty response in results
- `FINISH_REASON_UNSPECIFIED` or `FINISH_REASON_MAX_TOKENS`
- Job succeeds but some entries have errors

**Solutions:**
```python
def split_pdf(input_path: str, max_pages: int = 50) -> list[str]:
    """Split large PDF into smaller chunks.

    Args:
        input_path: Path to input PDF
        max_pages: Maximum pages per chunk

    Returns:
        List of paths to split PDFs
    """
    from pypdf import PdfReader, PdfWriter

    reader = PdfReader(input_path)
    total_pages = len(reader.pages)

    if total_pages <= max_pages:
        return [input_path]

    output_paths = []
    for start in range(0, total_pages, max_pages):
        end = min(start + max_pages, total_pages)
        writer = PdfWriter()

        for page_num in range(start, end):
            writer.add_page(reader.pages[page_num])

        output_path = input_path.replace('.pdf', f'_part{start//max_pages + 1}.pdf')
        with open(output_path, 'wb') as f:
            writer.write(f)
        output_paths.append(output_path)

    return output_paths


def check_pdf_size(path: str, max_mb: int = 50) -> bool:
    """Check if PDF is within size limits."""
    size_mb = Path(path).stat().st_size / (1024 * 1024)
    return size_mb <= max_mb
```

---

## Gotcha 6: API Key vs Application Default Credentials (ADC)

**Problem:** Vertex AI requires ADC authentication, not just API keys.

**Symptom:** `DefaultCredentialsError: Could not automatically determine credentials`

**Two Authentication Modes:**

### Standard Gemini API (API Key)

```python
import google.generativeai as genai

# Simple API key auth
genai.configure(api_key=os.environ["GOOGLE_API_KEY"])

# Works for standard batch API
client = genai.Client(api_key=os.environ["GOOGLE_API_KEY"])
```

### Vertex AI (ADC Required)

```python
import google.generativeai as genai

# CRITICAL: vertexai=True requires ADC, not API key
client = genai.Client(
    vertexai=True,
    project="your-project-id",
    location="us-central1"
)

# API key is IGNORED when vertexai=True
```

**Setup ADC:**

```bash
# Step 1: User login (for gcloud commands)
gcloud auth login

# Step 2: ADC login (for Python libraries)
gcloud auth application-default login

# Step 3: Enable Vertex AI API
gcloud services enable aiplatform.googleapis.com

# Verify ADC location
ls ~/.config/gcloud/application_default_credentials.json
```

**When to Use Each:**

| Feature | API Key | ADC (Vertex AI) |
|---------|---------|-----------------|
| Setup | Simple (just key) | Requires gcloud SDK |
| Use Case | Development, demos | Production, enterprise |
| Regions | us-central1 only | Multiple regions |
| VPC Support | No | Yes |
| Required API | Gemini API | Vertex AI API |
| Cost | Standard | Volume discounts available |

**Common Mistakes:**

```python
# ❌ WRONG: Passing API key with vertexai=True (ignored)
client = genai.Client(
    api_key=os.environ["GOOGLE_API_KEY"],
    vertexai=True  # API key is ignored!
)

# ✓ CORRECT: Use ADC with vertexai=True
client = genai.Client(
    vertexai=True,
    project="your-project-id",
    location="us-central1"
)

# ✓ CORRECT: Use API key without vertexai
client = genai.Client(api_key=os.environ["GOOGLE_API_KEY"])
```

**Service Account (Production Alternative):**

For automated systems without user interaction:

```python
from google.oauth2 import service_account

# Load service account credentials
credentials = service_account.Credentials.from_service_account_file(
    'service-account.json',
    scopes=['https://www.googleapis.com/auth/cloud-platform']
)

# Use with genai library
client = genai.Client(
    vertexai=True,
    project="your-project-id",
    location="us-central1",
    credentials=credentials
)
```

**Service Account Requirements:**
- `roles/storage.objectAdmin` on GCS bucket
- `roles/aiplatform.user` for Vertex AI
- Bucket must have IAM bindings for the service account

**Troubleshooting Auth Errors:**

```bash
# Check if ADC exists
ls ~/.config/gcloud/application_default_credentials.json

# Re-authenticate if missing
gcloud auth application-default login

# Check current project
gcloud config get-value project

# Verify API is enabled
gcloud services list --enabled | grep aiplatform

# If not enabled:
gcloud services enable aiplatform.googleapis.com
```

---

## Gotcha 7: Output URI Must Be a Prefix, Not a File

**Problem:** Output URI is a prefix; the API appends job ID and timestamps.

**Wrong:**
```python
output_uri = "gs://bucket/results/output.jsonl"  # Will fail or create weird paths
```

**Correct:**
```python
output_uri = "gs://bucket/results/"  # Trailing slash recommended
# Results appear at: gs://bucket/results/{job_id}/output.jsonl
```

**Finding Results:**
```python
def find_batch_output(output_prefix: str, job_name: str) -> str:
    """Find the actual output file location.

    Args:
        output_prefix: The URI prefix used when submitting
        job_name: The batch job resource name

    Returns:
        GCS URI to the output JSONL
    """
    # Job name format: batches/{batch_id}
    batch_id = job_name.split('/')[-1]

    client = storage.Client()
    parts = output_prefix.replace("gs://", "").split("/", 1)
    bucket_name = parts[0]
    prefix = parts[1] if len(parts) > 1 else ""

    bucket = client.bucket(bucket_name)

    # Search for output files
    blobs = list(bucket.list_blobs(prefix=prefix))

    for blob in blobs:
        if batch_id in blob.name and blob.name.endswith('.jsonl'):
            return f"gs://{bucket_name}/{blob.name}"

    raise FileNotFoundError(f"No output found for job {job_name}")
```

---

## Gotcha 8: Rate Limits and Quotas

**Problem:** Batch API has separate quotas from synchronous API.

**Limits (as of 2024):**
| Limit Type | Value |
|------------|-------|
| Max requests per JSONL | 10,000 |
| Max concurrent jobs | 10 |
| Max job size | 100MB |
| Job expiration | 24 hours |

**Handling Large Workloads:**
```python
def chunk_requests(requests: list[dict], chunk_size: int = 10000) -> list[list[dict]]:
    """Split requests into chunks for multiple jobs.

    Args:
        requests: All batch requests
        chunk_size: Max requests per job

    Returns:
        List of request chunks
    """
    return [
        requests[i:i + chunk_size]
        for i in range(0, len(requests), chunk_size)
    ]


def submit_chunked_jobs(chunks: list[list[dict]], bucket: str) -> list[str]:
    """Submit multiple batch jobs for large workloads.

    Args:
        chunks: List of request chunks
        bucket: GCS bucket name

    Returns:
        List of job names
    """
    job_names = []

    for i, chunk in enumerate(chunks):
        # Write chunk to JSONL
        jsonl_path = f"/tmp/batch_chunk_{i}.jsonl"
        write_jsonl(chunk, jsonl_path)

        # Upload and submit
        input_uri = upload_to_gcs(jsonl_path, bucket, f"requests/chunk_{i}.jsonl")
        output_uri = f"gs://{bucket}/outputs/chunk_{i}/"

        job = submit_batch_job(input_uri, output_uri)
        job_names.append(job.name)

        print(f"Submitted chunk {i+1}/{len(chunks)}: {job.name}")

    return job_names
```

---

## Gotcha 9: JSON Response Parsing Requires Careful Handling

**Problem:** Even with `responseMimeType: "application/json"`, responses may not be valid JSON.

**Common Issues:**
- Markdown code fences around JSON: ` ```json ... ``` `
- Truncated responses for large outputs
- Model adds explanatory text before/after JSON

**Robust Parsing:**
```python
import re

def extract_json_from_response(text: str) -> dict | None:
    """Extract JSON from potentially messy response text.

    Args:
        text: Raw response text from model

    Returns:
        Parsed JSON dict, or None if extraction fails
    """
    if not text:
        return None

    # Try direct parse first
    try:
        return json.loads(text)
    except json.JSONDecodeError:
        pass

    # Remove markdown code fences
    patterns = [
        r'```json\s*(.*?)\s*```',  # ```json ... ```
        r'```\s*(.*?)\s*```',       # ``` ... ```
        r'`(.*?)`',                  # inline code
    ]

    for pattern in patterns:
        match = re.search(pattern, text, re.DOTALL)
        if match:
            try:
                return json.loads(match.group(1))
            except json.JSONDecodeError:
                continue

    # Try to find JSON object boundaries
    start = text.find('{')
    end = text.rfind('}')

    if start != -1 and end != -1 and end > start:
        try:
            return json.loads(text[start:end + 1])
        except json.JSONDecodeError:
            pass

    # Try JSON array
    start = text.find('[')
    end = text.rfind(']')

    if start != -1 and end != -1 and end > start:
        try:
            return json.loads(text[start:end + 1])
        except json.JSONDecodeError:
            pass

    return None


def parse_batch_results_robust(jsonl_path: str) -> list[dict]:
    """Parse batch results with robust JSON extraction.

    Args:
        jsonl_path: Path to result JSONL file

    Returns:
        List of results with parsed JSON where possible
    """
    results = []

    with open(jsonl_path, 'r') as f:
        for line_num, line in enumerate(f, 1):
            try:
                entry = json.loads(line)
                request_id = entry.get("metadata", {}).get("request_id")

                response = entry.get("response", {})
                candidates = response.get("candidates", [])

                if candidates:
                    text = candidates[0].get("content", {}).get("parts", [{}])[0].get("text", "")
                    parsed_json = extract_json_from_response(text)

                    results.append({
                        "request_id": request_id,
                        "raw_response": text,
                        "parsed_json": parsed_json,
                        "parse_success": parsed_json is not None,
                        "finish_reason": candidates[0].get("finishReason")
                    })
                else:
                    results.append({
                        "request_id": request_id,
                        "error": response.get("error"),
                        "raw_response": None,
                        "parsed_json": None,
                        "parse_success": False
                    })

            except json.JSONDecodeError as e:
                print(f"Failed to parse line {line_num}: {e}")
                results.append({
                    "line_number": line_num,
                    "error": str(e),
                    "parse_success": False
                })

    return results
```

---

## Gotcha 10: Metadata Must Be Flat Primitives

**Problem:** Vertex AI Batch API only accepts primitive types (STRING, INTEGER, FLOAT, BOOLEAN, TIMESTAMP, DATE, DATETIME, NUMERIC) for metadata values. Nested objects or arrays cause job failures.

**Symptom:** Job fails with error:
```
The column or property "metadata" in the specified input data is of unsupported type.
Supported types for this column are: [STRING, INTEGER, FLOAT, BOOLEAN, TIMESTAMP, DATE, DATETIME, NUMERIC].
```

**Wrong:**
```python
# ❌ Nested object - NOT SUPPORTED
{
    "request": {...},
    "metadata": {
        "request_id": "icon_123",
        "file_info": {              # This breaks!
            "name": "copy.svg",
            "size": 1024
        }
    }
}
```

**Correct Option 1: Flatten**
```python
# ✓ Flat structure with primitives only
{
    "request": {...},
    "metadata": {
        "request_id": "icon_123",
        "file_name": "copy.svg",
        "file_size": 1024
    }
}
```

**Correct Option 2: Serialize to JSON String**
```python
# ✓ Complex data as JSON string
import json

{
    "request": {...},
    "metadata": {
        "request_id": "icon_123",
        "file_info": json.dumps({"name": "copy.svg", "size": 1024})  # String!
    }
}
```

**When to Use Each:**
- **Flatten**: When you need to filter/query by metadata fields
- **Serialize**: When you just need to preserve context for result processing

**Why:** Vertex AI stores metadata in BigQuery-compatible format, which doesn't support nested types.

**Validation:**
```python
def validate_metadata(metadata: dict) -> bool:
    """Check metadata contains only primitive types."""
    for key, value in metadata.items():
        if isinstance(value, (dict, list)):
            raise ValueError(
                f"Metadata value for '{key}' is {type(value).__name__}. "
                f"Only primitives (str, int, float, bool) are allowed. "
                f"Use json.dumps() to serialize complex data."
            )
        if not isinstance(value, (str, int, float, bool, type(None))):
            raise ValueError(f"Unsupported metadata type for '{key}': {type(value)}")
    return True
```

---

## Gotcha 11: `dest` is a config field, not a top-level kwarg (SDK changed)

**Problem:** The Batch API output location is `dest`, and in the **current**
google-genai SDK it lives inside the `config` dict — NOT as a top-level
keyword argument. Older SDK versions accepted `dest=` as a kwarg; the
current signature does not. Old code (and old docs/examples) crash with
`TypeError: Batches.create() got an unexpected keyword argument 'dest'`.

**Verify your SDK first:**
```python
import inspect
from google import genai
client = genai.Client(vertexai=True, project="...", location="us-central1")
print(inspect.signature(client.batches.create))
# Current SDK: (*, model, src, config)
# Older SDK:   (*, model, src, dest, config)
```

**Symptoms:**
- `TypeError: Batches.create() got an unexpected keyword argument 'dest'` (current SDK, kwarg form)
- `TypeError: ... unexpected keyword argument 'destination'` (always — that name never existed)

**Wrong Attempts:**
```python
# ❌ WRONG: destination= never existed
job = client.batches.create(
    model="gemini-2.5-flash-lite",
    src="gs://bucket/input.jsonl",
    destination="gs://bucket/output/",
)

# ❌ WRONG on current SDK: kwarg form (worked on older SDK)
job = client.batches.create(
    model="gemini-2.5-flash-lite",
    src="gs://bucket/input.jsonl",
    dest="gs://bucket/output/",       # TypeError on current SDK
    config={"display_name": "my-job"},
)

# ❌ WRONG: instantiating the wrapper type manually
from google.genai import types
job = client.batches.create(
    model="gemini-2.5-flash-lite",
    src="gs://bucket/input.jsonl",
    config=types.CreateBatchJobConfig(dest="gs://bucket/output/"),
)
```

**Correct (current SDK):**
```python
# ✓ CORRECT: dest inside the config dict
job = client.batches.create(
    model="gemini-2.5-flash-lite",
    src="gs://bucket/input.jsonl",
    config={
        "display_name": "my-job",
        "dest": "gs://bucket/output/",
    },
)
```

**Field reference:**
`CreateBatchJobConfig` fields = `http_options, display_name, dest, webhook_config`.
Always pass as a plain dict; the SDK converts it internally.

**Key Points:**
1. **`dest` is a config field** in the current SDK (was a kwarg historically)
2. **`destination` does not exist** — it never did
3. **Pass `config` as a plain dict** (not the wrapper class)
4. **Run `inspect.signature` first** if you suspect SDK drift

**Examples from Skill:**
- Standard API: `examples/batch_processor.py`
- Vertex AI: `examples/icon_batch_vision.py`

Both pass `dest` via `config={"dest": "gs://..."}`.

---

## Gotcha 12: File Search Store — uploadToFileSearchStore 503

`client.fileSearchStores.uploadToFileSearchStore()` returns 503 for files >10KB. This is a known API bug (as of April 2026).

**Fix:** Two-step upload:
1. `client.files.upload({file: path, config: {displayName: name}})` — upload to File Service
2. Poll `client.files.get({name})` until `state === "ACTIVE"` (not PROCESSING)
3. `client.fileSearchStores.importFile({fileSearchStoreName, fileName, config: {customMetadata}})` — import into store
4. Poll the import operation until `done`

**Gotcha within the gotcha:** `importFile` does NOT propagate the File's `displayName` to the store document. The store document gets a random ID as displayName. If you need to identify documents by name, use `customMetadata` (see Gotcha 14).

```typescript
// WRONG — 503 for files >10KB
await client.fileSearchStores.uploadToFileSearchStore({
  file: path,
  fileSearchStoreName: storeName,
  config: { displayName: bibkey }
});

// RIGHT — two-step upload
const file = await client.files.upload({ file: path, config: { displayName: bibkey } });
// Poll until ACTIVE
while (file.state === "PROCESSING") {
  await sleep(3000);
  file = await client.files.get({ name: file.name });
}
await client.fileSearchStores.importFile({
  fileSearchStoreName: storeName,
  fileName: file.name,
  config: { customMetadata: [{ key: "bibkey", stringValue: bibkey }] }
});
```

---

## Gotcha 13: SDK Pager auto-pagination is broken for fileSearchStores.documents.list

`for await (const doc of pager)` stops after the first page (~10-20 docs). The async iterator's auto-pagination does not work reliably for this endpoint.

**Fix:** Use the SDK's manual pagination methods:

```typescript
// WRONG — stops after first page
const pager = await client.fileSearchStores.documents.list({ parent: storeName });
for await (const doc of pager) { docs.push(doc); } // only gets ~10 docs!

// ALSO WRONG — pager.params is INPUT config, not response token
pageToken = (pager.params as any)?.pageToken; // always undefined!

// RIGHT — use hasNextPage() + nextPage()
const pager = await client.fileSearchStores.documents.list({
  parent: storeName,
  config: { pageSize: 20 },
});
let page = pager.page;
while (true) {
  for (const doc of page) { docs.push(doc); }
  if (!pager.hasNextPage()) break;
  page = await pager.nextPage();
}
```

---

## Gotcha 14: Store document displayName is random after importFile

When using the two-step upload (Gotcha 12), `importFile` generates a random string as the store document's `displayName` (e.g., "d98ctytgehwv"). The File's `displayName` is NOT propagated.

**Fix:** Store identifying metadata in `customMetadata` during import, and read it back during list:

```typescript
// During upload — set customMetadata
await client.fileSearchStores.importFile({
  fileSearchStoreName: storeName,
  fileName: file.name,
  config: {
    customMetadata: [{ key: "bibkey", stringValue: "Author2024-ab" }]
  }
});

// During list — extract bibkey from customMetadata, not displayName
const bibkey = doc.customMetadata?.find(m => m.key === "bibkey")?.stringValue
  ?? doc.displayName; // fallback for legacy docs
```

---

## Gotcha 15: Batch inlinedResponse.response is raw JSON, not hydrated class

When using `batches.create()` with inline requests and polling with `batches.get()`, the `inlinedResponse.response` object is raw JSON — NOT a hydrated `GenerateContentResponse` class instance. The `.text` getter does not exist on raw JSON.

**Fix:** Extract text from the candidates array directly:

```typescript
// WRONG — .text getter doesn't exist on raw JSON objects
const text = inlineResponse.response?.text; // undefined!

// RIGHT — extract from candidates array
function extractResponseText(response: any): string {
  if (!response) return "";
  if (typeof response.text === "string") return response.text; // class instance
  const parts = response.candidates?.[0]?.content?.parts;
  if (Array.isArray(parts)) {
    return parts.filter(p => typeof p.text === "string").map(p => p.text).join("");
  }
  return "";
}
```

This handles both sequential mode (hydrated class with `.text` getter) and batch mode (raw JSON with candidates array).

---

## Gotcha 16: Batch API rejects responseMimeType + tools together

When a batch inline request includes both `responseMimeType: "application/json"` (or `responseSchema`) AND `tools` (like `fileSearch`, `google_search`), every individual response returns error code 3:

> "Tool use with a response mime type: 'application/json' is unsupported"

The batch job itself reports JOB_STATE_SUCCEEDED, but every `inlinedResponse` has `error` set.

**Fix:** When using tools in batch, omit `responseMimeType` and `responseSchema`. Use prompt-based JSON instructions:

```typescript
// WRONG -- error code 3 for every response
config: {
  tools: [{ fileSearch: { fileSearchStoreNames: [store] } }],
  responseMimeType: "application/json",  // INCOMPATIBLE with tools in batch
  responseSchema: { ... },
}

// RIGHT -- prompt instructs JSON format
contents: [{
  parts: [{
    text: prompt + '\n\nRespond with ONLY a JSON object: {"status": "SUPPORTED", ...}'
  }],
  role: "user",
}],
config: {
  tools: [{ fileSearch: { fileSearchStoreNames: [store] } }],
  // NO responseMimeType, NO responseSchema
}
```

Add a heuristic fallback parser to extract classification from free-text responses when the model doesn't return pure JSON.

**This does NOT affect sequential mode** -- `generateContent` supports tools + structured output together.

---

## Gotcha 17: Gemini 3.x needs a pinned thinking_level — and Pro rejects MINIMAL

Gemini 3.x models default to a high thinking level. In batch this fails **silently**: the job reports JOB_STATE_SUCCEEDED, but individual responses come back with `finishReason: MAX_TOKENS` and empty content — the model spent the whole budget thinking and emitted nothing. Always pin `thinkingConfig.thinkingLevel` in `generationConfig`.

The refinement (verified 2026-08-03): **the levels are not uniform across tiers.** Pro rejects `MINIMAL` outright:

> Thinking level MINIMAL is not supported for this model

Flash and Flash-Lite accept `MINIMAL`; Pro needs at least `LOW`. A single hardcoded constant therefore breaks the moment you switch tiers — which you will do, since tier comparison is a normal part of Stage 2 (see `scale-up-testing.md`). Pick the level per model:

```python
def thinking_level_for(model: str) -> str:
    """Lowest thinking level the model accepts. Pro rejects MINIMAL."""
    return "LOW" if "pro" in model else "MINIMAL"

generation_config = {
    "thinkingConfig": {"thinkingLevel": thinking_level_for(model)},
    ...
}
```

Verify the accepted levels against the live model docs before pinning a new model — this is exactly the kind of detail that shifts between releases.

---

## Gotcha 18: A `genai.Client()` created inline is garbage-collected mid-request

Constructing the client as a temporary — inside the call, or in a helper that returns a fresh one every time — lets Python collect it while its HTTP request is still in flight:

```
RuntimeError: Cannot send a request, as the client has been closed.
```

The traceback bottoms out in `httpx/_client.py send()`, so it reads like a network or SDK bug. It is neither: the `Client` owns an `httpx` connection pool and closes it on `__del__`.

Both of these fail, and the second is the trap — it *looks* like a clean factory:

```python
# BAD — temporary, collected while the request is in flight
print(genai.Client().batches.get(name=job).state)

# BAD — a new client per call, same lifetime problem
def client():
    return genai.Client(vertexai=True, project=P, location=L)
client().batches.create(...)
```

Hold the reference for the life of the process:

```python
_CLIENT = None

def client():
    global _CLIENT
    if _CLIENT is None:
        _CLIENT = genai.Client(vertexai=True, project=P, location=L)
    return _CLIENT
```

This bites hardest in **polling loops** (`while true; do python3 -c "...genai.Client().batches.get..."`), where every iteration builds and drops a client. Verified 2026-08-30 on `google-genai` 2.20.0; it killed a batch monitor and then the submit itself.

---

## Gotcha 19: Vertex batch needs the fully-qualified publisher model path

`batches.create(model="gemini-2.5-flash-lite", ...)` on a Vertex client returns:

```json
{"error": {"code": 404, "message": "The PublisherModel gemini-2.5-flash-lite does not exist.", "status": "NOT_FOUND"}}
```

The bare id works for `generate_content` but **not** for batch. Qualify it:

```python
model = m if m.startswith("publishers/") else f"publishers/google/models/{m}"
job = client.batches.create(model=model, src=src, config={"dest": dest})
```

The Standard API takes the bare id, so a script ported from that path hits this immediately.

---

## Gotcha 20: `models.list()` lists models Vertex batch will NOT serve in that region

This is the dangerous one, because the obvious diagnostic lies to you.

Chasing the Gotcha 19 404, the natural check is "is the model actually available here?" — and `models.list()` on a `us-central1` Vertex client **does** return `gemini-3.5-flash-lite`. Qualifying the path (Gotcha 19) still 404s with the identical message:

```
404 NOT_FOUND. The PublisherModel gemini-3.5-flash-lite does not exist.
```

The model is listed in the region and is not batch-servable there. Gemini **3.x is `location: "global"`**, while the 2.5 tier serves batch from `us-central1` — but batch also wants its GCS bucket in `us-central1`, so the two constraints pull apart and the error message never mentions region at all.

**`models.list()` membership is not a batch-availability check.** The only reliable test is submitting a job — and it takes about twenty seconds, so run it rather than reasoning about it.

**The fix is the location, NOT a model downgrade.** Verified 2026-08-30 by submitting the same JSONL four ways:

```
global       gemini-3.5-flash-lite    ACCEPTED
global       gemini-2.5-flash-lite    ACCEPTED
us-central1  gemini-3.5-flash-lite    REJECTED (404)
us-central1  gemini-2.5-flash-lite    ACCEPTED
```

A `location="global"` client accepts a `us-central1` `src` **and** `dest`, so the bucket does not move and the two constraints never actually conflict:

```python
loc = "global" if model_id.startswith("gemini-3") else "us-central1"
client = genai.Client(vertexai=True, project=P, location=loc)
```

**Do not respond to this 404 by dropping a tier.** That is the trap: the 404 names the model, so a downgrade looks like the fix and the job then runs — with a weaker model you never evaluated. In the incident that produced this note, dropping 3.5-flash-lite → 2.5-flash-lite silently changed the *output*: on a document citing an out-of-enum statute, 3.5 correctly returned the schema's `other`, while 2.5 coerced it to a plausible in-enum value the document never cited. The batch still "succeeded". Swapping a model mid-pipeline invalidates every prompt eval you ran before the swap — re-validate, or fix the location instead.

And pair this with Gotcha 17 in the other direction: 2.5 has thinking off by default and **rejects** `thinkingConfig`, which 3.x requires. So switching tiers to dodge this 404 also means making `thinkingConfig` conditional:

```python
cfg = {"response_mime_type": "application/json"}
if model_id.startswith("gemini-3"):
    cfg["thinking_config"] = {"thinking_level": thinking_level_for(model_id)}
```

Verified 2026-08-30, us-central1, `google-genai` 2.20.0: four consecutive submit failures — client GC, bare model id, listed-but-unservable 3.5-flash-lite, then a thinking-config mismatch — before a job reached `JOB_STATE_PENDING`.

---

## Gotcha 21: Gemini 3.x: never set temperature/top_p/top_k

For all Gemini 3 models, Google strongly recommends keeping the `temperature` parameter at its default value of `1.0`. Setting it below 1.0 (such as `0.0` for structured extraction) may lead to unexpected behavior, such as looping or degraded performance.

If you are migrating from Gemini 2.x or 1.5, **remove any explicit low temperature**. The same applies to `top_p` and `top_k`.

```python
# ❌ WRONG for Gemini 3.x
cfg = {"response_mime_type": "application/json", "temperature": 0.0}

# ✓ CORRECT for Gemini 3.x
cfg = {"response_mime_type": "application/json"}
```

---

## Gotcha 22: Batch search grounding requires markdown/text output, not JSON

When using the `googleSearch` tool in a batch request, demanding JSON-only output (`response_mime_type: "application/json"`) causes the model to **silently skip searching**.

In a measured test (Gemini 3.8 Flash, Standard-API batch, 2026-09-30):
- A prompt demanding JSON-only output produced 0 of 138 grounded rows.
- The same prompt asking for labelled MARKDOWN output grounded 92 of 138.
- This held regardless of temperature, metadata presence, or thinking level.

Enabling the tool does not force a search. If you need search grounding in batch, ask for labelled plain-text or markdown and parse it yourself. Always check `groundingMetadata` per row.

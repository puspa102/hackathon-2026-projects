# 🏥 AI Healthcare Innovation Hackathon — Participant Resources

> **Organized by [CareDevi](https://caredevi.com) in partnership with [Gazuntite](https://www.gazuntite.com/)**· Connecting Users, Empowering Clinicians

---

## 📋 Event Overview

| Detail | Info |
|---|---|
| **Event** | AI Healthcare Innovation Hackathon 2026 |
| **Dates** | April 25–26, 2026 (Saturday 8 AM – Sunday 8 PM CT) |

### 🏆 Prizes

| Award | Prize |
|---|---|
| 🥇 1st Place | $1,000 |
| 🤖 Best AI Solution | $500 |
| 🔗 Best Integration | $500 |

### 🛤️ Hackathon Tracks

Choose one track and build something that matters:

1. **AI Patient Triage** — Intelligent symptom analysis and patient routing
2. **Health Data & Interoperability** — Breaking down data silos in healthcare
3. **Population Health Intelligence** — Data-driven community health insights
4. **AI-Powered Care Coordination** — Seamless multi-provider collaboration

---

## 🚀 Getting Started

### 📖 Participant Guide

Full participant guide, submission instructions, judging criteria, and logistics:
👉 **[Participant Guide](https://caredevi-events.slack.com/files/U0AR8EX5X2Q/F0AUP8U21N3/particpant-guide.pdf)**

### 💬 Slack Channels

Join the CareDevi Events Slack workspace and use the appropriate channels including but not limited to:

**#announcements**\
**#hackathon-resources**\
**#hackathon-help-support**\
**#hackathon-ask-a-mentor**\
**#hackathon-demo-day**

---

## 🤖 Using AI/LLM for Code Generation & Implementing AI Solutions

We strongly encourage all participants to take advantage of AI-powered coding tools to maximize productivity and build more ambitious solutions during the 36-hour sprint. Work smarter, not just harder.

### ✅ Recommended AI Coding Assistants

Use whichever tools you're most comfortable with:

- **[GitHub Copilot](https://github.com/features/copilot)** — AI pair programmer integrated directly into VS Code, JetBrains, and other IDEs
- **[Claude Code](https://claude.ai/code)** — Anthropic's agentic coding tool; excellent for architecture, refactoring, and complex logic
- **Any other tool you prefer** — Cursor, Codeium, Tabnine, etc. Use what makes you most productive.

### 🤗 Hugging Face — Open-Source Models for Code Generation & AI Solutions

[Hugging Face](https://huggingface.co) is the go-to hub for finding, evaluating, and deploying open-source AI/ML models — including powerful code generation models perfect for this hackathon.

**Why Hugging Face?**
- Browse thousands of models across tasks: code generation, NLP, classification, summarization, and more
- Each model has a **Model Card** that explains what the model does, its intended use, limitations, and how to implement it in popular languages (Python, JavaScript, etc.)
- **Inference Providers** on the model card page show you which cloud backends support running the model via API (e.g., Hugging Face Inference API, Together AI, Replicate, etc.) — making it easy to get started without managing GPU infrastructure
- You can call most models using a simple REST API or via popular SDKs

> 💡 **Pro Tip for Teams:** One team member can create the Hugging Face account and share the API token securely with the team. **Never commit API tokens to your Git repository.** Use environment variables or a `.env` file that is listed in your `.gitignore`.

---

### 🛠️ Step-by-Step: Setting Up Hugging Face + VS Code Continue Plugin

The [Continue](https://www.continue.dev/) plugin for VS Code gives you an AI chat and code completion assistant directly in your editor. Here's how to set it up with a powerful open-source coding model from Hugging Face.

#### Step 1 — Create a Hugging Face Account

1. Go to [https://huggingface.co](https://huggingface.co)
2. Click **Sign Up** (top right)
3. Enter your email address and create a password
4. Verify your email address

#### Step 2 — Generate an API Key (Access Token)

1. Log in to Hugging Face
2. Click your **profile avatar** (top right) → **Settings**
3. In the left sidebar, click **Access Tokens**
4. Click **New token**
5. Give it a name (e.g., `hackathon-token`), select **Read** role (sufficient for inference)
6. Click **Generate a token** and copy the token value immediately — you won't be able to see it again
7. Store it somewhere safe (e.g., a `.env` file in your project that is **not** committed to Git)

```bash
# .env file (add this file to .gitignore!)
HF_API_KEY=hf_your-api-key-here
```

#### Step 3 — Install the Continue Plugin in VS Code

1. Open VS Code
2. Go to the **Extensions** panel (`Ctrl+Shift+X` / `Cmd+Shift+X`)
3. Search for **"Continue"** and install the [extension](https://marketplace.visualstudio.com/items?itemName=Continue.continue) by `Continue Dev`
4. Once installed, you'll see the Continue icon in your left sidebar

#### Step 4 — Configure Continue with a Hugging Face Model

Continue uses a `config.yaml` file for configuration. Here's how to set it up using **Qwen/Qwen2.5-Coder-32B-Instruct** as an example — a highly capable open-source code generation model.

1. Open the Continue panel in VS Code and click the **gear/settings icon** to open your config file, or navigate directly to `~/.continue/config.yaml`
2. Add the following configuration:

```yaml
name: Local Config
version: 1.0.0
schema: v1
models:
  - name: "Qwen Hugging Face Model"
    provider: "openai"
    model: "Qwen/Qwen2.5-Coder-32B-Instruct"
    apiBase: "https://router.huggingface.co/v1"
    apiKey: "hf_your-api-key-here"
```

> Replace `hf_your-api-key-here` with your actual token. Consider using an environment variable reference if your Continue version supports it.

3. Save the file — Continue will automatically reload
4. Open the Continue chat panel and start chatting with the model or use inline code completion!

#### Step 5 — Try It Out

Once configured, you can:
- **Chat**: Ask the model to write functions, explain code, suggest architectures
- **Inline autocomplete**: Start typing and accept suggestions with `Tab`
- **Agent mode**: Ask Continue to make multi-file edits across your codebase

#### Other Recommended Models on Hugging Face

Visit each model's page on Hugging Face for its Model Card and Inference Provider details:

| Model | Best For |
|---|---|
| `Qwen/Qwen2.5-Coder-32B-Instruct` | General-purpose code generation |
| `deepseek-ai/DeepSeek-Coder-V2-Instruct` | Complex reasoning and code |
| `microsoft/BiomedNLP-BiomedBERT-base-uncased-abstract` | Biomedical NLP tasks |
| `aaditya/Llama3-OpenBioLLM-70B` | Healthcare/clinical text tasks |
| `johnsnowlabs/JSL-MedS-NER-q16_v2` | Medical named entity recognition |

---

## 📐 Health Data Standards & Frameworks

### HL7 FHIR (Fast Healthcare Interoperability Resources)

**FHIR** is the modern, globally adopted standard for exchanging healthcare data. It defines a set of **"resources"** — structured data objects representing clinical and administrative concepts like Patient, Observation, Medication, Encounter, DiagnosticReport, and more. Resources are accessed and exchanged via standard RESTful APIs using JSON or XML.

**Why it matters for this hackathon:**
- FHIR is how modern healthcare systems expose and share patient data
- Cloud platforms (AWS HealthLake, Azure Health Data Services, Google Cloud Healthcare API) all support FHIR R4/R5
- You can spin up a FHIR server in under an hour and start querying synthetic patient data almost immediately
- AI systems increasingly use FHIR as the preferred structured format for ingesting clinical data into LLMs and analytics pipelines

**Core FHIR Concepts:**
- **Resources**: Building blocks of FHIR data (145+ in R4, 157+ in R5). Common ones: `Patient`, `Observation`, `Condition`, `MedicationRequest`, `Encounter`, `DiagnosticReport`, `AllergyIntolerance`, `CarePlan`
- **RESTful API**: Standard HTTP verbs — `GET`, `POST`, `PUT`, `DELETE` — to read and write resources
- **Bundles**: A collection of multiple FHIR resources returned together in a single API response
- **Search Parameters**: Each resource type has defined search parameters (e.g., `/Observation?patient=123&code=55284-4`)
- **Implementation Guides (IGs)**: Community-defined profiles that constrain FHIR for specific use cases (e.g., US Core, USCDI)

**Key references:**
- Official FHIR specification: [https://hl7.org/fhir/](https://hl7.org/fhir/)
- FHIR R4 resource list: [https://hl7.org/fhir/R4/resourcelist.html](https://hl7.org/fhir/R4/resourcelist.html)
- HAPI FHIR (popular open-source FHIR server): [https://hapifhir.io](https://hapifhir.io)
- Medplum (developer-friendly FHIR platform): [https://www.medplum.com](https://www.medplum.com)

### SMART on FHIR

**SMART on FHIR** is the authorization and launch framework built on top of FHIR. It uses **OAuth2 and OpenID Connect** to allow apps to securely request access to patient data from a FHIR server with the patient's (or clinician's) consent. It's the standard way healthcare apps authenticate and authorize access to EHR data.

- SMART on FHIR v2 is the current standard (as of 2026)
- Supports both patient-facing and clinician-facing app launches
- Reference: [https://docs.smarthealthit.org](https://docs.smarthealthit.org)

---

### 📗 Recommended eBook: *FHIR Architecture Decisions* by Darren Devitt

This free eBook is **highly recommended reading** before and during the hackathon. It provides practical, unbiased guidance on how to design FHIR-based systems — covering decisions that directly affect hackathon implementations.

**👉 Download: [FHIR Architecture Decisions (PDF)](https://darrendevitt.com/wp-content/uploads/2026/04/FHIR-Architecture-Decisions.pdf)**

#### Key Topics from the Book Relevant to Your Hackathon Project:

**1. The Role of the FHIR Server**
Understand what a FHIR server actually does (and doesn't do). Critical for avoiding the "platform illusion trap" where teams over-rely on the server to handle things it was never designed for.

**2. Three Architectural Models — Which One Should You Build?**
- **Facade Model**: A translation layer that maps your existing data to FHIR on the fly. Fast to build, good for read-only demos and regulatory scenarios.
- **Hybrid Model**: Syncs data from source systems into a FHIR server. Strong performance, no changes needed to existing systems. Best for most hackathon use cases that need a functioning API.
- **FHIR-Native Model**: The FHIR server is the source of truth. Ideal for greenfield projects with no legacy data dependencies — common in hackathon contexts.

**3. Clarifying Your Requirements (9 Key Questions)**
The book walks through 9 questions every team should answer before building: Why are you using FHIR? Who owns the data? Who are your consumers? What are your deal-breakers? Answering these early prevents costly architectural mistakes.

**4. Facade Model in Practice**
Practical guidance on building read-only and read/write FHIR facades. Useful if your team wants a quick working demo without a full FHIR server.

**5. Hybrid Model in Practice**
How to sync data from source systems to a FHIR server using CDC, event-driven pipelines, or batch jobs. Relevant if you're connecting to simulated EHR data (e.g., Synthea datasets).

**6. FHIR-Native Model in Practice**
Design patterns for greenfield healthcare apps. Highly applicable to hackathon AI solutions that generate their own clinical data (triage outputs, care plans, population health scores).

**7. Selecting the Right FHIR Architecture**
A decision matrix mapping your project requirements to the right model. Use this to make a fast, confident architecture decision on day one of the hackathon.

**8. Choosing a FHIR Server**
Overview of managed (Azure, AWS, Google), enterprise (Smile Digital Health, Firely), and open-source (HAPI, Medplum) servers. For the hackathon, **Medplum** and **HAPI FHIR** are recommended as quick-start options.

**9. Components Beyond the Server (Appendix I)**
A practical checklist of what you need to build *around* your FHIR server: API gateways, data mapping layers, terminology services, audit logging, de-identification, and more. Use this to scope your hackathon project realistically.

**10. FHIR Server Vendor Landscape (Appendix II)**
A comprehensive list of FHIR server vendors by category (managed cloud, enterprise, open-source). Useful for quickly identifying which server fits your time and budget constraints.

---

## 🏷️ Healthcare Data & Terminologies

Understanding healthcare terminologies helps your AI models interpret clinical data correctly. Here's a quick, practical guide:

### The Quick Reference

| Terminology | Use It For | Example |
|---|---|---|
| **SNOMED CT** | Clinical conditions, diagnoses, procedures, findings | "Use SNOMED for conditions" — e.g., `73211009` = Diabetes mellitus |
| **LOINC** | Lab results, vital signs, clinical observations | "Use LOINC for labs" — e.g., `2339-0` = Blood Glucose, `8867-4` = Heart Rate |
| **ICD-10-CM** | Diagnosis billing codes, administrative/claims data | "Use ICD-10 for billing diagnoses" — e.g., `E11.9` = Type 2 diabetes without complications |
| **RxNorm** | Medications, drug names, dosing | "Use RxNorm for drugs" — e.g., `1049502` = Metformin 500mg |
| **CPT** | Medical procedures and services (billing) | "Use CPT for procedures" — e.g., `99213` = Office/outpatient visit |
| **NDC** | Drug product identification (National Drug Codes) | "Use NDC for drug products" — e.g., specific pill manufacturer codes |

### Practical Tips for Hackathon Teams

- **FHIR uses these terminologies natively.** In FHIR resources, codes are expressed as `system + code + display` (e.g., `"system": "http://loinc.org", "code": "2339-0", "display": "Glucose [Mass/volume] in Blood"`)
- **Don't memorize codes.** Use [https://clinicaltables.nlm.nih.gov](https://clinicaltables.nlm.nih.gov) or [https://loinc.org/search](https://loinc.org/search) to look up codes dynamically
- **SNOMED browser**: [https://browser.ihtsdotools.org](https://browser.ihtsdotools.org)
- **RxNorm browser**: [https://mor.nlm.nih.gov/RxNav/](https://mor.nlm.nih.gov/RxNav/)
- **For AI/NLP tasks**, these terminologies are your ground truth for normalizing extracted clinical entities — if your model extracts "diabetes," map it to SNOMED `73211009` for interoperability

---

## 🔒 Privacy, Security & Responsible AI

Healthcare data is sensitive. Even in a hackathon setting with synthetic data, building with privacy and security in mind is essential — and will be part of how judges evaluate your solution.

### HIPAA Basics

**HIPAA (Health Insurance Portability and Accountability Act)** is the US federal law governing the privacy and security of Protected Health Information (PHI).

Key concepts to know:
- **PHI** includes: names, dates, geographic identifiers, phone numbers, email addresses, SSNs, medical record numbers, health plan numbers, biometric identifiers, and full-face photos
- **The Privacy Rule** limits who can use and disclose PHI
- **The Security Rule** requires technical, physical, and administrative safeguards for electronic PHI (ePHI)
- **Minimum Necessary Principle**: Only access or use the minimum amount of PHI needed for the task

> ⚠️ For this hackathon, **do not use real patient data.** Use synthetic datasets only (see Synthea below).

### De-Identification Tips

If you're working with any data that might contain patient information:

- **Safe Harbor method**: Remove all 18 types of PHI identifiers (names, dates except year, geographic data smaller than state, etc.)
- **Expert Determination method**: Statistical/scientific methods to ensure re-identification risk is very small
- **Practical hackathon approach**: Use Synthea-generated data from the start — it's already de-identified by design
- Never log or display patient identifiers in your app's UI, console, or debug output
- Don't store sensitive data in browser `localStorage` or unencrypted flat files

### Safe AI Usage

- **Add disclaimers**: Any AI output that could influence clinical decisions must include a disclaimer (e.g., *"This tool is for informational purposes only and is not a substitute for professional medical advice."*)
- **No clinical claims**: Do not present your hackathon prototype as a certified medical device or claim diagnostic accuracy without validation
- **Hallucination risk**: LLMs can generate plausible-sounding but incorrect medical information. Always ground outputs in verified data sources (see RAG section below)
- **Bias awareness**: AI models trained on historical healthcare data can reflect and amplify existing biases across patient demographics

### Regulatory Compliance (Awareness Only)

These are real-world frameworks teams should be aware of for post-hackathon development:

- **HIPAA** (US) — PHI privacy and security
- **FDA SaMD (Software as a Medical Device)** — If your AI makes clinical decisions, it may require FDA clearance
- **ONC Information Blocking Rule** — Requires healthcare organizations to share data via FHIR APIs
- **EU MDR / EHDS** — European equivalents for medical devices and health data sharing

### 🧪 Sample / Synthetic Data: Synthea

**[Synthea](https://github.com/synthetichealth/synthea)** is an open-source synthetic patient generator that produces realistic (but entirely fake) patient records in FHIR, CSV, CCDA, and other formats.

- Generates complete patient histories: demographics, conditions, medications, procedures, labs, encounters
- Available as pre-generated datasets or run locally to generate custom populations
- Pre-generated FHIR R4 datasets: [https://synthea.mitre.org/downloads](https://synthea.mitre.org/downloads)
- GitHub: [https://github.com/synthetichealth/synthea](https://github.com/synthetichealth/synthea)

> 💡 Synthea data can be loaded directly into a HAPI FHIR or Medplum server for realistic testing.

---

## 🧠 AI in Healthcare — Quick Guides

Short, practical guidance to help your team avoid common pitfalls and build more robust AI healthcare solutions.

### 1. Clinical NLP Basics

Natural Language Processing (NLP) is extremely valuable in healthcare because so much clinical information lives in unstructured text (doctor's notes, discharge summaries, etc.).

**Common tasks:**
- **Named Entity Recognition (NER)**: Extract clinical entities — symptoms, medications, diagnoses, lab values, body parts — from free text
- **Relation Extraction**: Identify relationships (e.g., "patient takes Metformin for diabetes")
- **Negation Detection**: Recognize when something is negated ("no chest pain") — critical for clinical accuracy
- **Temporal Extraction**: Extract when events happened ("started 3 days ago")

**Tools to explore:**
- [spaCy + scispaCy](https://allenai.github.io/scispacy/) — NLP library with biomedical models
- [medspaCy](https://github.com/medspacy/medspacy) — Clinical NLP pipeline built on spaCy
- [John Snow Labs NLP for Healthcare](https://nlp.johnsnowlabs.com/healthcare) — Enterprise clinical NLP
- Hugging Face models: search `medical NER` or `clinical NLP` at [huggingface.co/models](https://huggingface.co/models)

**Quick start prompt for an LLM:**
```
Extract the following from this clinical note: 
1. Diagnoses (map to SNOMED if possible)
2. Active medications (map to RxNorm)
3. Relevant lab values with dates
4. Any negated findings

Clinical note: [paste text here]

Return as structured JSON.
```

---

### 2. RAG (Retrieval-Augmented Generation) for Medical Knowledge Grounding

**The problem**: LLMs trained on general data can hallucinate medical facts or give outdated clinical guidance.

**The solution**: RAG grounds LLM outputs in authoritative, up-to-date medical knowledge by retrieving relevant documents before generating a response.

**How it works (simplified):**
1. Build a vector database from trusted medical sources (clinical guidelines, drug databases, FHIR resources)
2. At query time, retrieve the most relevant documents for the user's question
3. Pass retrieved documents + user question to the LLM as context
4. The LLM generates a response grounded in the retrieved evidence

**Useful sources for your RAG knowledge base:**
- [PubMed / MEDLINE](https://pubmed.ncbi.nlm.nih.gov) — Biomedical literature
- [NIH MedlinePlus](https://medlineplus.gov) — Patient-friendly clinical content
- [CDC Clinical Guidelines](https://www.cdc.gov/guidelines) — Evidence-based recommendations
- [FDA Drug Labels / DailyMed](https://dailymed.nlm.nih.gov) — Official drug information
- Your Synthea FHIR data — Patient-level context for personalized responses

**Quick stack for a hackathon RAG system:**
- [LangChain](https://www.langchain.com/) or [LlamaIndex](https://www.llamaindex.ai/) — RAG orchestration frameworks
- [ChromaDB](https://www.trychroma.com/) or [FAISS](https://github.com/facebookresearch/faiss) — Lightweight local vector stores
- Any HuggingFace embedding model — `sentence-transformers/all-MiniLM-L6-v2` is a solid, fast option

---

### 3. Prompting for Safety — Avoiding Hallucinations in Healthcare

Healthcare is a high-stakes domain. A hallucinated drug interaction or misdiagnosis can cause real harm. Use these prompting strategies:

**✅ Do This:**

```
You are a clinical decision support assistant. 
Answer ONLY based on the provided patient data and context below. 
If the answer is not clearly supported by the provided information, say "I don't have enough information to answer this."
Always include a disclaimer that this output is not a substitute for clinical judgment.

Patient context: [FHIR data / relevant records]
Question: [user query]
```

- **Be explicit about source constraints**: Tell the model to only use provided context
- **Request confidence levels**: Ask the model to indicate how confident it is and why
- **Ask for citations**: Request that claims reference specific data points from the context
- **Chain-of-thought reasoning**: Ask the model to "think step by step" — this reduces factual errors on complex clinical questions
- **Output structured data**: JSON outputs are less prone to hallucination than open-ended prose for clinical data extraction tasks

**⚠️ Warning signs of hallucination in clinical AI:**
- Specific drug dosages not present in your context
- Lab values that weren't in the patient record
- Clinical guidelines stated with false certainty
- Invented references or studies

---

### 4. When NOT to Use LLMs

LLMs are powerful but not appropriate for every task. Knowing their limits makes for better, safer solutions.

| Situation | Why LLMs Fall Short | Better Alternative |
|---|---|---|
| **Real-time critical alerts** (e.g., sepsis alarm) | Too slow, non-deterministic | Rule-based systems, trained classifiers |
| **Exact lab value interpretation** | Can misread or hallucinate numbers | Structured FHIR queries + threshold logic |
| **Drug interaction checking** | May miss interactions or invent them | Dedicated drug databases (e.g., RxNorm, OpenFDA) |
| **Regulatory-grade diagnosis** | Not validated, not FDA-cleared | Validated clinical algorithms |
| **High-volume, low-latency pipelines** | Token generation is slow | Lightweight ML models, rule engines |
| **Tasks requiring 100% reproducibility** | LLMs are probabilistic | Deterministic code/algorithms |
| **Patient-facing diagnostic conclusions** | Risk of harmful overconfidence | Always route to a clinician |

> 💡 **A strong hackathon submission uses LLMs for what they're genuinely good at** — natural language understanding, information synthesis, generating suggestions for clinician review — and uses traditional code or structured data pipelines for tasks requiring precision and reliability.

---

## 🔗 Additional Resources

| Resource | Link |
|---|---|
| HL7 FHIR Official Spec | [https://hl7.org/fhir/](https://hl7.org/fhir/) |
| SMART on FHIR | [https://docs.smarthealthit.org](https://docs.smarthealthit.org) |
| FHIR Architecture Decisions eBook | [https://darrendevitt.com/wp-content/uploads/2026/04/FHIR-Architecture-Decisions.pdf](https://darrendevitt.com/wp-content/uploads/2026/04/FHIR-Architecture-Decisions.pdf) |
| HAPI FHIR (open-source server) | [https://hapifhir.io](https://hapifhir.io) |
| Medplum (developer FHIR platform) | [https://www.medplum.com](https://www.medplum.com) |
| Synthea Synthetic Patient Data | [https://synthea.mitre.org/downloads](https://synthea.mitre.org/downloads) |
| Hugging Face Models | [https://huggingface.co/models](https://huggingface.co/models) |
| LOINC Search | [https://loinc.org/search](https://loinc.org/search) |
| SNOMED CT Browser | [https://browser.ihtsdotools.org](https://browser.ihtsdotools.org) |
| RxNorm Browser | [https://mor.nlm.nih.gov/RxNav/](https://mor.nlm.nih.gov/RxNav/) |
| NLM Clinical Tables | [https://clinicaltables.nlm.nih.gov](https://clinicaltables.nlm.nih.gov) |
| Continue IDE Plugin | [https://www.continue.dev](https://www.continue.dev) |
| LangChain (RAG framework) | [https://www.langchain.com](https://www.langchain.com) |
| LlamaIndex (RAG framework) | [https://www.llamaindex.ai](https://www.llamaindex.ai) |
| scispaCy (biomedical NLP) | [https://allenai.github.io/scispacy/](https://allenai.github.io/scispacy/) |
| OpenFDA (drug/device data API) | [https://open.fda.gov](https://open.fda.gov) |
| PubMed | [https://pubmed.ncbi.nlm.nih.gov](https://pubmed.ncbi.nlm.nih.gov) |

---

*Good luck, and build something that matters! 🏥 💡*

*Questions? Reach out on Slack!
# Meridian AI — Complete Learner Guide

All learner documents in one file. Section numbers match the individual files in the `docs/` folder.

## Contents

- [00 · Overview — what you will build](#00--overview--what-you-will-build)
- [01 · Requirements](#01--requirements)
- [02 · Accounts, the $300 credit and costs](#02--accounts-the-300-credit-and-costs)
- [03 · Project basics — what is in a software project, and why](#03--project-basics--what-is-in-a-software-project-and-why)
- [04 · Project tour — every folder and file, and why it is organised this way](#04--project-tour--every-folder-and-file-and-why-it-is-organised-this-way)
- [05 · Architecture and how the pieces work together](#05--architecture-and-how-the-pieces-work-together)
- [06 · Google Cloud setup (paths B and C)](#06--google-cloud-setup-paths-b-and-c)
- [07 · Run the project on your computer](#07--run-the-project-on-your-computer)
- [08 · The web API (`backend/api/`)](#08--the-web-api-backendapi)
- [09 · FastAPI in depth](#09--fastapi-in-depth)
- [10 · Configuration and logging](#10--configuration-and-logging)
- [11 · Document question answering — the RAG pipeline (`backend/rag/`)](#11--document-question-answering--the-rag-pipeline-backendrag)
- [12 · The audit agents (`backend/agent/`)](#12--the-audit-agents-backendagent)
- [13 · The user interface (`frontend/`)](#13--the-user-interface-frontend)
- [14 · Docker and Cloud Run](#14--docker-and-cloud-run)
- [15 · Provisioning — how the cloud resources get created](#15--provisioning--how-the-cloud-resources-get-created)
- [16 · Automated deployment with GitHub Actions](#16--automated-deployment-with-github-actions)
- [17 · Cleanup — stop all charges](#17--cleanup--stop-all-charges)
- [18 · Troubleshooting](#18--troubleshooting)
- [19 · Design decisions — the reasons behind each choice](#19--design-decisions--the-reasons-behind-each-choice)
- [20 · Alternatives and next steps](#20--alternatives-and-next-steps)
- [21 · Glossary](#21--glossary)

---

<a id="chapter-00"></a>

## 00 · Overview — what you will build

**Meridian AI** is a web application that helps a company check a purchase before paying for it. It has two features:

1. **Document Q&A (RAG).** You upload PDFs (policies, contracts, reports). You ask questions in plain English and get answers based on those documents.
2. **Procurement audit (agents).** You paste a purchase request. Three specialist AI agents review it, then a "CFO" step writes one summary memo:

   | Agent | Checks |
   |---|---|
   | Risk & Compliance | Is the vendor on a sanctions list? How financially safe is the vendor? |
   | Tax & Treasury | What VAT and import duty apply? Is the quoted exchange rate reasonable? |
   | Financial Control | Is it a capital or an operating expense? Who must approve it? |

The company in the examples, **Aldermoor Industries**, is **fictional**. Its documents are made-up teaching data.

> The audit tools ask an AI model from its general knowledge (only the exchange-rate check uses a live data source). This project teaches the architecture. It is **not** a real compliance system.

### What you will learn

| Topic | Where it appears |
|---|---|
| Building a web API with **FastAPI** | `backend/api/` |
| **RAG**: PDF → chunks → embeddings → vector database → answers | `backend/rag/` |
| **Agents** with LangChain: tools, prompts, a supervisor | `backend/agent/` |
| **Google Cloud**: projects, IAM, Cloud Storage, Vertex AI, Cloud Run, Secret Manager | [06](#chapter-06), [14](#chapter-14) |
| **Docker** packaging | `Dockerfile` |
| **CI/CD** with GitHub Actions | `.github/workflows/deploy.yml` |
| Organising a project into modules, configuration and tests | [03](#chapter-03), [04](#chapter-04) |
| **Logging**: levels, structured JSON logs, where to read them | [10](#chapter-10) |
| **Provisioning** cloud resources: GitHub Actions + `gcloud` (used), Terraform (optional example) | [15](#chapter-15) |
| The reasoning behind each design choice | [19](#chapter-19) |

### What the finished app looks like

Four screens (tabs):

| Tab | What you do |
|---|---|
| **Document Upload** | Upload PDFs so they can be searched |
| **RAG Q&A** | Ask questions about the uploaded documents |
| **Audit** | Run the multi-agent audit on a purchase request |
| **System Status** | See configuration and health |

### Three ways to use this repository

| Path | You need | You get |
|---|---|---|
| **A. Audit only, on your computer** | Gemini API key | The audit feature. Quickest start (about 20 minutes). |
| **B. Everything on your computer** | A + Google Cloud project + GitHub account | Audit **and** document Q&A. The cloud resources (vector database, storage) are created once by the GitHub workflow, then you run the app locally against them |
| **C. Deployed on the internet** | B | The same app on a public Cloud Run URL (the workflow in B already deploys it) |

Read the documents in order: the numbers in the file names are the reading order. If any word is unfamiliar, [03 · Project basics](#chapter-03) explains it.


---

<a id="chapter-01"></a>

## 01 · Requirements

Check this list before you start. Details for accounts and costs are in [02 · Accounts, credits and costs](#chapter-02).

### Knowledge you need

| You should know | Level |
|---|---|
| Python | Comfortable with functions, classes, packages, virtual environments |
| **LangChain basics** | Prompts, chat models, chains, what a tool is |
| Command line | Run commands, change directories, set environment variables |
| Git | Clone a repository |

You do **not** need prior experience with Google Cloud, FastAPI, vector databases, Docker, or CI/CD. They are explained in these documents.

### Accounts you need

| Account | Needed for | Cost | Required for path |
|---|---|---|---|
| **Google account** (Gmail or Workspace) | Everything Google | Free | A, B, C |
| **Gemini API key** from Google AI Studio | The chat model (answers and agents) | Free tier available | A, B, C |
| **Google Cloud account** with billing enabled | Vector database, storage, Cloud Run | $300 free credit for new customers (see 02) | B, C |
| **GitHub account** | Creates the cloud resources and deploys the app (GitHub Actions) | Free | B, C |

A **credit or debit card is required** to create a Google Cloud account, even for the free trial. Google places a temporary authorisation hold to verify it. It is not a charge.

### Software you need

| Tool | Version | Used for | Check with |
|---|---|---|---|
| **Python** | 3.12 | Backend | `python3 --version` |
| **Node.js** and npm | 20 or newer | Frontend | `node --version` |
| **Git** | any recent | Getting the code | `git --version` |
| **Google Cloud CLI** (`gcloud`) | recent | Cloud setup (paths B, C) | `gcloud --version` |
| **Docker Desktop** | recent | Optional, container run | `docker --version` |
| A code editor | e.g. VS Code | Reading and editing | — |
| A web browser | any | The app and Google Cloud console | — |

Install links:
- Python: https://www.python.org/downloads/
- Node.js: https://nodejs.org/
- Google Cloud CLI: https://cloud.google.com/sdk/docs/install
- Docker: https://docs.docker.com/get-docker/

**Windows users:** the commands in these documents use macOS/Linux syntax. Use **WSL 2** (Windows Subsystem for Linux) for the smoothest experience, or use the Windows variants shown where they differ.

### Computer and network

| Item | Minimum |
|---|---|
| RAM | 8 GB |
| Free disk space | 3 GB (Python packages, Node packages, Docker image) |
| Internet | Required (Google APIs, package downloads) |

### Time you should plan

| Task | Time |
|---|---|
| Path A (audit only, local) | about 20–30 minutes |
| Google Cloud setup | about 30–45 minutes |
| First cloud deployment (mostly waiting for the vector index) | **30–45 minutes**, unattended |
| Reading the code walkthroughs | 2–3 hours |

### Before you continue

- [ ] I have a Google account.
- [ ] I can create a Gemini API key (see 02).
- [ ] I have Python 3.12, Node.js 20+, and Git installed.
- [ ] For paths B and C: I have a payment card for Google Cloud verification, and I have read the cost warnings in 02.
- [ ] For paths B and C: I have a GitHub account.


---

<a id="chapter-02"></a>

## 02 · Accounts, the $300 credit and costs

> Prices and free-tier limits change. The numbers below were checked in October 2026. Always confirm on the linked official pages before relying on them.

### 1. Gemini API key (Google AI Studio)

The chat model (`gemini-3.8-flash`) is called with an **API key**. It does not use your Google Cloud billing.

1. Open https://aistudio.google.com/apikey and sign in with your Google account.
2. Choose **Create API key**. Copy it.
3. Keep it secret. Treat it like a password. Never commit it to Git or paste it into screenshots.

| Fact | Detail |
|---|---|
| Free tier | Yes. For `gemini-3.8-flash`, the free tier is "free of charge" for input and output, subject to rate limits. |
| Privacy on the free tier | Google states that free-tier content may be **used to improve its products**. Do not send confidential data. Use only the fictional sample documents. |
| Paid tier | Prices per 1 million tokens: input $0.75, output $3.75 through 31 Dec 2026. From 1 Jan 2027: input $1.50, output $7.50. Paid-tier data is not used to improve products. |
| Rate limits | https://ai.google.dev/gemini-api/docs/rate-limits |
| Model list and retirements | https://ai.google.dev/gemini-api/docs/models |

Models are retired regularly. The project's earlier default, `gemini-2.5-pro`, stops working in October 2026. The model name is a setting (`VERTEX_LLM_MODEL_NAME`), so you can change it without touching code.

### 2. Google Cloud account and the $300 free trial

Google Cloud is needed for the vector database (Vertex AI Vector Search), file storage, and hosting (Cloud Run). Path A does not need it.

#### How the free trial works

| Question | Answer (from Google's Free Trial documentation) |
|---|---|
| How much credit? | **$300** of "Welcome credit" |
| For how long? | **90 days** (about three months) from sign-up |
| Who qualifies? | **New customers only**: you have never been a paying Google Cloud, Google Maps Platform or Firebase customer and have not used the trial before |
| Is a card needed? | **Yes.** A valid payment method is required. The authorisation is "a hold, not an actual charge." |
| Do I get charged automatically? | **No.** You are billed only if you manually upgrade to a paid account |
| What if the 90 days or $300 run out first? | The trial ends. After that there is a **30-day grace period**, then free-trial resources are **permanently deleted** unless you upgrade |
| If I upgrade? | You are billed for usage **not covered by the remaining credit**, and for products that are not part of the free trial |

Source: https://docs.cloud.google.com/free/docs/free-cloud-features

The credit is a **balance in dollars**. Every Google Cloud service you use subtracts from it. The 90-day limit and the $300 limit apply together: the trial ends at whichever comes first.

#### Trial limitations to know

Google lists these limits for free-trial accounts:

- No GPUs on virtual machines
- No Google Cloud Marketplace
- No quota increase requests
- No Windows Server VMs
- Certain generative AI services are restricted

Some users also report that Vertex AI model requests on trial accounts are throttled hard, with fixed rate limits. In this project the **chat model uses your AI Studio key**, so it is unaffected. **Embeddings use Vertex AI**, so they are the part that could hit a trial limit. If you see a message such as *"Project is not allowed to use …"* or repeated rate-limit errors during document upload, see [18 · Troubleshooting](#chapter-18). The usual remedy is to **activate the full (paid) account** in Billing. Your remaining credit still applies first. Only usage beyond it is charged.

#### Create the account

1. Go to https://cloud.google.com/free and choose **Get started for free**.
2. Sign in, accept the terms, add your payment method.
3. Create a project (done in [06](#chapter-06)).

### 3. Where the money goes

| Service | How it is billed | Expected cost for this project |
|---|---|---|
| **Vertex AI Vector Search** | **Per hour, for as long as an index is deployed to an endpoint, even with zero traffic** | **The main cost.** See the warning below |
| **Cloud Run** | Per use (CPU time, memory, requests). Scales to zero when idle | Usually inside the monthly free allowance for light use (about 2 million requests, 180,000 vCPU-seconds, 360,000 GiB-seconds per month) |
| **Cloud Build** | Per build minute | A monthly free allowance exists (reported as 2,500 minutes) |
| **Cloud Storage** | Per GB stored | A few cents or less for sample PDFs and logs |
| **Artifact Registry** | Per GB of stored images | Small |
| **Secret Manager** | Per active secret version and per access | Small (6 active versions free per month) |
| **Vertex AI embeddings** | Per characters embedded | Small for a few documents |
| **Gemini API chat** | Free tier, or per token on the paid tier | Free tier for light use |

Free-allowance numbers come from public summaries of Google's pricing pages. Confirm on https://cloud.google.com/run/pricing, https://cloud.google.com/build/pricing and https://cloud.google.com/secret-manager/pricing.

#### ⚠ The Vector Search endpoint

A Vector Search index is searched through an **endpoint** that keeps one or more machines running. You pay by the hour while the index is **deployed**, whether or not anyone uses it.

- A small `e2-standard-2` node is reported at roughly **$0.077 per hour (about $56 per month per node)** on third-party price guides. This is not an official figure. Check https://cloud.google.com/vertex-ai/pricing.
- The deployment command in `.github/workflows/deploy.yml` does **not** set a machine type or replica count. Google's documentation says that when replica counts are not set they default to **2**. The default machine type is not documented on the pages checked. **Your real hourly cost may therefore be higher than the single-node figure.**
- At $0.077/hour per node, two nodes would use about $3.70 per day. A larger machine type costs more.

**What to do:**
1. Before deploying, create a **budget alert** (steps below).
2. After the first deployment, open **Billing → Reports** the next day and check the daily cost.
3. When you finish a work session, **undeploy and delete** the index and endpoint. See [17 · Cleanup](#chapter-17). Re-creating them takes 30–45 minutes, so plan to do your cloud work in one sitting.

#### Create a budget alert (do this first)

1. In the Cloud Console open **Billing → Budgets & alerts**.
2. **Create budget**. Name it `meridian-budget`.
3. Scope: your project. Amount: for example **$20**.
4. Alert thresholds: 50 %, 90 %, 100 %. Keep email notifications on.

A budget alert **notifies** you. It does **not stop** spending. You must delete resources yourself.

### 4. GitHub account (paths B and C)

Used to create the cloud resources and deploy the app automatically. Create a free account at https://github.com. GitHub Actions is free for public repositories and has a monthly free allowance for private ones.

### 5. Summary

| Path | Accounts | Money |
|---|---|---|
| A | Google account, Gemini API key | Free |
| B | + Google Cloud (trial) + GitHub | Uses trial credit. Dominated by Vector Search hours |
| C | Same as B | Same cost as B, plus a public URL. Cloud Run is mostly free at low traffic |


---

<a id="chapter-03"></a>

## 03 · Project basics — what is in a software project, and why

Read this if any of these words are unfamiliar: *repository, package, module, virtual environment, requirements file, environment variable, `.env`, API, frontend, backend, container, pipeline*. If you already know them, go straight to [04 · Project tour](#chapter-04).

This page explains the *ideas*. Document 04 then shows where each idea lives in this project.

---

### 1. A project is more than code

When you first learn to program, a "program" is one file. A real application is a **folder of many files**, and they fall into a few kinds. Knowing the kind tells you how to treat a file.

| Kind of file | Examples in this project | How you treat it |
|---|---|---|
| **Source code**: instructions the computer runs | `backend/rag/retrieval.py`, `frontend/src/lib/api.ts` | You read and edit it |
| **Configuration**: settings that change behaviour without changing code | `.env`, `requirements.txt`, `package.json`, `Dockerfile` | You edit values, carefully |
| **Secrets**: keys and passwords | the Gemini API key in `.env`, `credentials/*.json` | **Never commit them to Git** |
| **Data / assets**: inputs the program uses | `course/sample_docs/*.pdf`, `init_embeddings.json` | You supply or replace them |
| **Documentation**: explanations for people | `README.md`, everything in `docs/` | You read it and keep it up to date |
| **Automation**: scripts that run for you | `.github/workflows/deploy.yml` | You trigger it; it runs on a server |
| **Generated files**: created by tools, not written by hand | `frontend/dist/`, `__pycache__/`, `node_modules/` | **Never edit by hand; not committed** |

### 2. Repository, Git and GitHub

- A **repository** (repo) is the project folder plus its complete history of changes.
- **Git** is the tool that records that history. A **commit** is one saved set of changes with a message. A **branch** is a separate line of work.
- **GitHub** is a website that stores repositories so people can share and collaborate.
- **`.gitignore`** lists files Git must not track: secrets, generated files, your personal settings. This is the main reason a secret does not end up on the internet by accident.

### 3. Frontend and backend

Most web applications are split in two:

```
 Your browser                                A computer running your Python code
┌──────────────────┐   requests (HTTP)     ┌───────────────────────────────┐
│ FRONTEND         │ ───────────────────►  │ BACKEND                       │
│ what you see:    │                       │ the logic: reads documents,   │
│ buttons, tabs    │ ◄───────────────────  │ calls AI models, returns data │
└──────────────────┘   responses (JSON)    └───────────────────────────────┘
```

- The **frontend** runs in the user's browser. In this project it is written in TypeScript with React.
- The **backend** runs on a server. In this project it is written in Python with FastAPI.
- They communicate through an **API**: a list of addresses (URLs) the backend offers, each doing one job, exchanging data as **JSON** (plain text structured like a Python dictionary).

Why separate them? Each has its own tools, its own language, and can be changed without touching the other. The frontend does not need to know *how* an answer is produced, only *which address to ask*.

### 4. Python project vocabulary

| Term | Meaning | Where you see it here |
|---|---|---|
| **Module** | One `.py` file you can `import` | `retrieval.py` |
| **Package** | A folder of modules, marked by an `__init__.py` file | `backend/rag/` |
| **Import** | Using code from another module | `from rag.llm import get_llm` |
| **Dependency** | A package written by someone else that your code uses | `fastapi`, `langchain` |
| **`requirements.txt`** | A list of dependencies and versions | root of the project |
| **Virtual environment** | A private copy of Python and packages for one project, so projects do not interfere | the `.venv/` folder |
| **Pinning** | Writing an exact version (`fastapi==0.135.1`) so everyone gets identical behaviour | `requirements.txt` |

The usual routine:

```bash
python3.12 -m venv .venv          # create the private environment (once)
source .venv/bin/activate         # switch it on (each new terminal)
pip install -r requirements.txt   # install the dependencies
```

If you forget to activate the environment, Python cannot find the packages and you see `ModuleNotFoundError`.

### 5. Configuration: settings kept out of code

Some values change between computers or between "my laptop" and "the live server": a project ID, a bucket name, a model name. And some values are secret: an API key. Putting these inside the code is a bad idea because:

1. changing them means editing code;
2. secrets would be committed to Git and visible to everyone.

The standard solution is **environment variables**: named values that exist outside your code, in the operating system's environment. Your code asks for them by name.

For convenience on your own computer, a `.env` file holds them:

```
GOOGLE_API_KEY=abc123
GCP_PROJECT_ID=my-project
```

The program reads `.env` when it starts. `.env` is listed in `.gitignore` so it is never committed. `.env.example` is a **template** with the names but no real values, and *is* committed, so you know what to fill in.

On the live server there is no `.env`; the values are supplied by the hosting platform (Cloud Run environment variables and Secret Manager).

### 6. Layers, modules and "one job per file"

A good project is split so that each piece has **one job** and you can find things by name. The split used here:

| Question | Answer in this project |
|---|---|
| Where is the code that answers HTTP requests? | `backend/api/` |
| Where is the code that deals with documents and AI search? | `backend/rag/` |
| Where is the agent code? | `backend/agent/` |
| Where are the settings? | `backend/config/` |
| Where is the logging? | `backend/logger/` |
| Where is the screen the user sees? | `frontend/` |

If something breaks, the error message tells you which area to open. Details and reasons are in [04](#chapter-04) and [19](#chapter-19).

### 7. Containers, the cloud and automation

| Idea | One-paragraph explanation |
|---|---|
| **Cloud provider** | A company (here Google) that rents you computers, storage and services by the hour, over the internet, instead of you buying hardware |
| **Project (Google Cloud)** | A named account-like space that holds all your resources and your bill |
| **Docker image / container** | A sealed package containing your app *and* the exact environment it needs. Anyone can run it and get the same result. A **container** is a running copy |
| **Provisioning** | Creating the cloud resources your app needs (storage, database, servers). See [15](#chapter-15) |
| **Deployment** | Putting a new version of your app onto those resources so people can use it |
| **CI/CD** | *Continuous Integration / Continuous Delivery*: a robot that builds, tests and deploys your code automatically each time you push changes. Here, **GitHub Actions** does this |
| **Logging** | Your program writing a running diary of what it does, so you can understand problems afterwards. See [10](#chapter-10) |

### 8. What the application does (in one paragraph)

You upload PDF documents. The backend cuts them into small pieces, converts each piece into numbers that represent its meaning (an *embedding*), and stores them in a *vector database*. When you ask a question, the backend converts the question the same way, finds the closest stored pieces, and asks Google's Gemini model to answer using only those pieces. Separately, you can submit a purchase request, and three AI "agents" (risk, tax, accounting control) check it using tools, after which a final step writes a summary memo.

### 9. How to read this guide

1. Finish [00](#chapter-00) to [02](#chapter-02) to know what you are building and what it costs.
2. Read [04 · Project tour](#chapter-04) with the repository open next to it. Open each file as it is described.
3. Read [05 · Architecture and flows](#chapter-05) to see how the files work together.
4. Run it ([06](#chapter-06), [07](#chapter-07)).
5. Read the deep dives in order: [08](#chapter-08) → [09](#chapter-09) → [10](#chapter-10) → [11](#chapter-11) → [12](#chapter-12) → [13](#chapter-13).
6. Read how it is shipped: [14](#chapter-14) → [15](#chapter-15) → [16](#chapter-16).
7. Keep [17](#chapter-17), [18](#chapter-18) and [21](#chapter-21) nearby.


---

<a id="chapter-04"></a>

## 04 · Project tour — every folder and file, and why it is organised this way

Open the repository in your editor and keep this page beside it. Every file is listed. Terms like *package*, `.env` or *Dockerfile* are explained in [03 · Project basics](#chapter-03).

---

### 1. The whole repository at a glance

```
meridian-ai-learner-edition/
│
├── backend/                  PYTHON: the server (API, document search, agents)
├── frontend/                 TYPESCRIPT/REACT: the screens in the browser
│
├── Dockerfile                Recipe that packages frontend + backend into one image
├── .dockerignore             Files that must NOT go into that image
├── .github/workflows/        GitHub Actions: the automated deployment
├── infra/terraform/          OPTIONAL: the same cloud resources written for Terraform
│
├── requirements.txt          Python packages the app needs (exact versions)
├── requirements-dev.txt      + packages for tests and the sample-PDF generator
├── .env.example              Template for your private settings file
├── .gitignore                Files Git must not track
│
├── generate_json.py          Creates the one starter vector the index needs
├── init_embeddings.json      Output of generate_json.py (committed example)
├── index_metadata.json       Example of the index settings (the workflow writes its own)
│
├── Supporting Documents/     The architecture diagram image
├── docs/                     This learner guide (+ runnable examples)
├── course/                   Instructor material + the four sample PDFs
└── README.md                 The front door: what the project is and where to start
```

#### Is Terraform used? Or GitHub Actions?

**GitHub Actions is what this project uses.** The file `.github/workflows/deploy.yml` creates the cloud resources by running `gcloud` commands, then builds and deploys the app. **Terraform is not part of the deployment.** The `infra/terraform/` folder is an *optional, alternative* way of creating the same resources, included so you can learn the technique. You never need it to run the project. Do not use both on the same Google Cloud project (they would try to create the same resources). The full explanation is in [15 · Provisioning](#chapter-15).

---

### 2. Why the project is divided this way

There are three separate ideas behind the layout.

#### 2.1 Divide by *responsibility*, not by size

Each folder answers one question. When something breaks, the error tells you which question to ask, and therefore which folder to open.

| Folder | Question it answers |
|---|---|
| `backend/api/` | How does the outside world talk to the server? |
| `backend/rag/` | How do we find the right passages in documents and answer from them? |
| `backend/agent/` | How do the AI agents check a purchase request? |
| `backend/config/` | Where do settings come from? |
| `backend/logger/` | How does the program write its diary? |
| `frontend/` | What does the user see and click? |

A single large file would mix all of these. A change to the tax prompt would sit a few lines from the code that opens PDFs, and a mistake in one could break the other. In separate files a change stays local. This is the *single responsibility* principle: **one file, one job**.

#### 2.2 Divide by *how often and why it changes*

| Changes often, by developers | Changes per environment | Changes rarely |
|---|---|---|
| Code in `backend/`, `frontend/src/` | `.env`, GitHub secrets, Cloud Run settings | `Dockerfile`, `deploy.yml`, `tsconfig*.json` |

Keeping code, settings and infrastructure in different places means you can change a model name without touching code, and redeploy infrastructure without touching the application.

#### 2.3 Divide so that dependencies point one way

```
api  ──►  rag, agent  ──►  config, logger
```

`api` may use `rag` and `agent`. `rag` and `agent` may use `config` and `logger`. Never the other way. `rag` knows nothing about web addresses; `config` knows nothing about documents. This keeps code testable (you can test `rag` without starting a web server) and prevents circular imports. The diagram and rules are in [05](#chapter-05).

---

### 3. `backend/` — the Python server

Run from the project root as `uvicorn api.main:app --app-dir backend`. The `--app-dir backend` option makes `backend/` the place Python searches for packages, which is why code writes `from rag.llm import get_llm` and not `from backend.rag.llm import get_llm`.

Each package folder contains an `__init__.py`. That empty-or-tiny file tells Python "this folder is a package".

#### 3.1 `backend/api/` — the web layer

| File | What it does | Key contents |
|---|---|---|
| `main.py` | Creates the web application and wires everything together | the `FastAPI` app, CORS middleware, the four routers, a `lifespan` function that uploads logs on shutdown, and static-file serving for the built React app |
| `endpoints.py` | Defines every URL | `health`, `system_status`, `run_audit`, `rag_query`, `upload_documents`, `list_uploads`, `trigger_gcs_ingestion`; `get_supervisor()` builds the audit supervisor on first use |
| `schemas.py` | Describes the data in and out | `AuditRequest`, `AuditResponse`, `QueryRequest`, `QueryResponse` (Pydantic classes) |
| `__init__.py` | Marks the folder as a package | – |

Why three files? `schemas.py` is *what the data looks like*, `endpoints.py` is *what happens at each URL*, `main.py` is *how the app is assembled*. Deep dives: [08](#chapter-08), [09](#chapter-09).

#### 3.2 `backend/rag/` — document question answering

| File | What it does | Key contents |
|---|---|---|
| `llm.py` | Gives the rest of the code the Gemini chat model | `get_llm()`, `extract_text()` |
| `embeddings.py` | Gives the code the text-to-numbers model | `get_embeddings()` |
| `vector_store.py` | Connects to the vector database | `get_vector_store()` |
| `data_ingestion.py` | Gets documents *into* the database | `split_into_chunks()`, `ingest_pdf()`, `ingest_data_from_gcs()`, `CHUNK_SIZE`, `CHUNK_OVERLAP` |
| `retrieval.py` | Gets answers *out* | `build_retriever()`, `ask_question()`, `SYSTEM_PROMPT` |

Why five files? Each is one external thing or one step: the chat model, the embedding model, the database, putting data in, taking answers out. If you replace Gemini with another model you edit only `llm.py`. If you replace Vertex Vector Search you edit `vector_store.py`. Deep dive: [11](#chapter-11).

#### 3.3 `backend/agent/` — the audit agents

| File | What it does | Key contents |
|---|---|---|
| `tools.py` | The five functions an agent may call | `check_sanctions_list`, `get_vendor_credit_score`, `calculate_cross_border_tax`, `validate_fx_hedge`, `categorize_expense` |
| `prompts.py` | The written instructions for each agent | `RISK_AGENT_PROMPT`, `TAX_AGENT_PROMPT`, `CONTROL_AGENT_PROMPT`, `SYNTHESIS_PROMPT_TEMPLATE` |
| `agents.py` | Builds the agents and runs them in order | `create_specialized_agent()`, `ProcurementSupervisor.run_audit()` |

Why three files? **Tools** (what an agent can *do*), **prompts** (what an agent is *told*) and **orchestration** (the *order* things happen) are three different decisions that change for different reasons. Prompt wording is edited constantly; orchestration rarely. Deep dive: [12](#chapter-12).

#### 3.4 `backend/config/` and `backend/logger/`

| File | What it does |
|---|---|
| `config/settings.py` | One `Settings` class that reads every setting from environment variables / `.env` and provides a ready object `settings`. No other file reads `.env`. |
| `logger/custom_logger.py` | Builds the logger: JSON lines to the console and a file, adds a `severity` field, uploads the file to Cloud Storage when the server stops. |
| `logger/__init__.py` | Creates one shared logger, `GLOBAL_LOGGER`, which every module imports as `log`. |

Why separate? Almost every other file needs settings and logging. Putting them at the bottom of the dependency chart means everything can use them and they depend on nothing. Deep dive: [10](#chapter-10).

#### 3.5 `backend/tests/` — automated checks

| File | What it does |
|---|---|
| `conftest.py` | Runs before the tests: sets fake settings so no cloud account is needed |
| `test_api.py` | Nine tests: health, status, unknown URL, question route, audit route, non-PDF rejection, chunking, sample PDFs, log severity |

Run with `pytest backend/tests`. Tests replace the AI and the cloud with simple stand-ins ("stubs"), so they are fast, free and repeatable.

---

### 4. `frontend/` — the browser application

Built with **React** (a library for building screens from components), **TypeScript** (JavaScript with types), **Vite** (a build tool and development server), **Tailwind CSS** (styling through short class names) and **shadcn/ui** (ready-made accessible components). The project was originally generated with a tool that created the setup files below. You only need to understand a small part of it.

#### 4.1 Files you should read

| File | What it does |
|---|---|
| `src/lib/api.ts` | **The one place that calls the backend.** One function per URL |
| `src/pages/Index.tsx` | The page layout: sidebar plus the four tabs (RAG Q&A, Procurement Audit, Index Documents, System Status) |
| `src/components/DocumentUploadTab.tsx` | The *Index Documents* screen: choose PDFs, upload, see results, import from the bucket |
| `src/components/RagQATab.tsx` | The *RAG Q&A* screen: question box, retrieval-strategy choice, answer history |
| `src/components/AuditTab.tsx` | The *Procurement Audit* screen: request text, progress, the three reports and the memo |
| `src/components/SystemStatusTab.tsx` | The *System Status* screen: shows `/api/status` |

#### 4.2 Files that make the frontend work (you rarely edit these)

| File | Purpose |
|---|---|
| `index.html` | The single HTML page. React fills in `<div id="root">` |
| `src/main.tsx` | Starts React and puts `App` on the page |
| `src/App.tsx` | Sets up page routing and shared providers; shows `Index` at `/`, `NotFound` otherwise |
| `src/pages/NotFound.tsx` | The "page not found" screen |
| `src/components/NavLink.tsx` | A small link helper |
| `src/components/ui/` | 49 generated shadcn/ui building blocks (buttons, cards, tabs…). **Do not edit by hand**; they come from the `shadcn` tool |
| `src/hooks/` | Small reusable React helpers (`use-toast`, `use-mobile`) |
| `src/lib/utils.ts` | The `cn()` helper that combines CSS class names |
| `src/index.css`, `src/App.css` | Global styles and colour variables |
| `src/vite-env.d.ts` | Type declarations for Vite |

#### 4.3 Configuration files (tooling settings)

| File | Purpose |
|---|---|
| `package.json` | The frontend's `requirements.txt`: dependencies and the commands `npm run dev`, `build`, `lint`, `test` |
| `package-lock.json` | Exact versions installed. **Used by Docker** (`npm ci`) |
| `bun.lock` | A second lock file from the Bun package manager. Unused by this project's Docker build; npm is the supported tool |
| `vite.config.ts` | Dev server port **3000**, the `@` shortcut for `src/`, React plugin |
| `tsconfig.json`, `tsconfig.app.json`, `tsconfig.node.json` | TypeScript compiler rules (app code vs tool code) |
| `tailwind.config.ts`, `postcss.config.js` | Styling system settings |
| `components.json` | Settings for the shadcn/ui generator |
| `eslint.config.js` | Code-style checks (`npm run lint`) |
| `vitest.config.ts`, `src/test/setup.ts`, `src/test/example.test.ts` | Frontend unit-test setup; the only test is a placeholder |
| `playwright.config.ts`, `playwright-fixture.ts` | Browser end-to-end test setup (not used by the course) |

Why a separate folder? The frontend has its own language, package manager (`npm`), tools and build output (`frontend/dist/`). Keeping it in its own folder means `pip` and `npm` never touch each other's files.

---

### 5. Root files

| File | What it does | Why it is at the root |
|---|---|---|
| `README.md` | Introduction and links | The first thing GitHub shows |
| `requirements.txt` | Pinned Python dependencies | `pip install -r requirements.txt` and Docker both look here |
| `requirements-dev.txt` | `-r requirements.txt` plus `pytest`, `httpx`, `reportlab` | Tools learners need but production does not |
| `.env.example` | Template listing every setting | Copy to `.env` |
| `.gitignore` | Stops secrets and generated files entering Git | Applies to the whole repository |
| `.dockerignore` | Keeps `.env`, `credentials/`, `.git`, `node_modules`, logs out of the image | Docker reads it from the build folder |
| `Dockerfile` | Builds the image (see [14](#chapter-14)) | Docker reads it from the build folder |
| `generate_json.py` | Writes `init_embeddings.json`: one random 768-number vector with the id `init_0001` | The workflow runs `python generate_json.py` |
| `init_embeddings.json` | Output of the above. A Vector Search index must start with at least one vector; this is it. The workflow deletes it from the index afterwards | Copied to the bucket during provisioning |
| `index_metadata.json` | **Example** of the index's creation settings (768 dimensions, dot-product distance…). The workflow writes its own copy at deploy time with your real bucket; Terraform has the same values written as code. The `YOUR_PROJECT_ID` in it is a placeholder | Reference for the reader |

---

### 6. Other folders

| Folder | Contents |
|---|---|
| `.github/workflows/deploy.yml` | The deployment pipeline ([16](#chapter-16)) |
| `infra/terraform/` | Optional Terraform version of the provisioning: `versions.tf`, `variables.tf`, `main.tf`, `outputs.tf`, `terraform.tfvars.example` ([15](#chapter-15)) |
| `docs/` | This guide, plus `docs/examples/` with six small runnable programs |
| `course/` | Notes for instructors, and `course/sample_docs/` with four fictional PDFs for trying the app |
| `Supporting Documents/` | `architecture_diagram.png` |

#### Folders that appear on your computer but are not in Git

| Folder | Created by | Why it is not committed |
|---|---|---|
| `.venv/` | `python -m venv` | Your private Python environment; recreate it from `requirements.txt` |
| `frontend/node_modules/` | `npm install` | Downloaded packages; recreate from `package-lock.json` |
| `frontend/dist/` | `npm run build` | Build output; Docker rebuilds it |
| `backend/logs/`, `logs/` | the logger | Local diary files |
| `__pycache__/`, `.pytest_cache/` | Python, pytest | Caches |
| `credentials/` | you | Holds secrets |
| `.env` | you | Holds secrets |

---

### 7. How the pieces work together (preview)

```
Browser ─► frontend/src/lib/api.ts ─► backend/api/endpoints.py ─┬─► backend/rag/*   ─► Vertex AI, Gemini
                                                                └─► backend/agent/* ─► Gemini
                    every module reads:  backend/config/settings.py   and writes:  backend/logger/*
```

[05 · Architecture and flows](#chapter-05) follows a real request through these files step by step.

---

### 8. Which parts need which accounts?

| Part | Gemini key | Google Cloud |
|---|:---:|:---:|
| `/api/health`, `/api/status` | – | – |
| `/api/agent/audit` | ✔ | – |
| `/api/rag/ask`, `/api/rag/upload`, `/api/rag/ingest-gcs` | ✔ | ✔ |
| `docs/examples/*` | – | – |
| `pytest backend/tests` | – | – |

---

### 9. Exercise: find it yourself

Open the repository and answer without searching the internet:

1. Which file decides the chunk size? *(Answer: `backend/rag/data_ingestion.py`, `CHUNK_SIZE`.)*
2. Where is the instruction that tells the CFO step what `RED ALERT` means? *(`backend/agent/prompts.py`.)*
3. If the Gemini model is retired, which file or setting do you change? *(`VERTEX_LLM_MODEL_NAME` in `.env`; default in `backend/config/settings.py`.)*
4. Which file would you edit to make the page's tab order different? *(`frontend/src/pages/Index.tsx`.)*
5. Which file creates the cloud storage bucket? *(`.github/workflows/deploy.yml`; or `infra/terraform/main.tf` if you use Terraform.)*
6. Which file stops your API key from being baked into the Docker image? *(`.dockerignore`.)*


---

<a id="chapter-05"></a>

## 05 · Architecture and how the pieces work together

### 1. The big picture

```
 ┌────────────────────────────────────────────────────────────────────────────┐
 │ Your browser                                                               │
 │   React app: Document Upload · RAG Q&A · Audit · System Status             │
 └───────────────▲────────────────────────────────────────────────────────────┘
                 │ HTTPS, JSON
 ┌───────────────┴────────────────────────────────────────────────────────────┐
 │ Google Cloud Run (one container)                                           │
 │   FastAPI backend  +  the built React files                                │
 │   ┌─────────────────────────┐   ┌─────────────────────────────────────┐    │
 │   │ RAG: rag/*              │   │ Agents: agent/*                     │    │
 │   │ chunk → embed → search  │   │ Risk · Tax · Control → CFO memo     │    │
 │   └──────┬───────────┬──────┘   └──────────────────┬──────────────────┘    │
 └──────────┼───────────┼─────────────────────────────┼───────────────────────┘
            │           │                             │
   Vertex AI embeddings │                             │
   (text-embedding-005) │                             │
            │   Vertex AI Vector Search          Gemini API (API key)
            │   (index + endpoint)               gemini-3.8-flash
            │           │
        Cloud Storage bucket: PDFs + logs        Secret Manager: Gemini key
```

Supporting systems: **GitHub Actions** builds and deploys; **Artifact Registry** stores the container image; **Cloud Build** builds it; **IAM** controls access.

### 2. The layers

| Layer | Technology | Where |
|---|---|---|
| User interface | React, TypeScript, Vite, Tailwind CSS, shadcn/ui | `frontend/` |
| Web API | FastAPI, Uvicorn, Pydantic | `backend/api/` |
| AI orchestration | LangChain (`create_agent`, retrieval chains) | `backend/rag/`, `backend/agent/` |
| Chat model | Gemini via Gemini API (API key) | `rag/llm.py` |
| Embeddings and vector database | Vertex AI (Google Cloud credentials) | `rag/embeddings.py`, `rag/vector_store.py` |
| File storage | Cloud Storage | `rag/data_ingestion.py`, `endpoints.py` |
| Hosting | Cloud Run | `Dockerfile`, `deploy.yml` |
| Secrets | Secret Manager | `deploy.yml` |
| Automation | GitHub Actions | `.github/workflows/deploy.yml` |

#### Two ways of signing in to Google

The project uses both:

| Used for | How it authenticates | Setting |
|---|---|---|
| Gemini chat (`rag/llm.py`) | **API key** | `GOOGLE_API_KEY` |
| Embeddings, Vector Search, Cloud Storage | **Google Cloud credentials** (a service account, or your own login) | `GCP_SERVICE_ACCOUNT_PATH` or `gcloud auth application-default login` |

### 3. Request flows

#### 3.1 Uploading a document

```
Browser ──POST /api/rag/upload (PDF)──► endpoints.upload_documents
   1. save the file temporarily
   2. copy it to Cloud Storage  gs://<bucket>/uploads/<name>.pdf
   3. data_ingestion.ingest_pdf:
        PyPDFLoader → pages
        RecursiveCharacterTextSplitter (1000 characters, 100 overlap) → chunks
        embeddings.embed → one 768-number vector per chunk
        vector_store.add_documents → stored in Vector Search
   4. return {filename, status, pages, chunks}
```

#### 3.2 Asking a question

```
Browser ──POST /api/rag/ask {query, retriever_type}──► endpoints.rag_query
   retrieval.ask_question:
     1. retriever finds the closest chunks to the question (by meaning)
     2. a prompt is filled:  "Use this context … Context: <chunks> … Question: <query>"
     3. Gemini writes the answer from that context
   ◄── {answer}
```

Three retrieval strategies are available (the radio buttons in the UI):

| Strategy | What it does |
|---|---|
| `similarity` (Normal) | Top 3 closest chunks |
| `multiquery` | Gemini rewrites the question several ways and merges the results |
| `contextual` | Fetches 10 chunks, then Gemini trims each to the relevant part |

#### 3.3 Running an audit

```
Browser ──POST /api/agent/audit {request_text}──► endpoints.run_audit
   ProcurementSupervisor.run_audit:
     1. Risk agent    → tools: check_sanctions_list, get_vendor_credit_score
     2. Tax agent     → tools: calculate_cross_border_tax, validate_fx_hedge
     3. Control agent → tools: categorize_expense
     4. CFO step      → one model call that reads the three reports
   ◄── {risk_result, tax_result, control_result, cfo_memo}
```

The CFO prompt applies fixed rules based on keywords in the reports:

| If any report contains … | Final decision |
|---|---|
| `RED ALERT` | REJECTED |
| `FX ALERT` or `HOLD FOR TREASURY AUDIT` | CONDITIONAL HOLD |
| only `APPROVED` / `SUCCESS` | APPROVED TO PAY |

#### 3.4 Deploying

```
git push to main (or "Run workflow")
  └► GitHub Actions
       1. sign in to Google Cloud with the service-account key
       2. enable the Google APIs
       3. create the Cloud Storage bucket
       4. create the Vector Search index and endpoint, deploy the index (30–45 min the first time)
       5. store the Gemini key in Secret Manager
       6. Cloud Build builds the Docker image
       7. Cloud Run runs the image and gets a public URL
```

### 4. Google Cloud services used and why

| Service | What it does here | Why it was chosen |
|---|---|---|
| **Cloud Run** | Runs the container; starts on demand and scales to zero | No server to manage; you pay for use |
| **Vertex AI Vector Search** | Stores embeddings and finds the nearest ones quickly | Managed, scales, integrates with LangChain |
| **Vertex AI embeddings** | Turns text into vectors | Same platform as the vector database |
| **Cloud Storage** | Keeps uploaded PDFs, logs, and the staging data for the index | Cheap, durable file storage |
| **Secret Manager** | Holds the Gemini key; Cloud Run reads it at start | Keys stay out of code and images |
| **Artifact Registry** | Stores Docker images | Required place for images on Google Cloud |
| **Cloud Build** | Builds the image without Docker on your machine | Runs in the cloud from the workflow |
| **IAM / service accounts** | Controls who can do what | Gives the GitHub robot and Cloud Run only the access they need |
| **Cloud Logging** | Shows the application's log lines | Debugging a running service |

Alternatives to each service are listed in [20 · Alternatives and next steps](#chapter-20).

### 5. Important design decisions

| Decision | Reason |
|---|---|
| One container serves both frontend and API | One URL, no CORS problems in production, simpler deployment |
| The embedding model must give **768** numbers | The index is created with 768 dimensions. The same model must be used when storing and searching |
| Chat uses an API key, embeddings use Google Cloud credentials | Shows both authentication styles; the key is kept in Secret Manager in production |
| Models and connections are created on first use | The app starts and the health check works before the cloud is configured |
| Agents are built with LangChain's `create_agent` | It runs on LangGraph internally, so the project contains no graph code to maintain |
| Log files are uploaded to Cloud Storage on shutdown | Cloud Run's local disk disappears when the container stops |

---

### 6. Following real requests through the files

The flows in section 3 show *what* happens. Here is *which function in which file* does each step. Open the files and follow along.

#### 6.1 The server starts

You run `uvicorn api.main:app --app-dir backend`.

| Order | File | What happens |
|---|---|---|
| 1 | `api/main.py` | Python imports it. At the top it imports `api/endpoints.py` |
| 2 | `api/endpoints.py` | Its imports pull in `agent/agents.py`, `rag/data_ingestion.py`, `rag/retrieval.py`, `config/settings.py`, `logger/__init__.py`. **No model or database is created yet** |
| 3 | `config/settings.py` | Builds the `settings` object from environment variables and `.env` |
| 4 | `logger/__init__.py` | Creates `CustomLogger()` (makes the `logs/` folder, picks a timestamped file name) and the shared `GLOBAL_LOGGER` |
| 5 | `api/main.py` | Creates the `FastAPI` app, adds CORS, registers the four routers, mounts the React files if `frontend/dist` exists |
| 6 | uvicorn | Starts listening on the port. The log shows `Application startup complete` |

Because nothing external was created in these steps, the server starts even with an empty `.env`. That is why `/api/health` always works.

#### 6.2 "Upload a PDF"

| Order | File → function | What happens |
|---|---|---|
| 1 | `frontend/src/components/DocumentUploadTab.tsx` | You pick files and click upload |
| 2 | `frontend/src/lib/api.ts` → `uploadDocuments()` | Sends the files as a form to `POST /api/rag/upload` |
| 3 | `api/endpoints.py` → `upload_documents()` | FastAPI hands over the files; non-PDFs are marked "skipped" |
| 4 | same | Saves the PDF to a temporary folder; copies it to Cloud Storage |
| 5 | `rag/data_ingestion.py` → `ingest_pdf()` (in a worker thread) | Loads pages with `PyPDFLoader`; sets each page's `source` |
| 6 | `rag/data_ingestion.py` → `split_into_chunks()` | `RecursiveCharacterTextSplitter`, 1000 characters, 100 overlap |
| 7 | `rag/vector_store.py` → `get_vector_store()` | **First use**: connects to Vertex AI Vector Search and builds the embedding model |
| 8 | `VectorSearchVectorStore.add_documents()` | Calls the embedding model for each chunk, writes vectors to the index |
| 9 | `api/endpoints.py` | Returns `{filename, status, pages, chunks}`; remembers it in `_upload_history` |
| 10 | `logger` | Every step wrote a JSON line (`File saved to GCS`, `Embedding chunks…`, `Successfully ingested chunks`) |

#### 6.3 "Ask a question"

| Order | File → function | What happens |
|---|---|---|
| 1 | `RagQATab.tsx` → `api.ts` → `askQuestion()` | `POST /api/rag/ask` with `{query, retriever_type}` |
| 2 | `api/schemas.py` → `QueryRequest` | FastAPI validates the body |
| 3 | `api/endpoints.py` → `rag_query()` | Calls `ask_question()` |
| 4 | `rag/retrieval.py` → `build_retriever()` | Chooses similarity / multiquery / contextual |
| 5 | `rag/retrieval.py` → `ask_question()` | Builds the prompt and the two chains |
| 6 | `rag_chain.invoke()` | Embeds the question → searches the index → fills the prompt with the chunks → calls Gemini |
| 7 | `api/schemas.py` → `QueryResponse` | `{answer}` returned |

#### 6.4 "Run an audit"

| Order | File → function | What happens |
|---|---|---|
| 1 | `AuditTab.tsx` → `runAudit()` | `POST /api/agent/audit` |
| 2 | `endpoints.py` → `run_audit()` → `get_supervisor()` | **First use**: `ProcurementSupervisor()` is created and builds three agents with `create_agent` |
| 3 | `agents.py` → `run_audit()` | Calls `_invoke_agent()` for risk, then tax, then control |
| 4 | LangChain agent loop | The model reads the prompt, **chooses a tool**, `tools.py` runs it, the result goes back to the model, repeat, then final text |
| 5 | `agents.py` | Fills `SYNTHESIS_PROMPT_TEMPLATE` with the three reports; one model call writes the memo |
| 6 | `endpoints.py` | Returns `AuditResponse` with four text fields |

#### 6.5 The server stops

`api/main.py` → `lifespan` → `_LOGGER_INSTANCE.flush_to_gcs()` uploads today's log file to `gs://<bucket>/logs/<timestamp>.log`. A second hook (`atexit`) in `logger/custom_logger.py` does the same if the first path is skipped; a flag prevents a double upload.

---

### 7. Why this arrangement works

| Property | How the structure provides it |
|---|---|
| You can start and demo the server with no cloud | Nothing external is created at import time |
| You can test without cloud accounts | Tests replace the two functions the routes call (`ask_question`, `get_supervisor`) |
| You can swap the model or database | Only `llm.py`, `embeddings.py` or `vector_store.py` change |
| Upload and bucket-import behave identically | Both call `ingest_pdf()` |
| Prompts can be tuned by non-programmers | They are plain text in `prompts.py` |
| Failures are visible | Every phase logs; every route turns exceptions into an HTTP 500 with the message |


---

<a id="chapter-06"></a>

## 06 · Google Cloud setup (paths B and C)

You will create a Google Cloud project, a robot account for GitHub, and let a GitHub workflow create everything else. Read [02](#chapter-02) first and create your budget alert.

Total time: about 30 minutes of work plus 30–45 minutes of waiting.

### Step 1 · Create a project

A **project** is the container for all your Google Cloud resources and billing.

1. Open https://console.cloud.google.com/ and sign in.
2. Click the project selector at the top → **New project**.
3. Name it, for example `meridian-ai`. Note the **Project ID** shown under the name (for example `meridian-ai-123456`). It must be globally unique, and you cannot change it later. You will use the ID, not the name.
4. Click **Create** and select the new project.

### Step 2 · Link billing

Cloud Run and Vertex AI do not work without a billing account linked to the project. The free trial credit is applied through this billing account.

1. Open **Billing** in the console menu.
2. Link a billing account to your project. If this is your first time, the free-trial sign-up is offered here.
3. Create the budget alert described in [02](#chapter-02) if you have not already.

### Step 3 · Install and sign in to the Google Cloud CLI

```bash
gcloud auth login
gcloud config set project YOUR_PROJECT_ID
gcloud config list
```

Replace `YOUR_PROJECT_ID` with the Project ID from step 1. `gcloud config list` should show your project.

### Step 4 · Create the deployer service account

A **service account** is an identity for a program instead of a person. GitHub will use this one to build and deploy on your behalf.

```bash
export PROJECT_ID="YOUR_PROJECT_ID"

## 1. Create the account
gcloud iam service-accounts create github-deployer \
  --display-name="GitHub Actions Deployer" \
  --project=$PROJECT_ID

## 2. Give it permission to create resources
gcloud projects add-iam-policy-binding $PROJECT_ID \
  --member="serviceAccount:github-deployer@${PROJECT_ID}.iam.gserviceaccount.com" \
  --role="roles/editor"

## 3. Give it permission to manage access settings
gcloud projects add-iam-policy-binding $PROJECT_ID \
  --member="serviceAccount:github-deployer@${PROJECT_ID}.iam.gserviceaccount.com" \
  --role="roles/resourcemanager.projectIamAdmin"

## 4. Create a key file
gcloud iam service-accounts keys create github-deployer-key.json \
  --iam-account=github-deployer@${PROJECT_ID}.iam.gserviceaccount.com
```

On Windows PowerShell, replace `export PROJECT_ID="..."` with `$env:PROJECT_ID="..."` and `$PROJECT_ID` with `$env:PROJECT_ID`.

> **Security notes**
> - `github-deployer-key.json` is a powerful credential. **Never commit it**, email it, or paste it anywhere except the GitHub secret in step 6. Delete the local copy after you have added it to GitHub.
> - The `editor` and `projectIamAdmin` roles are broad. They keep this tutorial simple. A production project would give a deployer only the specific roles it needs, and would use *Workload Identity Federation* so that no key file exists at all ([20](#chapter-20)).
> - If the key is ever exposed, delete it: Console → IAM & Admin → Service accounts → `github-deployer` → Keys → delete.

### Step 5 · Get your copy of the code on GitHub

The deployment workflow runs in **your own** GitHub repository. (Terraform is not required: the workflow creates everything. See [15](#chapter-15) for how, and for the optional Terraform alternative.)

1. On the project's GitHub page choose **Fork** (or create a new repository and push the code to it).
2. Open the **Actions** tab of your fork. If GitHub shows a notice that workflows are disabled on forks, enable them.

### Step 6 · Add three GitHub secrets

In your repository: **Settings → Secrets and variables → Actions → New repository secret**.

| Secret name | Value |
|---|---|
| `GCP_PROJECT_ID` | Your Project ID, e.g. `meridian-ai-123456` |
| `GCP_CREDENTIALS_JSON` | The **entire contents** of `github-deployer-key.json`, including the braces |
| `GOOGLE_API_KEY` | Your Gemini API key from AI Studio |

### Step 7 · Run the deployment workflow

1. Open **Actions → Deploy to GCP Cloud Run → Run workflow** (choose your branch).
   The workflow also starts automatically on every push to `main`.
2. The workflow performs these stages (each is a step you can expand in the log):

   | Stage | What happens |
   |---|---|
   | Authenticate | Signs in with the service-account key |
   | Enable APIs | Switches on the Google APIs the project needs, then waits 90 seconds |
   | Storage | Creates the bucket `<project-id>-vector-staging` |
   | Vector Search | Creates a small starter file, an index, an endpoint, and deploys the index to the endpoint. **The first run takes 30–45 minutes** |
   | Secrets | Stores your Gemini key in Secret Manager and lets Cloud Run read it |
   | Build | Cloud Build builds the Docker image |
   | Deploy | Cloud Run starts the service and gives it a public URL |
   | Public access | Allows anyone with the URL to open it |

3. Wait until the run shows a green check. Later runs take a few minutes because the index already exists.

### Step 8 · Collect the values you need locally

You need three things from the run.

**The Vector Search index and endpoint IDs.** Either read them from the workflow log (step *Provision Vector Search Index & Endpoint*, lines starting `Created Index:`, `Index already exists:`, `Created Endpoint:` or `Endpoint already exists:`) or ask Google Cloud:

```bash
gcloud ai indexes list --region=us-central1
gcloud ai index-endpoints list --region=us-central1
```

Copy the ID shown for `financial-docs-production` (index) and `financial-docs-endpoint` (endpoint). Either the plain number or the full `projects/…/indexes/…` path works in `.env`.

**The public URL.** In the *Deploy to Cloud Run* step log, find `Service URL: https://…run.app`.

**The bucket name.** `<project-id>-vector-staging`.

### Step 9 · What now exists in your project

Check in the console that you can see them:

| Resource | Where to look |
|---|---|
| Bucket `<project-id>-vector-staging` | Cloud Storage → Buckets |
| Index and endpoint | Vertex AI → Vector Search |
| Secret `GOOGLE_API_KEY` | Security → Secret Manager |
| Image | Artifact Registry |
| Service `meridian-ai-cloud-run` | Cloud Run |

> **Cost reminder:** the deployed Vector Search index is billing by the hour right now. See the warning in [02](#chapter-02) and the cleanup steps in [17](#chapter-17).

### Next

[07 · Run it locally](#chapter-07), using the IDs you just collected.


---

<a id="chapter-07"></a>

## 07 · Run the project on your computer

Two stages. **Stage 1** needs only a Gemini API key and gives you the audit feature. **Stage 2** adds document Q&A and needs the cloud resources from [06](#chapter-06).

All commands are run from the **project root folder** (the folder that contains `backend/`, `frontend/` and `README.md`). This matters: settings are read from the `.env` file in the folder you run from.

### Stage 0 · Get the code and install packages

```bash
git clone https://github.com/mayank953/meridian-ai-learner-edition.git
cd meridian-ai-learner-edition

python3.12 -m venv .venv
source .venv/bin/activate          # Windows PowerShell: .venv\Scripts\Activate.ps1
pip install -r requirements-dev.txt
```

If you downloaded a ZIP instead of cloning, unzip it, open a terminal in the unzipped folder (it contains `backend/`, `frontend/` and `README.md`) and continue from `python3.12 -m venv .venv`. If you forked the repository in the Google Cloud setup guide (doc 06), clone your fork instead.

Check that the automated tests pass. They need no accounts:

```bash
pytest backend/tests
```

Expected: `8 passed`.

### Stage 1 · Audit only (Gemini key only)

1. Create your settings file:
   ```bash
   cp .env.example .env              # Windows: copy .env.example .env
   ```
2. Open `.env` and set at least:
   ```
   GOOGLE_API_KEY=your-gemini-api-key
   ```
   The other values can stay as they are for now.
3. Start the backend:
   ```bash
   uvicorn api.main:app --app-dir backend --reload --port 8080
   ```
   Wait for `Application startup complete`.
4. Open http://localhost:8080/docs. This is the automatically generated API page.
5. Check it is alive: expand `GET /api/health` → **Try it out** → **Execute**. You should get `{"status": "ok"}`.
6. Run an audit: expand `POST /api/agent/audit` → **Try it out** and use this body:
   ```json
   {
     "request_text": "Purchase Request - Aldermoor Industries Global Procurement:\n- Vendor: Takumi Controls Europe B.V. (Netherlands)\n- Item: Industrial PLC Controllers + HMI Panels (Qty: 200)\n- Total Cost: 480,000 EUR\n- Origin: JP (Japan)\n- Destination: DE (Aldermoor Industries, Hamburg, Germany)\n- FX Rate quoted: 1 EUR = 163.5 JPY"
   }
   ```
   Click **Execute**. The audit makes several model calls, so it takes a while. Expect from several seconds to a minute or more.
7. The response has four parts: `risk_result`, `tax_result`, `control_result`, `cfo_memo`.

**What you should see:** each report follows the exact format defined in `backend/agent/prompts.py`. The wording differs from run to run because the model writes it, but the structure stays the same. The vendor in the example is fictional and unknown to the model, so expect a cautious risk assessment.

**Try a second request** with the exchange rate changed to `1 EUR = 190 JPY`. The tax report should flag a difference from the market rate of more than 5 % (`FX ALERT`), and the CFO memo should then say **CONDITIONAL HOLD**.

#### Add the user interface

Open a **second terminal** (keep the backend running):

```bash
cd frontend
npm install
npm run dev
```

Open http://localhost:3000 and use the **Audit** tab. The page sends its requests directly to `http://localhost:8080`.

### Stage 2 · Document Q&A (needs the cloud resources)

1. **Sign in to Google Cloud for your code.** Choose one:

   *Option 1, your own login (no key file):*
   ```bash
   gcloud auth application-default login
   gcloud auth application-default set-quota-project YOUR_PROJECT_ID
   ```
   *Option 2, the service-account key:* put the JSON file in a folder named `credentials/` and set `GCP_SERVICE_ACCOUNT_PATH=./credentials/service-account.json` in `.env`. The `credentials/` folder is ignored by Git.

2. **Fill in `.env`:**
   ```
   ENVIRONMENT=local
   GCP_PROJECT_ID=YOUR_PROJECT_ID
   GCP_REGION=us-central1
   GOOGLE_API_KEY=your-gemini-api-key
   GCS_BUCKET_NAME=YOUR_PROJECT_ID-vector-staging
   GCS_PREFIX=uploads/
   VECTOR_SEARCH_INDEX_ID=<from doc 06, step 8>
   VECTOR_SEARCH_INDEX_ENDPOINT_ID=<from doc 06, step 8>
   ```
3. Restart the backend (stop with `Ctrl+C`, start again).
4. Open http://localhost:8080/api/status. The project, region, bucket and IDs should show your values.
5. Upload the sample documents in the **Document Upload** tab, or call `POST /api/rag/upload` in `/docs`. The four PDFs are in `course/sample_docs/`. Each upload reports `pages` and `chunks`.
6. Ask questions in the **RAG Q&A** tab. A short wait after uploading may be needed before new chunks become searchable.

| Question | Answer found in the sample documents |
|---|---|
| What is Aldermoor Industries total revenue in FY2024? | EUR 2.84 billion |
| What are the standard payment terms for servo motor suppliers? | Net-45 (for vendors with a credit score of 75 or higher) |
| What EU customs duty applies to PLC controllers imported from Japan? | 2.2 % |
| What is the IFRS depreciation schedule for filling line equipment? | 10 years, straight line |

7. Ask something that is not in the documents, for example "Who won the 2018 World Cup?". The answer should say it does not know. The prompt tells the model to answer only from the retrieved context.
8. Try the three retrieval options (Normal, Multi-Query, Contextual Compression) and compare answers and speed.

To recreate the sample PDFs: `python course/sample_docs/generate_sample_docs.py`.

### Stage 3 · Run it in Docker (optional)

```bash
docker build -t meridian-ai .

docker run -p 8080:8080 \
  --env-file .env \
  -e GOOGLE_APPLICATION_CREDENTIALS=/creds/service-account.json \
  -v "$(pwd)/credentials:/creds:ro" \
  meridian-ai
```

Open http://localhost:8080. One container now serves the user interface and the API. The image contains no `.env` and no credentials; you supply them when you run it.

### Common problems

| Message or symptom | See |
|---|---|
| `ModuleNotFoundError: No module named 'api'` | Run from the project root with `--app-dir backend` |
| Settings seem empty | `.env` is read from the folder you run from |
| `index_id is required for api_version='v1'` | Set `VECTOR_SEARCH_INDEX_ID` and the endpoint ID |
| `403` from Cloud Storage or Vertex AI | [18 · Troubleshooting](#chapter-18) |
| Port 8080 already in use | Stop the other program or use `--port 8081` |


---

<a id="chapter-08"></a>

## 08 · The web API (`backend/api/`)

The API is the part of the program that a browser (or any other program) can talk to over HTTP. It is built with **FastAPI** and run by **Uvicorn**.

### Concepts

| Term | Meaning |
|---|---|
| **Endpoint / route** | A URL plus an HTTP method, e.g. `POST /api/rag/ask` |
| **Request / response** | What the caller sends and what it gets back, here as JSON |
| **Pydantic model** | A Python class that describes the expected shape of data and checks it automatically |
| **Router** | A group of related routes |
| **CORS** | A browser rule about which websites may call your API |
| **Uvicorn** | The server program that runs the FastAPI app |

### A minimal FastAPI app

```python
from fastapi import FastAPI
app = FastAPI()

@app.get("/hello")
def hello():
    return {"message": "hello"}
```

Run it with `uvicorn file_name:app --reload`, then open `http://localhost:8000/hello` and `http://localhost:8000/docs`. Meridian's API follows the same pattern, with more routes.

### `schemas.py` — the shapes of data

```python
class AuditRequest(BaseModel):
    request_text: str

class AuditResponse(BaseModel):
    risk_result: str
    tax_result: str
    control_result: str
    cfo_memo: str

class QueryRequest(BaseModel):
    query: str
    retriever_type: str = "similarity"

class QueryResponse(BaseModel):
    answer: str
```

If a caller sends a body without `query`, FastAPI rejects it with status **422** and names the missing field. You do not write that check yourself. The same classes produce the documentation at `/docs`.

### `endpoints.py` — the routes

Routers group the URLs:

```python
health_router = APIRouter(prefix="/api", tags=["Health"])
status_router = APIRouter(prefix="/api", tags=["Status"])
agent_router  = APIRouter(prefix="/api/agent", tags=["Agent"])
rag_router    = APIRouter(prefix="/api/rag", tags=["RAG"])
```

Each route is short. It validates input (through the schema), calls one function from `rag/` or `agent/`, and returns the result. The question route:

```python
@rag_router.post("/ask", response_model=QueryResponse)
def rag_query(payload: QueryRequest):
    try:
        return QueryResponse(answer=ask_question(payload.query, payload.retriever_type))
    except Exception as e:
        log.error("RAG query failed", error=str(e))
        raise HTTPException(status_code=500, detail=str(e))
```

When something goes wrong the route returns status 500 and the real error text in `detail`. The front end shows this message, and so do the troubleshooting tips in [18](#chapter-18).

#### Upload is `async`; the others are not

`POST /api/rag/upload` is declared `async def` because it must `await` the uploaded file. Embedding a document is slow, blocking work, so it is handed to a worker thread:

```python
summary = await run_in_threadpool(ingest_pdf, local_path, f"upload://{upload.filename}")
```

This keeps the server responsive to other requests, such as the health check, while a large PDF is processed.

#### The audit route builds its supervisor on first use

```python
@lru_cache(maxsize=1)
def get_supervisor() -> ProcurementSupervisor:
    return ProcurementSupervisor()
```

`lru_cache` makes the function run once and remember the result. The agents are created at the first audit request, not when the server starts.

### `main.py` — putting it together

`main.py` creates the `FastAPI` app, adds the CORS middleware, registers the four routers and, if the folder `frontend/dist` exists (inside Docker and Cloud Run), serves the built React application:

- `/assets/...` is served as static files.
- Any other path returns the file if it exists, otherwise `index.html`, so the React app can handle its own pages.
- Unknown URLs that start with `/api/` return a 404 error instead of the web page.
- A path check makes sure requests cannot read files outside the `dist` folder.

A `lifespan` function runs when the server stops and uploads the log file to Cloud Storage.

CORS is set to allow all origins (`allow_origins=["*"]`). That is convenient for learning. For a real product, list only your own domain(s).

### `config/settings.py` — settings in one place

```python
class Settings(BaseSettings):
    llm_model_name: str = Field("gemini-3.8-flash", validation_alias="VERTEX_LLM_MODEL_NAME")
    embedding_model_name: str = Field("text-embedding-005", validation_alias="VERTEX_EMBEDDING_MODEL_NAME")
    ...
    model_config = SettingsConfigDict(env_file=".env", ...)
```

`pydantic-settings` reads environment variables and the `.env` file and turns them into typed attributes (`settings.GCP_PROJECT`, …). The rest of the code imports `settings`; no other file reads `.env`.

### Try it yourself

1. Start the backend. In `/docs`, send `POST /api/rag/ask` with the body `{}`. Read the 422 response.
2. Open `/api/status`. Change `GCP_REGION` in `.env`, restart, and open it again.
3. In `endpoints.py` add a route `GET /api/ping` that returns the current time. Reload `/docs` to see it appear.


---

<a id="chapter-09"></a>

## 09 · FastAPI in depth

[08](#chapter-08) shows this project's API files. This page explains the ideas underneath, so that you understand *why* the code is written the way it is. The runnable file `docs/examples/01_fastapi_hello.py` goes with this page.

---

### 1. What is a web API, concretely?

A program on one computer (the *client*) sends a text message to a program on another (the *server*), and gets a text message back. The rules of the conversation are called **HTTP**.

A request has:

| Part | Example | Meaning |
|---|---|---|
| **Method** | `POST` | What kind of action. `GET` = read, `POST` = send data to be processed, `PUT`/`PATCH` = update, `DELETE` = remove |
| **URL / path** | `/api/rag/ask` | Which thing you are talking to |
| **Query string** | `?shout=true` | Optional extra settings in the URL |
| **Headers** | `Content-Type: application/json` | Information about the message |
| **Body** | `{"query": "What is..."}` | The data itself (for `POST`) |

A response has a **status code** and (usually) a body:

| Code | Meaning | Where this project returns it |
|---|---|---|
| `200` | OK | normal success |
| `400` | Bad request | `POST /api/rag/upload` with no files |
| `404` | Not found | an unknown `/api/...` URL |
| `422` | Your data has the wrong shape | FastAPI, automatically, when the body does not match the schema |
| `500` | The server failed | any exception in a route (the message is in `detail`) |

**JSON** is the text format both sides use: `{"query": "hello", "retriever_type": "similarity"}`. It maps directly to Python dictionaries and lists.

You can watch real traffic: in a browser press F12 → **Network**, click a button in the app, and click the request.

### 2. What FastAPI does for you

You write ordinary Python functions. FastAPI:

1. matches the incoming URL and method to a function (**routing**);
2. converts the request into Python values and **checks** them against your type hints (**validation**);
3. calls your function;
4. converts the return value into JSON (**serialisation**), checking it against `response_model` if you gave one;
5. generates interactive documentation at `/docs` and a machine-readable description at `/openapi.json`.

Look at this route from the project:

```python
@rag_router.post("/ask", response_model=QueryResponse)
def rag_query(payload: QueryRequest):
    return QueryResponse(answer=ask_question(payload.query, payload.retriever_type))
```

Everything is declared by the *type hint* `payload: QueryRequest`. FastAPI reads it and knows: "the body must be JSON, with a `query` string and an optional `retriever_type` string".

### 3. FastAPI, Uvicorn and ASGI

- **FastAPI** is the framework: your routes and rules.
- **Uvicorn** is the server process that listens on a network port, receives the raw bytes, and passes requests to FastAPI.
- **ASGI** is the agreed interface between them. It is why you start the app with `uvicorn api.main:app`: *module path* `api.main`, then the *variable* `app` inside it.
- `--reload` restarts the server when you save a file (development only). `--port 8080` chooses the port. `--app-dir backend` adds the `backend/` folder to Python's search path.

### 4. The life of one request

```
 client ─► Uvicorn ─► middleware (CORS) ─► router matches path+method
                                              │
                      validate path/query/body against type hints  ──► 422 if wrong
                                              │
                                  your function runs  ──► exception? ──► 500 (or your HTTPException)
                                              │
                      check/convert result with response_model
                                              │
 client ◄── Uvicorn ◄── middleware ◄───── response
```

### 5. Pydantic: the data-checking engine

A Pydantic model is a class whose attributes have types:

```python
class QueryRequest(BaseModel):
    query: str
    retriever_type: str = "similarity"   # has a default → optional
```

- `{"query": "hi"}` is accepted; `retriever_type` becomes `"similarity"`.
- `{}` is rejected: *Field required*.
- `{"query": 5}` — Pydantic tries to convert; failing that, it is rejected.

The same library powers **settings**: `pydantic-settings` reads environment variables and converts the text `"0.0"` into the number `0.0` ([10](#chapter-10)).

Try `docs/examples/01_fastapi_hello.py`: it adds a rule `quantity > 0` and shows the exact error messages.

### 6. Routers: keeping routes organised

```python
health_router = APIRouter(prefix="/api", tags=["Health"])
rag_router    = APIRouter(prefix="/api/rag", tags=["RAG"])

@rag_router.post("/ask")        # full path: /api/rag/ask
```

- `prefix` is added in front of every route in the router.
- `tags` group the routes in `/docs`.
- `app.include_router(rag_router)` in `main.py` plugs the group into the app.

Why use routers? In a small app you could write `@app.post(...)` everywhere. Routers let you define routes in one file and assemble the app in another, which is how `endpoints.py` and `main.py` are split.

### 7. `def` or `async def`? (the most confusing FastAPI topic)

A server handles many requests at the same time. There are two ways to do that:

| Style | How it works | In this project |
|---|---|---|
| **`def` (normal function)** | FastAPI runs it in a **thread pool**: a set of helper threads. While one thread waits for Gemini, other threads serve other requests | Almost every route |
| **`async def`** | Runs on the main **event loop**. Inside it you use `await` for operations that wait (network, files). While one request awaits, the loop serves others. **But any slow, non-awaited code inside blocks everybody** | `upload_documents` |

`upload_documents` is `async def` because it must `await upload.read()` to read the file. But embedding PDF text is slow, ordinary Python. Running it directly would freeze the event loop, so even `/api/health` would stop answering. The fix is in the code:

```python
summary = await run_in_threadpool(ingest_pdf, local_path, f"upload://{upload.filename}")
```

`run_in_threadpool` moves the slow function onto a helper thread and `await`s its result.

Rule of thumb: **use plain `def` unless you need `await`; never run slow blocking code directly inside `async def`.**

### 8. Errors

Any exception that nobody catches becomes a bare `500 Internal Server Error`. The routes here catch exceptions, log them, and raise:

```python
raise HTTPException(status_code=500, detail=str(e))
```

This returns `{"detail": "..."}`. The React code in `api.ts` reads `body.detail` and shows it to the user, so the real error is visible in the browser, not only in the terminal. (In a public production system you might hide internal error text from users.)

### 9. Middleware and CORS

**Middleware** is code that wraps every request and response. This project uses one: `CORSMiddleware`.

**The problem CORS solves:** a browser, for safety, stops a web page from `http://localhost:3000` calling an API at a *different origin* (`http://localhost:8080`) unless the API says that is allowed. Before the real request the browser sends a small "preflight" `OPTIONS` request asking permission. The middleware answers it.

```python
app.add_middleware(CORSMiddleware, allow_origins=["*"], allow_credentials=True,
                   allow_methods=["*"], allow_headers=["*"])
```

`allow_origins=["*"]` means *any* website may call this API from a browser. That is convenient while learning. In production you list your own site(s). When the app runs in Docker/Cloud Run, the page and the API come from the same address, so CORS does not apply at all.

If you ever see *"blocked by CORS policy"* in the browser console, the API is unreachable or answered with an error that lacked the CORS headers. See [18](#chapter-18).

### 10. Lifespan: running code at start and stop

```python
@asynccontextmanager
async def lifespan(app):
    yield                              # the app serves requests while paused here
    _LOGGER_INSTANCE.flush_to_gcs()    # runs once, on shutdown
```

Code before `yield` runs at startup; code after runs at shutdown. This project uses only the shutdown half, to upload the log file. (This replaces the older `@app.on_event("shutdown")` decorator, which FastAPI has deprecated.)

### 11. Serving the React app from the same server

In `main.py`, if the folder `frontend/dist` exists, the API also serves the website:

```python
app.mount("/assets", StaticFiles(directory=".../assets"), name="assets")

@app.get("/{catchall:path}", include_in_schema=False)
def serve_frontend(catchall: str): ...
```

Order matters: the routers are registered **first**, so `/api/...` URLs reach your API routes. The *catch-all* route comes last and matches everything else, returning a real file if one exists, otherwise `index.html`, so the browser-side router can show the right page. The function returns a 404 for unknown `/api/` paths so typos in API URLs are not hidden behind the web page, and it checks that the requested file is inside `dist/` so nobody can read other files on the server.

### 12. Dependencies with `lru_cache`: create once, reuse

```python
@lru_cache(maxsize=1)
def get_supervisor() -> ProcurementSupervisor:
    return ProcurementSupervisor()
```

`lru_cache(maxsize=1)` remembers the result of the first call. Every later call returns the same object without rebuilding. Used for the supervisor, the chat model, the embedding model and the vector-store connection. Two benefits: nothing expensive happens at import time, and each object is created exactly once.

(FastAPI also has its own `Depends(...)` system for sharing resources. This project does not need it.)

### 13. Testing the API without a server

FastAPI includes `TestClient`, which calls your app in memory:

```python
from fastapi.testclient import TestClient
client = TestClient(app)
assert client.get("/api/health").json() == {"status": "ok"}
```

To test a route that would call Gemini, replace the function it calls with a stand-in. `monkeypatch` is a pytest tool for swapping things temporarily:

```python
monkeypatch.setattr(endpoints, "ask_question", lambda query, retriever_type: "stub answer")
res = client.post("/api/rag/ask", json={"query": "hello"})
assert res.json() == {"answer": "stub answer"}
```

This works because `endpoints.py` calls `ask_question` as a name inside its own module. See `backend/tests/test_api.py`.

### 14. Common mistakes

| Mistake | Symptom | Fix |
|---|---|---|
| Starting uvicorn from the wrong folder | `ModuleNotFoundError: No module named 'api'` | Run from the project root with `--app-dir backend` |
| Slow code inside `async def` | The whole server freezes during one request | Use `def`, or `run_in_threadpool` |
| Forgetting `response_model` fields | Extra data silently dropped or missing | Match the model to what you return |
| Reading settings at import time from an unset variable | Value is empty | Run from the folder that holds `.env`; check `/api/status` |
| Catch-all route placed before API routers | Every `/api/...` call returns the web page | Register routers first |

### 15. Exercises

1. Run `docs/examples/01_fastapi_hello.py`; in `/docs` trigger each of the 422 and 400 responses.
2. Add a `DELETE /orders/{id}` route and look at it in `/docs`.
3. Make a slow route with `async def` and `time.sleep(10)`, then call `/hello` in another tab. Change `async def` to `def` and repeat. What changes?
4. In the main project, send `POST /api/rag/ask` with an empty body. Read the 422 message.


---

<a id="chapter-10"></a>

## 10 · Configuration and logging

Two small packages, `backend/config/` and `backend/logger/`, are used by almost every other file. Understanding them removes a lot of mystery from the rest of the code.

---

### Part A · Configuration

#### A1. The problem

The program needs values that differ between computers and must sometimes stay secret: the project ID, the bucket, the model name, the API key. If they were typed into the code you would have to edit code to change them, and secrets would be committed to Git.

#### A2. The solution: environment variables

An **environment variable** is a named value held by the operating system for a running program. Examples: `GOOGLE_API_KEY`, `GCP_REGION`. Your Python code can read them with `os.environ`. You can see them:

```bash
export GCP_REGION=europe-west1       # set one for this terminal
echo $GCP_REGION                      # read it back
```

#### A3. Where the values come from, in priority order

| Priority | Source | Typical use |
|---|---|---|
| 1 (highest) | A real environment variable | Cloud Run, Docker `-e`, a one-off `GCP_REGION=x python ...` |
| 2 | The `.env` file in the folder you run from | Your computer |
| 3 | The default written in `settings.py` | Sensible fallback |

Run `docs/examples/06_settings_demo.py` and then `GCP_REGION=europe-west1 python 06_settings_demo.py` to watch priority 1 beat priority 3.

#### A4. `backend/config/settings.py`

```python
class Settings(BaseSettings):
    app_name: str = "Meridian AI - Procurement Intelligence"
    GOOGLE_API_KEY: str = Field("", validation_alias="GOOGLE_API_KEY")
    GCP_PROJECT: str = Field("", validation_alias="GCP_PROJECT_ID")
    llm_model_name: str = Field("gemini-3.8-flash", validation_alias="VERTEX_LLM_MODEL_NAME")
    llm_temperature: float = Field(0.0, validation_alias="LLM_TEMPERATURE")
    ...
    model_config = SettingsConfigDict(env_file=".env", env_file_encoding="utf-8", extra="ignore")

settings = Settings()
```

- Each attribute is a setting. `validation_alias` is the **environment variable name** to read (the Python name and the variable name differ for some, e.g. `GCP_PROJECT` ← `GCP_PROJECT_ID`).
- Types are enforced: `LLM_TEMPERATURE=abc` stops the program with a clear error; `"0.5"` becomes the number `0.5`.
- `env_file=".env"` is **relative to the folder you run from**. That is why commands must be run from the project root.
- `extra="ignore"` lets `.env` contain variables the class does not list.
- `settings = Settings()` is created once, at import. Every module does `from config.settings import settings`.

At the bottom of the file, if `GCP_SERVICE_ACCOUNT_PATH` points to an existing file, the code sets the standard variable `GOOGLE_APPLICATION_CREDENTIALS` so Google's libraries find your key.

#### A5. The complete list of settings

| `.env` name | Python attribute | Default | Used by |
|---|---|---|---|
| `ENVIRONMENT` | `app_env` | `""` | information only |
| `GOOGLE_API_KEY` | `GOOGLE_API_KEY` | `""` | `rag/llm.py` |
| `GCP_PROJECT_ID` | `GCP_PROJECT` | `""` | Vertex AI, Storage |
| `GCP_REGION` | `GCP_REGION` | `""` | Vertex AI |
| `GCS_BUCKET_NAME` | `GCS_BUCKET_NAME` | `""` | uploads, staging, log upload |
| `GCS_PREFIX` | `GCS_PREFIX` | `""` | folder for uploads (use `uploads/`) |
| `GCP_SERVICE_ACCOUNT_PATH` | `gcp_service_account_path` | `""` | credentials file |
| `VERTEX_LLM_MODEL_NAME` | `llm_model_name` | `gemini-3.8-flash` | chat model |
| `LLM_TEMPERATURE` | `llm_temperature` | `0.0` | randomness of answers |
| `VERTEX_EMBEDDING_MODEL_NAME` | `embedding_model_name` | `text-embedding-005` | embeddings (768 numbers) |
| `VECTOR_SEARCH_INDEX_ID` | `vector_search_index_id` | `""` | vector database |
| `VECTOR_SEARCH_INDEX_ENDPOINT_ID` | `vector_search_index_endpoint_id` | `""` | vector database |

#### A6. Where each environment keeps its settings

| Place | Mechanism |
|---|---|
| Your computer | `.env` file (never committed) |
| Docker locally | `docker run --env-file .env` |
| Cloud Run | `--set-env-vars` for plain values and `--update-secrets` for the API key (in `deploy.yml`) |
| GitHub Actions | Repository secrets (`GCP_PROJECT_ID`, `GCP_CREDENTIALS_JSON`, `GOOGLE_API_KEY`) |
| Tests | `backend/tests/conftest.py` sets fake values |

#### A7. Rules

1. Never commit `.env` or a service-account file. Both are in `.gitignore` and `.dockerignore`.
2. Add every new setting to `Settings` **and** to `.env.example`.
3. Read settings only through `settings`; never call `os.environ` in other files.

---

### Part B · Logging

#### B1. Why log at all?

When a program runs on a server you cannot watch it. Logging is the program writing a **diary**: what it started, what it finished, what went wrong. When a learner says "it doesn't work", the diary is how you find out why. `print()` is not enough because it has no importance level, no timestamp, no structure and cannot be filtered.

#### B2. Log levels

Every message has a level that says how serious it is:

| Level | Use for | Example in this project |
|---|---|---|
| `DEBUG` | Detail for developers | (not used) |
| `INFO` | Normal progress | `"Loaded PDF from GCS"`, `"Phase complete"` |
| `WARNING` | Something odd that was handled | `"No chunks extracted, skipping indexing"` |
| `ERROR` | An operation failed | `"Upload failed"`, `"RAG query failed"` |
| `CRITICAL` | The program cannot continue | (not used) |

A logger set to a level shows that level and everything more serious. This project's handlers are set to `INFO`.

#### B3. Plain logs vs structured logs

Plain text:

```
2026-10-03 03:40:45 INFO Loaded PDF from GCS blob=policy.pdf pages=12
```

Structured (JSON), one object per line:

```json
{"blob": "policy.pdf", "pages": 12, "timestamp": "2026-10-02T22:10:45Z", "level": "info", "severity": "INFO", "event": "Loaded PDF from GCS"}
```

A person can read the first more easily, but a *program* cannot reliably pick out the number of pages. With the second, a logging service can answer "show all errors", "show everything with pages > 100", "count uploads per hour". The cloud tools used here (Cloud Logging) are built for it.

This project uses **structlog**, a library that produces structured logs. You pass the message and then named facts:

```python
log.info("Loaded PDF from GCS", blob=blob.name, pages=len(docs))
```

Run `docs/examples/02_logging_demo.py` to see both styles side by side.

#### B4. How the logger is built — `backend/logger/custom_logger.py`

```python
class CustomLogger:
    def __init__(self, log_dir="logs"):
        self.logs_dir = os.path.join(os.getcwd(), log_dir)       # a "logs" folder where you run the app
        os.makedirs(self.logs_dir, exist_ok=True)
        self._timestamp = datetime.now().strftime('%m_%d_%Y_%H_%M_%S')
        self.log_file_path = os.path.join(self.logs_dir, f"{self._timestamp}.log")
        atexit.register(self.flush_to_gcs)                        # run at program exit
```

`get_logger()` then does three things:

1. **Two destinations** ("handlers"): a `StreamHandler` (the console/terminal) and a `FileHandler` (the file in `logs/`). Both print just the message, because structlog has already formatted it.
2. **A processor chain** (steps each log line passes through, in order):

   | Processor | Effect |
   |---|---|
   | `TimeStamper(fmt="iso", utc=True, key="timestamp")` | adds `"timestamp": "2026-10-02T22:10:45Z"` |
   | `add_log_level` | adds `"level": "info"` |
   | `add_severity` (project code) | adds `"severity": "INFO"`, which Cloud Logging understands |
   | `EventRenamer(to="event")` | stores the message under the key `event` |
   | `JSONRenderer()` | turns the dictionary into one JSON line |

3. Returns a logger object. `cache_logger_on_first_use=True` speeds up later calls.

`logger/__init__.py` creates **one** shared instance and one shared logger:

```python
_LOGGER_INSTANCE = CustomLogger()
GLOBAL_LOGGER = _LOGGER_INSTANCE.get_logger("MeridianAI_Backend")
```

Every module starts with `from logger import GLOBAL_LOGGER as log`, so all log lines go to the same file in the same format.

#### B5. Why a `severity` field?

Cloud Run copies everything your program prints to Cloud Logging. Cloud Logging looks for a field named **`severity`** in a JSON line to decide whether an entry is shown as info, warning or error and to let you filter. Without it every line is just "default". The `add_severity` function in `custom_logger.py` copies the level into that field, upper-cased. The original `level` field is kept, so nothing breaks. A unit test (`test_log_lines_carry_a_severity_field_for_cloud_logging`) guards this.

#### B6. Why upload logs to Cloud Storage at shutdown?

A container's disk is temporary: when Cloud Run stops the container, the `logs/` folder disappears. `flush_to_gcs()` uploads the day's file to `gs://<bucket>/logs/<timestamp>.log` when the server stops (called from the `lifespan` function in `main.py`, and also through `atexit`). If `GCS_BUCKET_NAME` is empty (local runs, tests) it prints a one-line note and skips. A `_gcs_flushed` flag prevents uploading twice. This is a safety copy; in the cloud you would normally just read the live logs in Cloud Logging.

#### B7. What gets logged where

| Event | File | Level |
|---|---|---|
| Frontend not built | `api/main.py` | warning |
| Audit/RAG/ingestion failures | `api/endpoints.py` | error |
| File saved to GCS; chunks created | `api/endpoints.py`, `rag/data_ingestion.py` | info |
| RAG query received/answered | `rag/retrieval.py` | info |
| Each audit phase start/finish, with the result text | `agent/agents.py` | info |

> Logs contain the questions and answers. Do not put confidential data into the sample app, and treat the log files as sensitive.

#### B8. Reading logs

| Where | How |
|---|---|
| Your terminal | The JSON lines appear as the server runs |
| `logs/<timestamp>.log` | Same lines, saved. `grep '"severity": "ERROR"' logs/*.log` finds errors |
| Cloud Run | Console → Cloud Run → your service → **Logs** (or **Logs Explorer**). Filter `severity>=ERROR`, or text such as `Upload failed` |
| Bucket | `gs://<bucket>/logs/` after the server stopped |

Uvicorn's own access lines (`INFO: 127.0.0.1 - "POST /api/rag/ask" 200`) use Python's standard logging format, not JSON. That is normal.

#### B9. Adding your own log line

```python
from logger import GLOBAL_LOGGER as log

log.info("Vendor screened", vendor=vendor_name, result="CLEARED")
log.error("Credit lookup failed", vendor=vendor_name, error=str(e))
```

Guidelines: one event per line, a short constant message, and facts as keyword arguments (not glued into the message). Never log keys, passwords or whole documents.

#### B10. Exercises

1. Start the backend and call `GET /api/health`. Open `logs/` and find the newest file. What is in it?
2. Run an audit and follow the phase lines in the terminal.
3. Add a `log.info` line to `rag/retrieval.py` that records `len(response["answer"])`.
4. Run `docs/examples/02_logging_demo.py`; add a `log.warning(...)` of your own.
5. Cause an error (empty `VECTOR_SEARCH_INDEX_ID`) and find the resulting `"level": "error"` line.


---

<a id="chapter-11"></a>

## 11 · Document question answering — the RAG pipeline (`backend/rag/`)

**RAG** (Retrieval-Augmented Generation) lets a language model answer from *your* documents, which it has never seen in training.

```
Preparing (once per document)                  Asking (every question)
PDF → pages → chunks → embeddings → store      question → embedding → closest chunks
                                                          → prompt (chunks + question) → Gemini → answer
```

### Concepts

| Term | Meaning |
|---|---|
| **Chunk** | A short piece of a document (here about 1000 characters). Small pieces make search precise |
| **Overlap** | Consecutive chunks share some text (100 characters) so a sentence is not cut in half |
| **Embedding** | A list of numbers (here 768) that represents the *meaning* of a text. Texts with similar meaning have similar numbers |
| **Vector database** | Storage that can quickly find the stored vectors closest to a given vector |
| **Index** | In Vertex AI Vector Search: the stored vectors and the structure used to search them |
| **Endpoint** | The running service that answers searches against a deployed index. It bills by the hour |
| **Retriever** | The LangChain component that returns the best chunks for a question |

### `llm.py` — the chat model

```python
@lru_cache(maxsize=1)
def get_llm() -> ChatGoogleGenerativeAI:
    return ChatGoogleGenerativeAI(
        model=settings.llm_model_name,
        google_api_key=settings.GOOGLE_API_KEY,
        temperature=settings.llm_temperature,
    )
```

- It uses the **Gemini API key**, not Google Cloud credentials.
- `lru_cache` creates the model once and reuses it. Nothing is created at import time.
- `extract_text()` in the same file handles Gemini replies that arrive as a list of content blocks instead of plain text.

### `embeddings.py` — text to numbers

```python
@lru_cache(maxsize=1)
def get_embeddings() -> VertexAIEmbeddings:
    return VertexAIEmbeddings(model_name=settings.embedding_model_name)
```

- Uses Vertex AI and your **Google Cloud credentials**.
- `text-embedding-005` produces **768** numbers per text.
- The index was created with 768 dimensions (see `index_metadata.json` and the workflow). Documents and questions must use **the same** embedding model. If you change the model, create a new index.

Check it yourself (from the project root):

```bash
PYTHONPATH=backend python -c "from rag.embeddings import get_embeddings; print(len(get_embeddings().embed_query('servo motor')))"
```

Expected output: `768`.

### `vector_store.py` — the database connection

```python
@lru_cache(maxsize=1)
def get_vector_store() -> VectorSearchVectorStore:
    aiplatform.init(project=settings.GCP_PROJECT, location=settings.GCP_REGION)
    return VectorSearchVectorStore.from_components(
        project_id=settings.GCP_PROJECT,
        region=settings.GCP_REGION,
        embedding=get_embeddings(),
        index_id=settings.vector_search_index_id,
        endpoint_id=settings.vector_search_index_endpoint_id,
        gcs_bucket_name=settings.GCS_BUCKET_NAME,
        stream_update=True,
    )
```

- `stream_update=True` lets new documents become searchable within a short time. Without it, updates are applied in batches.
- The bucket is used for staging data when adding documents.
- If the index ID is empty you get `index_id is required for api_version='v1'`.

### `data_ingestion.py` — getting documents in

```python
CHUNK_SIZE = 1000
CHUNK_OVERLAP = 100

def split_into_chunks(pages):
    splitter = RecursiveCharacterTextSplitter(chunk_size=CHUNK_SIZE, chunk_overlap=CHUNK_OVERLAP)
    return splitter.split_documents(pages)

def ingest_pdf(local_path, source):
    pages = PyPDFLoader(local_path).load()
    for page in pages:
        page.metadata["source"] = source
    chunks = split_into_chunks(pages)
    if chunks:
        get_vector_store().add_documents(chunks)
    return {"pages": len(pages), "chunks": len(chunks)}
```

Step by step: load the PDF into pages → mark each page with where it came from → split into chunks → embed and store. `add_documents` calls the embedding model for you.

Two routes use `ingest_pdf`:

| Route | Source of the PDF |
|---|---|
| `POST /api/rag/upload` | Files uploaded from the browser |
| `POST /api/rag/ingest-gcs` | PDFs already in the Cloud Storage bucket (`ingest_data_from_gcs`) |

PDFs that contain only scanned images have no text to extract; the upload route reports them as skipped.

### `retrieval.py` — answering

```python
def ask_question(query, retriever_type="similarity") -> str:
    prompt = ChatPromptTemplate.from_messages([("system", SYSTEM_PROMPT), ("human", "{input}")])
    question_answer_chain = create_stuff_documents_chain(get_llm(), prompt)
    rag_chain = create_retrieval_chain(build_retriever(retriever_type), question_answer_chain)
    response = rag_chain.invoke({"input": query})
    return response["answer"]
```

Two chains:

1. `create_stuff_documents_chain` puts ("stuffs") the retrieved chunks into the prompt where `{context}` appears, then calls the model.
2. `create_retrieval_chain` runs the retriever first, then the first chain.

The system prompt tells the model to answer only from the context and say it does not know otherwise:

```
Use the following pieces of retrieved context to answer the question.
If you don't know the answer based on the context, say that you don't know.
```

#### Retrieval strategies

`build_retriever` returns one of three retrievers:

| Name | Behaviour | Trade-off |
|---|---|---|
| `similarity` | Closest 3 chunks | Fastest, cheapest |
| `multiquery` | Gemini writes several versions of the question; results are merged | Finds more, uses extra model calls |
| `contextual` | Fetch 10 chunks, then Gemini shortens each to the relevant sentences | Cleaner context, slowest |

#### A note on package names

`create_retrieval_chain` and the retrievers come from **`langchain-classic`** (imports start with `langchain_classic`). The agent code uses the current `langchain` package (`from langchain.agents import create_agent`). Both are in `requirements.txt`. Online examples mix old and new import paths, so check which package an import comes from.

### Try it yourself

1. Change `CHUNK_SIZE` to 300 in `data_ingestion.py`, upload a PDF again, and compare the answers.
2. Ask a question using each retriever type and note the response time.
3. Ask a question whose answer is not in your documents.
4. Read `index_metadata.json` and find `"dimensions": 768`.


---

<a id="chapter-12"></a>

## 12 · The audit agents (`backend/agent/`)

A RAG pipeline **answers questions**. An **agent** **does work**: it decides which tools to call, reads the results, and continues until it can give an answer.

### Concepts

| Term | Meaning |
|---|---|
| **Tool** | A Python function the model is allowed to call. The model reads its name, arguments and docstring to decide when to use it |
| **System prompt** | The standing instructions for an agent: role, responsibilities, how to decide, and exactly how to format the answer |
| **Agent** | A model + tools + a system prompt, running in a loop: think → call a tool → read the result → think again → answer |
| **Supervisor** | Ordinary Python code that runs several agents and combines their results |

### The five tools — `tools.py`

Each tool is a function marked with `@tool` from `langchain_core.tools`:

| Tool | Used by | What it does | Data source |
|---|---|---|---|
| `check_sanctions_list(vendor_name)` | Risk | Screens a vendor name against well-known sanctions lists | The model's general knowledge |
| `get_vendor_credit_score(vendor_name)` | Risk | Returns a score from 0–100 and a risk level (unknown vendors get 45) | The model's general knowledge |
| `calculate_cross_border_tax(amount, origin, destination)` | Tax | VAT/GST, import duty, total landed cost | The model's general knowledge |
| `validate_fx_hedge(currency_pair, rate_used)` | Tax | Compares the quoted exchange rate with the market rate; flags a difference above 5 % | **Live data** from `api.frankfurter.dev`; falls back to the model if it is unreachable |
| `categorize_expense(amount, item_description)` | Control | CapEx or OpEx, depreciation period, approval flags | The model's general knowledge |

> Four of the five tools ask the language model instead of calling real databases. That is a simplification for teaching. A real system would call a sanctions-screening service, a credit bureau, a tax engine, and so on.

How a tool is defined:

```python
@tool
def categorize_expense(amount: float, item_description: str) -> str:
    """Determines if the expense is Capital Expenditure (CapEx) or Operational (OpEx) using accounting standards."""
    ...
```

The docstring is part of the tool's description. The model uses it to decide when to call the tool, so write it clearly.

Each tool handles failure on its own. If the model call fails, it returns a message such as `SYSTEM WARNING: ... Manual review required.` rather than crashing the audit. Shared helpers: `_ask_llm()` (calls the model, catches errors) and `extract_text()` (normalises the reply).

### The prompts — `prompts.py`

There are four prompts. Each of the three agent prompts follows the same four parts:

1. **Role**: who the agent is
2. **Responsibilities**: what it is accountable for
3. **Decision framework**: which tool to call first, what thresholds to apply
4. **Output format**: an exact template for the answer

Example (shortened) from the risk prompt:

```
DECISION FRAMEWORK:
1. Run `check_sanctions_list` first — this is a hard blocker. A RED ALERT means immediate rejection.
2. Run `get_vendor_credit_score` next. Score ≥ 75 → LOW RISK ... Score < 50 → HIGH RISK ...

OUTPUT FORMAT — always respond in this exact structure:
SANCTIONS CHECK: [CLEARED / RED ALERT — reason]
CREDIT SCORE: [score] → [LOW / MODERATE / HIGH] RISK
...
```

A fixed output format makes the next step reliable. The CFO prompt looks for these exact words in the reports:

| Word | Comes from | Effect |
|---|---|---|
| `RED ALERT` | sanctions tool / risk prompt | Final decision: REJECTED |
| `FX ALERT` | exchange-rate tool | Final decision: CONDITIONAL HOLD |
| `HOLD FOR TREASURY AUDIT` | tax prompt | Final decision: CONDITIONAL HOLD |

If you rename one of these words, rename it everywhere.

All company details in the prompts (Aldermoor Industries, Hamburg, thresholds such as €250,000 and €1,000,000) are fictional.

### The supervisor — `agents.py`

Creating an agent takes one call:

```python
from langchain.agents import create_agent

def create_specialized_agent(tools, system_prompt):
    return create_agent(model=get_llm(), tools=tools, system_prompt=system_prompt)
```

The supervisor creates three agents, each with its own tools and prompt:

```python
self.risk_agent    = create_specialized_agent([check_sanctions_list, get_vendor_credit_score], RISK_AGENT_PROMPT)
self.tax_agent     = create_specialized_agent([calculate_cross_border_tax, validate_fx_hedge], TAX_AGENT_PROMPT)
self.control_agent = create_specialized_agent([categorize_expense], CONTROL_AGENT_PROMPT)
```

`run_audit()` runs them one after another and then asks the model for the CFO memo:

```python
risk_result    = self._invoke_agent(self.risk_agent, request)
tax_result     = self._invoke_agent(self.tax_agent, request)
control_result = self._invoke_agent(self.control_agent, request)

synthesis_prompt = SYNTHESIS_PROMPT_TEMPLATE.format(risk_result=..., tax_result=..., control_result=...)
cfo_memo = extract_text(self.llm.invoke(synthesis_prompt).content)
```

Calling an agent means passing it a message list and reading the last message:

```python
result = agent.invoke({"messages": [{"role": "user", "content": request}]})
text = extract_text(result["messages"][-1].content)
```

Each phase is written to the log, so you can follow an audit in the terminal.

The agents run **sequentially**. They could run in parallel because they do not depend on each other. Sequential code is easier to read and debug.

#### LangChain and LangGraph

`create_agent` is LangChain's standard way to build an agent. Internally it runs on **LangGraph**, which is why `langgraph` is listed in `requirements.txt` and appears in log output. This project does not write any LangGraph code. LangGraph itself is worth learning when you need loops, branches or shared state that a simple agent cannot express ([20](#chapter-20)).

#### Run the supervisor without the web server

From the `backend/` folder, with `GOOGLE_API_KEY` exported in your terminal (this run does not read `.env`, because `.env` is in the project root):

```bash
cd backend
GOOGLE_API_KEY=your-key python -m agent.agents
```

It audits a built-in sample request and prints the CFO memo.

### Things to know about agent output

- The model writes the text, so wording changes from run to run. The structure (headings and key words) should stay stable.
- Setting `LLM_TEMPERATURE=0` (the default) makes answers more repeatable. If a model repeats itself or loops, try `1.0`.
- A model can be wrong. Real audits keep a human in the loop.

### Try it yourself

1. Add a sixth tool, for example `check_delivery_risk(country: str)`, and give it to the control agent.
2. Change a threshold in `RISK_AGENT_PROMPT` (for example the 75 for "low risk") and run the same request again.
3. Submit a request with an exchange rate far from the market rate and read the CFO memo.
4. Remove the output-format section from one prompt. Compare the result and the CFO memo.


---

<a id="chapter-13"></a>

## 13 · The user interface (`frontend/`)

The interface is a **React** application written in **TypeScript**, built with **Vite**, styled with **Tailwind CSS** and **shadcn/ui** components. You do not need to know React to use or understand the rest of the project. This page shows how the interface connects to the backend.

### Files that matter

| File | Role |
|---|---|
| `src/lib/api.ts` | **All calls to the backend** are in this one file |
| `src/pages/Index.tsx` | Page layout and the tab navigation |
| `src/components/DocumentUploadTab.tsx` | Upload PDFs; button to import PDFs already in the bucket |
| `src/components/RagQATab.tsx` | Ask questions; choose the retrieval strategy |
| `src/components/AuditTab.tsx` | Enter a purchase request; shows the three reports and the memo |
| `src/components/SystemStatusTab.tsx` | Shows `/api/status` |
| `src/components/ui/` | Reusable buttons, cards and inputs (generated by shadcn/ui) |

### `api.ts`

```ts
const BASE_URL = import.meta.env.VITE_API_URL || (import.meta.env.DEV ? "http://localhost:8080" : "");
```

- While developing (`npm run dev`), the page calls the backend at `http://localhost:8080`.
- In production (the built files served by FastAPI), `BASE_URL` is empty, so calls go to the same address that served the page.
- Set `VITE_API_URL` if your backend runs somewhere else.

One small helper makes every call and turns errors into messages:

```ts
async function request<T>(path: string, options: RequestInit = {}): Promise<T> {
  const res = await fetch(`${BASE_URL}${path}`, options);
  if (!res.ok) {
    const body = await res.json().catch(() => ({}));
    throw new Error(body.detail || `HTTP ${res.status}`);
  }
  return res.json();
}
```

Then one function per endpoint, for example:

```ts
export async function askQuestion(query: string, retrieverType = "similarity") {
  return request<{ answer: string }>("/api/rag/ask", {
    method: "POST",
    headers: { "Content-Type": "application/json" },
    body: JSON.stringify({ query, retriever_type: retrieverType }),
  });
}
```

| UI action | Function | Endpoint |
|---|---|---|
| Upload | `uploadDocuments` | `POST /api/rag/upload` |
| Import from bucket | `triggerGcsIngestion` | `POST /api/rag/ingest-gcs` |
| Ask | `askQuestion` | `POST /api/rag/ask` |
| Run audit | `runAudit` | `POST /api/agent/audit` |
| Status | `getSystemStatus` | `GET /api/status` |

### Run and build

```bash
cd frontend
npm install
npm run dev        # development server on http://localhost:3000
npm run build      # creates frontend/dist (what the Docker image serves)
```

In your browser's developer tools, open the **Network** tab and click a button in the app to see the exact request and response for each action.


---

<a id="chapter-14"></a>

## 14 · Docker and Cloud Run

### Concepts

| Term | Meaning |
|---|---|
| **Image** | A packaged, read-only snapshot of an application and everything it needs |
| **Container** | A running copy of an image |
| **Dockerfile** | The recipe for building an image |
| **Multi-stage build** | A Dockerfile with several stages; only the last stage ends up in the final image |
| **Artifact Registry** | Google Cloud's storage for images |
| **Cloud Build** | Builds images in Google Cloud |
| **Cloud Run** | Runs containers on request, scaling from zero to many |

### The Dockerfile

The `Dockerfile` has two stages.

**Stage 1 — build the user interface (Node.js)**
```dockerfile
FROM node:20-alpine AS frontend-builder
WORKDIR /app/frontend
COPY frontend/package.json frontend/package-lock.json* ./
RUN if [ -f package-lock.json ]; then npm ci; else npm install; fi
COPY frontend/ ./
RUN npm run build
```
This installs the Node packages and creates the optimised website in `frontend/dist`.

**Stage 2 — the application (Python)**
```dockerfile
FROM python:3.12-slim AS backend-builder
WORKDIR /app
ENV PYTHONDONTWRITEBYTECODE=1
ENV PYTHONUNBUFFERED=1
RUN apt-get update && apt-get install -y --no-install-recommends build-essential && rm -rf /var/lib/apt/lists/*
COPY requirements.txt .
RUN pip install --no-cache-dir -r requirements.txt
COPY backend/ ./backend/
COPY --from=frontend-builder /app/frontend/dist /app/frontend/dist
EXPOSE 8080
CMD uvicorn api.main:app --app-dir backend --host 0.0.0.0 --port ${PORT:-8080}
```

Reading it line by line:

| Line | Meaning |
|---|---|
| `COPY requirements.txt` then `pip install` before copying the code | Docker caches each step. Package installation is slow, so it comes first and is only repeated when `requirements.txt` changes |
| `COPY --from=frontend-builder …` | Takes only the finished website from stage 1. Node.js itself does not enter the final image, which keeps it smaller |
| `--host 0.0.0.0` | Listen on all network interfaces inside the container |
| `--port ${PORT:-8080}` | Cloud Run tells the app which port to use through the `PORT` variable; default is 8080 |

`main.py` finds `frontend/dist` next to the backend and serves it, so **one container is the whole application**.

#### What is *not* in the image

`.dockerignore` excludes `.env`, `credentials/`, `.git/`, logs and `node_modules`. Secrets are supplied when the container runs, never baked into the image:

```bash
docker run -p 8080:8080 \
  --env-file .env \
  -e GOOGLE_APPLICATION_CREDENTIALS=/creds/service-account.json \
  -v "$(pwd)/credentials:/creds:ro" \
  meridian-ai
```

### Cloud Run

The workflow builds the image with Cloud Build and deploys it:

```bash
gcloud builds submit --tag <image> .
gcloud run deploy meridian-ai-cloud-run \
  --image <image> --region us-central1 --platform managed \
  --allow-unauthenticated --port 8080 --max-instances 3 \
  --set-env-vars="ENVIRONMENT=production,GCP_PROJECT_ID=...,..." \
  --update-secrets="GOOGLE_API_KEY=GOOGLE_API_KEY:latest"
```

| Option | Meaning |
|---|---|
| `--allow-unauthenticated` | Anyone with the URL can open the app |
| `--max-instances 3` | Never run more than three copies, which limits cost if someone floods the URL |
| `--set-env-vars` | Plain settings (project, region, bucket, model names, index IDs) |
| `--update-secrets` | Injects `GOOGLE_API_KEY` from Secret Manager as an environment variable |

Behaviour to know:

- **Scale to zero.** With no traffic no instance runs. The first request after a quiet period is slower (a *cold start*).
- **Temporary disk.** Files written inside the container disappear when it stops. That is why uploads are also stored in Cloud Storage and logs are uploaded on shutdown.
- **Identity.** The running service uses the project's default compute service account to reach Vertex AI, Cloud Storage and Secret Manager.

> **Public URL warning.** The deployed app has no sign-in. Anyone who finds the URL can upload files and run audits that use your Gemini quota. Delete the service when you are done ([17](#chapter-17)). Do not upload confidential documents.

### Image registry note

The workflow uses an image name of the form `gcr.io/<project>/…`. Google's older *Container Registry* has been shut down; `gcr.io` addresses now work only through Artifact Registry repositories. If the build or push step fails with a permission or "repository does not exist" error, see the GitHub Actions entry in [18 · Troubleshooting](#chapter-18).


---

<a id="chapter-15"></a>

## 15 · Provisioning — how the cloud resources get created

> **Short answer to a common question: this project provisions its cloud resources with GitHub Actions running `gcloud` commands (`.github/workflows/deploy.yml`). It does *not* use Terraform.** The folder `infra/terraform/` is an optional, equivalent way to do the same job, included for learning. Pick one approach per Google Cloud project.

---

### 1. What is "provisioning"?

Your code needs places to live and things to use: a storage bucket for PDFs, a vector database, a place to run the server, a locker for the API key. None of these exist in a new Google Cloud project. **Provisioning** means creating them (and the permissions that connect them). **Deployment** means putting a new version of your *code* onto them. This project's resources:

| Resource | What it is for |
|---|---|
| Enabled Google APIs | A service must be switched on in a project before you can use it |
| Cloud Storage bucket | PDFs, logs, index staging data |
| Vertex AI Vector Search index | Stores the vectors |
| Vertex AI Vector Search endpoint + deployed index | The running search service (billed by the hour) |
| Secret Manager secret | Holds the Gemini API key |
| Artifact Registry / image registry | Stores the Docker image |
| Cloud Run service | Runs the app |
| IAM permissions | Who may do what |

### 2. Three ways to create resources

| Way | How | Good | Bad |
|---|---|---|---|
| **A. Click in the console** | Web pages in console.cloud.google.com | Easiest to learn; nothing to install | Slow, error-prone, impossible to repeat exactly, undocumented |
| **B. Scripted commands** (what this project does) | A list of `gcloud` commands, run by a script or by GitHub Actions | Repeatable; the script *is* the documentation; no new tool | You must write "create only if it does not exist" logic yourself; no memory of what exists |
| **C. Infrastructure as Code with Terraform** | You *declare* what should exist; Terraform makes it so | Idempotent by design; shows a plan before changing; can destroy everything cleanly; tracks state | One more tool and language to learn; a state file to protect |

#### Imperative vs declarative

- **Imperative** (way B): you write the *steps*. "Create a bucket. Then create an index…". If you run it twice, you must guard against creating things twice.
- **Declarative** (way C): you write the *end result*. "There is a bucket named X." Terraform compares this with reality and does only what is missing.

### 3. What this project does: GitHub Actions + `gcloud`

`deploy.yml` is a recipe that GitHub runs on a temporary computer. The provisioning steps use the same pattern again and again: **check, then create only if missing.** This makes the workflow safe to re-run. Example from the bucket step:

```bash
if ! gcloud storage buckets describe gs://PROJECT-vector-staging >/dev/null 2>&1; then
  gcloud storage buckets create gs://PROJECT-vector-staging --location=us-central1 \
    --uniform-bucket-level-access --public-access-prevention
else
  echo "Vector bucket already exists."
fi
```

`describe` succeeds if the bucket exists; `!` negates it; so the `create` only runs on the first deployment. The same idea is used for the index, the endpoint, the deployed index and the secret.

Full step list: [16 · GitHub Actions](#chapter-16).

#### Pros and cons in this project

| Pro | Con |
|---|---|
| No extra tool: only `gcloud`, which you already install | No record of what was created. Deleting is done by hand ([17](#chapter-17)) |
| One file does provisioning **and** deployment | Long shell script with polling loops (`sleep 60`) to wait for slow operations |
| Easy to read top to bottom | Not safe against *drift* (someone changing resources in the console) |
| Re-runnable | Changing a setting on an existing resource needs extra code; the script only creates |

### 4. The optional Terraform version

Location: `infra/terraform/`. It declares the same resources. It is **not** used by the workflow and nothing in the application depends on it.

#### 4.1 Terraform in ten minutes

| Concept | Meaning | Example here |
|---|---|---|
| **Provider** | A plugin that knows how to talk to a platform | `hashicorp/google` in `versions.tf` |
| **Resource** | One thing to create | `resource "google_storage_bucket" "staging" { ... }` |
| **Variable** | An input you can change | `variable "project_id"` in `variables.tf` |
| **Output** | A value printed after creation | `service_url` in `outputs.tf` |
| **Reference** | One resource using another's value | `google_storage_bucket.staging.name` |
| **Dependency graph** | Terraform works out the creation order from references | The Cloud Run service waits for the secret, because it references it |
| **`depends_on`** | An explicit ordering when there is no reference | APIs must be enabled before resources |
| **`for_each`** | Create one resource per item in a list | One `google_project_service` per API |
| **State** | A file recording what Terraform created | `terraform.tfstate` (**git-ignored; contains secrets**) |
| **Plan** | A preview of what would change | `terraform plan` |
| **Apply / Destroy** | Make it so / remove everything it created | `terraform apply`, `terraform destroy` |

The four commands:

```bash
terraform init      # download the provider (once)
terraform plan      # show what would be created, changed or deleted - changes nothing
terraform apply     # do it (asks you to type yes)
terraform destroy   # remove everything Terraform created
```

#### 4.2 The files

| File | Contents |
|---|---|
| `versions.tf` | Required Terraform version, the Google provider, and its default project/region |
| `variables.tf` | Inputs: `project_id`, `region`, `gemini_api_key` (marked `sensitive`), `container_image`, model names, and the **cost-control knobs** `index_machine_type`, `index_replica_count`, `index_shard_size`, `cloud_run_max_instances` |
| `main.tf` | The resources (below) |
| `outputs.tf` | Prints the index ID, endpoint ID, bucket name, image repository and the service URL |
| `terraform.tfvars.example` | Template for your values |

Resources in `main.tf`, in the order they are declared:

| # | Resource | Equivalent step in `deploy.yml` |
|---|---|---|
| 1 | `google_project_service.apis` (one per API) | "Enable Required GCP APIs" |
| 2 | `google_storage_bucket.staging` + `google_storage_bucket_object.initial_embeddings` | "Ensure Storage Buckets Exist" + copying `init_embeddings.json` |
| 3 | `google_vertex_ai_index.documents` (768 dimensions, streaming updates) | `gcloud ai indexes create` |
| 4 | `google_vertex_ai_index_endpoint.documents` | `gcloud ai index-endpoints create` |
| 5 | `google_vertex_ai_index_endpoint_deployed_index.documents` | `gcloud ai index-endpoints deploy-index` |
| 6 | `google_secret_manager_secret` + `_version` | "Ensure Secret Manager Has API Key" |
| 7 | `google_artifact_registry_repository.images` | (the workflow uses `gcr.io` instead) |
| 8 | `google_service_account.app` + three `*_iam_member` grants | (the workflow uses the default compute account) |
| 9 | `google_cloud_run_v2_service.app` + `..._iam_member.public` | `gcloud run deploy` + public access |

#### 4.3 Differences from the workflow (so you are not surprised)

| Topic | `deploy.yml` | Terraform example |
|---|---|---|
| Vector Search machine type | not set (Google's default applies) | `e2-standard-2`, **set by a variable** |
| Replicas | not set (Google's default is 2) | `1`, **set by a variable** |
| Index shard size | `SHARD_SIZE_MEDIUM` | `SHARD_SIZE_SMALL` (variable) |
| Image registry | `gcr.io/<project>/…` | Artifact Registry repository `meridian` |
| App identity | project's default compute service account | A dedicated `meridian-app` account with only three permissions (least privilege) |
| The Docker image | built by the workflow | **You build it** (steps below); Terraform first uses Google's public hello-world image |

#### 4.4 How to run it

```bash
cd infra/terraform
cp terraform.tfvars.example terraform.tfvars        # edit: project_id, region
export TF_VAR_gemini_api_key="your-key"             # keep the key out of files
gcloud auth application-default login               # Terraform uses these credentials

terraform init
terraform plan
terraform apply
```

The first `apply` creates everything and shows a placeholder web page at `service_url` (Google's sample container). Then build and publish **your** image and re-apply:

```bash
REGION=us-central1
REPO="$REGION-docker.pkg.dev/YOUR_PROJECT_ID/meridian"
gcloud builds submit --tag "$REPO/meridian-ai:latest" ../..          # builds the Dockerfile in the cloud
terraform apply -var "container_image=$REPO/meridian-ai:latest"
```

Copy the outputs `vector_search_index_id`, `vector_search_endpoint_id` and `bucket_name` into your `.env`. Remove everything with `terraform destroy` (the bucket is configured to delete even when it contains files; this is for learning only).

#### 4.5 Honest limits of this example

- It passes `terraform fmt` and `terraform validate`, which check the *syntax and structure*. **It has not been applied to a real Google Cloud project by the author.** Treat it as a reference and expect to adjust it.
- Check Google's documentation on which Vector Search machine types fit which shard sizes before changing those variables; an invalid combination is rejected at apply time.
- Terraform's **state file records every value, including your API key**. It is git-ignored here. In a team you keep state in a protected remote location (for example a Cloud Storage bucket with versioning and tight access).
- **Do not run the GitHub workflow and Terraform against the same project.** Both create an index called `financial-docs-production`, an endpoint called `financial-docs-endpoint`, a secret `GOOGLE_API_KEY`, and a Cloud Run service `meridian-ai-cloud-run`; the second tool fails or conflicts.

### 5. Which should you use?

| Situation | Choice |
|---|---|
| Following this course | **GitHub Actions** (the default path in [06](#chapter-06)) |
| You want to understand infrastructure-as-code | Read `infra/terraform/` side by side with `deploy.yml`; try it in a throw-away project |
| A team product that must be reproducible, reviewed and audited | Terraform (or a similar tool) for infrastructure, with GitHub Actions only to run it and to deploy code |

### 6. Exercises

1. In `deploy.yml`, find the three `if`/`else` blocks that make the Vector Search step re-runnable.
2. In `main.tf`, find where Cloud Run gets the API key and explain why the key is not written in the file.
3. Run `terraform init && terraform validate` in `infra/terraform/` (no cloud account needed for `validate`).
4. Run `terraform plan` in a throw-away project and read what would be created. What would you not want to leave running overnight?


---

<a id="chapter-16"></a>

## 16 · Automated deployment with GitHub Actions

**CI/CD** means *continuous integration / continuous delivery*: every time you push code, a machine builds it and (optionally) deploys it, the same way each time. In this project the workflow file is `.github/workflows/deploy.yml`.

> **Provisioning and deployment both happen in this one workflow.** It creates the cloud resources with `gcloud` commands and then deploys the app. Terraform is not used here; an optional Terraform version exists in `infra/terraform/` ([15](#chapter-15)).

### When it runs

```yaml
on:
  push:
    branches: [main]
  workflow_dispatch:
```

- Automatically on every push to the `main` branch.
- Manually from **Actions → Deploy to GCP Cloud Run → Run workflow** (`workflow_dispatch`).

> Pushes to other branches do **not** deploy. Do your experiments on a branch and merge to `main` when you want to deploy.

### Settings at the top

```yaml
env:
  PROJECT_ID: ${{ secrets.GCP_PROJECT_ID }}
  REGION: us-central1
  SERVICE_NAME: meridian-ai-cloud-run
  IMAGE_NAME: gcr.io/${{ secrets.GCP_PROJECT_ID }}/meridian-ai-cloud-run
  VECTOR_BUCKET: gs://${{ secrets.GCP_PROJECT_ID }}-vector-staging
  INDEX_NAME: financial-docs-production
  ENDPOINT_NAME: financial-docs-endpoint
```

`${{ secrets.NAME }}` reads a GitHub secret (see [06](#chapter-06)). The region is fixed to `us-central1`; if you change it, also change `GCP_REGION` in your `.env`.

### The steps

| # | Step | What it does |
|---|---|---|
| 1 | Checkout | Downloads your code onto the GitHub runner |
| 2 | Authenticate | Signs in to Google Cloud with `GCP_CREDENTIALS_JSON` |
| 3 | Set up Cloud SDK | Installs `gcloud` on the runner |
| 4 | Enable APIs | `gcloud services enable …` for Vertex AI, Cloud Run, Secret Manager, Storage, Artifact Registry, Cloud Build, Logging, Monitoring, Trace, IAM, Resource Manager, BigQuery and Generative Language; waits 90 s |
| 5 | Buckets | Creates `gs://<project>-vector-staging` if it does not exist (no public access) |
| 6 | Initial embeddings file | `generate_json.py` writes a single random 768-number vector; it is copied to the bucket so the index can be created with at least one item |
| 7 | Vector Search | Creates the **index** (768 dimensions, streaming updates), the **endpoint**, and **deploys** the index. Each part is skipped if it already exists. Then removes the dummy vector. Slow the first time |
| 8 | Secrets | Creates the secret `GOOGLE_API_KEY`, adds your key as a new version, and lets Cloud Run's service account read **that secret** |
| 9 | Build | `gcloud builds submit` builds and stores the image |
| 10 | Deploy | `gcloud run deploy` with environment variables, the secret and `--max-instances 3` |
| 11 | Public access | Allows anyone to invoke the service and prints the access policy |

Notes:

- The workflow is **idempotent**: a second run reuses what exists, so it finishes in minutes.
- The index and endpoint IDs are passed to Cloud Run as `VECTOR_SEARCH_INDEX_ID` and `VECTOR_SEARCH_INDEX_ENDPOINT_ID`.
- The Gemini key is read inside the shell step through an environment variable, so its value is not written into the command text.
- BigQuery's API is enabled but not used by the application.
- The deployed Vector Search index starts billing as soon as it is deployed. See [02](#chapter-02).

### Reading a run

1. Open **Actions** and click the run.
2. Click the job *Provision & Deploy*. Each step can be expanded.
3. A red cross marks the failed step; the last lines of its log show the error. Common causes are in [18 · Troubleshooting](#chapter-18).
4. Re-run with **Re-run failed jobs**. Because of the idempotent design, re-running is safe.

### Security points

| Topic | Detail |
|---|---|
| Secrets | GitHub encrypts them and hides their values in logs. Never print them or put them in code |
| The JSON key | It is a long-lived credential. A more secure alternative is **Workload Identity Federation**, where GitHub proves its identity to Google Cloud without any stored key ([20](#chapter-20)) |
| Broad roles | `editor` and `projectIamAdmin` are convenient for learning. Production deployers get narrower roles |
| Public service | `allUsers` can invoke the service. Add sign-in before putting real data in |


---

<a id="chapter-17"></a>

## 17 · Cleanup — stop all charges

Do this at the end of every cloud session. Deployed Vector Search keeps billing even when nobody uses the app.

### What costs money while it exists

| Resource | Stops billing when you … |
|---|---|
| Vector Search **deployed index** on an endpoint | **Undeploy** it |
| Vector Search endpoint and index | Delete them (undeploy first) |
| Cloud Run service | Delete it (idle cost is zero, but delete anyway) |
| Cloud Storage bucket | Empty and delete it (tiny cost) |
| Artifact Registry images | Delete the repository or images (tiny cost) |

### Option 1 · Remove only the expensive part

```bash
export REGION=us-central1

## 1. Find the IDs
gcloud ai index-endpoints list --region=$REGION
gcloud ai indexes list --region=$REGION

## 2. Undeploy the index from the endpoint (this stops the hourly charge)
gcloud ai index-endpoints undeploy-index ENDPOINT_ID \
  --deployed-index-id=deployed_financial_docs --region=$REGION

## 3. Delete the endpoint and the index
gcloud ai index-endpoints delete ENDPOINT_ID --region=$REGION
gcloud ai indexes delete INDEX_ID --region=$REGION
```

When you start again, run the workflow; it re-creates the index and endpoint (30–45 minutes) and gives you new IDs for `.env`.

### Option 2 · Remove the Cloud Run service

```bash
gcloud run services delete meridian-ai-cloud-run --region=us-central1
```

### Option 3 · Delete everything (safest)

Deleting the project removes every resource in it and stops all charges. Google keeps a deleted project recoverable for 30 days.

```bash
gcloud projects delete YOUR_PROJECT_ID
```

### Also clean up credentials

- Delete the service-account key if you no longer need it: Console → IAM & Admin → Service accounts → `github-deployer` → Keys.
- Delete the local `github-deployer-key.json`.
- Remove the GitHub secrets if you are finished (Settings → Secrets and variables → Actions).
- If your Gemini API key was ever exposed, delete it at https://aistudio.google.com/apikey and create a new one.

### Check that nothing is still running

1. Console → **Vertex AI → Vector Search → Index endpoints**: no deployed indexes.
2. Console → **Cloud Run**: no services.
3. Console → **Billing → Reports**: cost per day drops to about zero the next day.
4. Your budget alert from [02](#chapter-02) remains as a safety net.


---

<a id="chapter-18"></a>

## 18 · Troubleshooting

Find the section for the part that is failing. Each entry gives the **symptom** (the message or behaviour), the **cause**, and the **fix**. Most API errors appear in the `detail` field of the response and in the terminal where the backend is running.

**First checks for almost any problem**

1. Are you in the project root folder? (`.env` is read from the folder you run from.)
2. Is the virtual environment active (`(.venv)` in your prompt) and `pip install -r requirements.txt` done?
3. Does `.env` contain your Gemini key and, for cloud features, project, bucket and index IDs? Compare with `.env.example`.
4. Read the last lines of the terminal output. The real error is usually there.

---

### Google Cloud and billing

**`403 ... does not have storage.objects.create access` (or any 403 from Cloud Storage/Vertex)**
Cause: your local credentials belong to a different Google account or service account than you think. Fix: check `gcloud auth list` and `gcloud config get account`; for the app, set `GCP_SERVICE_ACCOUNT_PATH` in `.env` to your service-account JSON (the app exports it as `GOOGLE_APPLICATION_CREDENTIALS`). Grant the account `Storage Object Admin` on the bucket if needed.

**`SERVICE_DISABLED` / "API has not been used in project … before or it is disabled"**
Cause: the API is not enabled. Fix: `gcloud services enable aiplatform.googleapis.com` (or re-run the workflow, which enables all of them). Wait a minute or two.

**"Billing account … is not enabled" / pipeline fails silently**
Cause: project has no billing account. Fix: Console → Billing → link an account.

**`Your default credentials were not found` / `DefaultCredentialsError`**
Cause: no Application Default Credentials. Fix: either `gcloud auth application-default login` or point `GOOGLE_APPLICATION_CREDENTIALS` at the service-account JSON.

**Quota project warnings**
Fix: `gcloud auth application-default set-quota-project <project-id>`.

**Wrong project is being used**
Fix: `gcloud config set project <project-id>` and check `GCP_PROJECT_ID` in `.env`.

**Unexpected bill**
Cause: the Vector Search endpoint keeps a node running 24/7. Fix: see [vector-search.md](#vector-search) (teardown) and set a budget alert.

**"Project is not allowed to use …" / repeated rate-limit or quota errors on a free-trial account**
Cause: free-trial accounts have restricted access and fixed quotas for some Vertex AI services (embeddings run on Vertex AI here; the Gemini chat key from AI Studio is separate). Fix: in Billing, activate the full (paid) account. Remaining trial credit is still applied first; only usage beyond it is charged. Then retry.

**Free-trial credit "disappeared" or resources were deleted**
Cause: the trial ends after 90 days or when the $300 is used. After a 30-day grace period trial resources are permanently deleted unless you upgrade. Fix: upgrade before that, or re-create resources in a new project.

---

### Running the backend (FastAPI)

**`ModuleNotFoundError: No module named 'api'`**
Cause: started from the wrong folder. Fix: from the **project root** run `uvicorn api.main:app --app-dir backend --reload --port 8080`.

**Settings are empty / `.env` not picked up**
Cause: `.env` is read from the *current folder*. Fix: run from the project root, where `.env` lives.

**`422 Unprocessable Entity`**
Cause: the request body does not match the Pydantic model (e.g. `query` missing). Fix: compare with the schema in `/docs`; the response body says which field is wrong.

**Browser: "blocked by CORS policy"**
Cause: frontend and backend on different origins. The backend allows all origins for the demo. Fix: check the backend is running on port 8080 and that `VITE_API_URL` is not pointing elsewhere.

**`Address already in use` (port 8080)**
Fix: `lsof -i :8080` then stop that process, or use `--port 8081` (and set `VITE_API_URL=http://localhost:8081`).

**`/api/rag/ask` returns 500 with a long message**
The `detail` field contains the real error; look it up in [langchain.md](#models-langchain-and-agents) or [vector-search.md](#vector-search).

**Frontend shows blank page on the Docker/Cloud Run URL**
Cause: `frontend/dist` was not built into the image. Fix: rebuild the image; check the first Docker stage ran `npm run build`.

---

### Models, LangChain and agents

**`index_id is required for api_version='v1'`**
Cause: `VECTOR_SEARCH_INDEX_ID` / `VECTOR_SEARCH_INDEX_ENDPOINT_ID` are empty. Fix: copy them from the GitHub Actions log (*Provision Vector Search* step) into `.env`.

**`404 models/<name> is not found` / "no longer available to new users"**
Cause: the model was retired or is not available to your key. Fix: set `VERTEX_LLM_MODEL_NAME` to a current model from https://ai.google.dev/gemini-api/docs/models (this project uses `gemini-3.8-flash`). `gemini-2.5-pro` is closed to new users and retires 16 Oct 2026.

**`API key not valid` / 400 from Gemini**
Fix: create a key at https://aistudio.google.com/apikey; no spaces or newlines in `.env`.

**`ImportError: cannot import name 'create_agent'`**
Cause: old `langchain` installed. Fix: `pip install -r requirements.txt` (needs `langchain==1.2.11`).

**`ModuleNotFoundError: langchain_classic`**
Fix: `pip install langchain-classic==1.0.2`. `create_retrieval_chain` moved there in LangChain 1.x.

**Agent answers instantly without using tools / loops forever**
Cause: tool docstrings unclear, or model temperature. Fix: improve the tool docstring; try `LLM_TEMPERATURE=1.0` (Gemini 3 default) or a different model.

**Tool results contain `LLM_ERROR`**
Cause: the tool's own model call failed (key, quota, model name). The agent output will say "Manual review required". Fix as above.

**`validate_fx_hedge` always uses the LLM fallback**
Cause: the Frankfurter API (`api.frankfurter.dev`) is unreachable from your network. The tool is built to fall back.

**Audit answers differ each run**
Normal: LLM output varies. The key words (`RED ALERT`, `FX ALERT`, `HOLD FOR TREASURY AUDIT`) should be stable.

---

### Vector Search

**Index creation/deployment takes 30–45 minutes the first time.** Normal. Start it hours before class.

**Searches return nothing right after uploading**
Cause: streaming updates take a short time to become searchable. Fix: wait ~30–60 seconds and ask again.

**Dimension mismatch error when upserting**
Cause: the embedding model does not output 768 dimensions (the index is created with 768). Fix: use `text-embedding-005` (default). Changing the model means creating a new index.

**`deployed index not found` / endpoint errors**
Cause: the index is not deployed to the endpoint yet. Check: Console → Vertex AI → Vector Search → Index endpoints.

**Same document uploaded twice → duplicate answers**
Expected: every upload adds chunks again. For class, upload each PDF once.

#### Teardown (stops the hourly charge)
```bash
REGION=us-central1
## 1. find ids
gcloud ai index-endpoints list --region=$REGION
gcloud ai indexes list --region=$REGION
## 2. undeploy the index from the endpoint (this is what stops the billing)
gcloud ai index-endpoints undeploy-index <ENDPOINT_ID> \
  --deployed-index-id=deployed_financial_docs --region=$REGION
## 3. delete endpoint and index
gcloud ai index-endpoints delete <ENDPOINT_ID> --region=$REGION
gcloud ai indexes delete <INDEX_ID> --region=$REGION
```
Also delete the Cloud Run service and the bucket if you are done with the project.

#### Alternatives
Vector Search 2.0 (collection-based, no separate endpoint step, hybrid search), Postgres + pgvector, Pinecone, Chroma, Vertex AI RAG Engine.

---

### Docker and Cloud Run

**Container starts but every request fails with empty settings**
Cause: the image deliberately contains no `.env` or credentials. Fix for local Docker:
```bash
docker run -p 8080:8080 --env-file .env \
  -e GOOGLE_APPLICATION_CREDENTIALS=/creds/service-account.json \
  -v "$(pwd)/credentials:/creds:ro" meridian-ai
```
On Cloud Run the environment variables and secret are set by the deploy step.

**Cloud Run: "container failed to start and listen on the port"**
Cause: app not listening on `$PORT` (8080) or crashed at start. Fix: read the revision logs (Cloud Run → Logs). The Dockerfile uses `--port ${PORT:-8080}`.

**Docker build fails at `npm ci`**
Cause: lockfile out of sync or no network. Fix: `cd frontend && npm install`, commit `package-lock.json`.

**Python packages fail to build**
Fix: keep `build-essential` in the Dockerfile's apt step.

**Cloud Run URL returns 403 "Forbidden"**
Cause: public access (`allUsers` → `run.invoker`) not applied. The last workflow step grants it.

**First request is slow**
Cause: scale-to-zero cold start. Fine for class; mention `--min-instances` as a paid option.

---

### GitHub Actions deployment

**Auth step fails: "invalid JSON" / "credentials_json"**
Cause: `GCP_CREDENTIALS_JSON` must be the **entire** contents of the key file, including braces. Fix: re-copy the file; no extra quotes.

**`GOOGLE_API_KEY` secret empty → app fails at runtime**
Fix: add it under Settings → Secrets and variables → Actions. The workflow strips whitespace and prints only the key length.

**Image build/push fails for `gcr.io/...` (permission denied / repository does not exist)**
Cause: Google Container Registry is shut down; `gcr.io` addresses only work when backed by an Artifact Registry repository, which can need creating first. **Not yet verified by a real deploy in this project.** Fix options: (a) create the `gcr.io` repository in Artifact Registry (Console → Artifact Registry → Create repository → format Docker, multi-region `us`, name `gcr.io`), or (b) change `IMAGE_NAME` in `deploy.yml` to `us-central1-docker.pkg.dev/<project>/<repo>/meridian-ai-cloud-run` and create that repository with `gcloud artifacts repositories create`.

**"Index creation in progress" loop times out**
Cause: first-time index creation is slow. Fix: re-run the workflow; it skips what already exists.

**Run takes 40+ minutes**
Normal on the first run (vector index + deployment). Later runs are minutes.

**Cloud Run deploy OK but app errors on every call**
Check the printed `INDEX_ID`/`ENDPOINT_ID`; read Cloud Run logs; check `VERTEX_LLM_MODEL_NAME` is a current model.

**Pushes to `main` redeploy everything**
By design (`on: push: main`). While teaching, work on a branch; use *Run workflow* manually.

#### Security notes
- A stored JSON key is a long-lived secret; the safer modern option is **Workload Identity Federation** (no key stored).
- `Editor` + `IAM Admin` is broad; fine for a classroom, not for production.
- `--allow-unauthenticated` makes the app public; `--max-instances 3` limits the damage if someone abuses it.

---

### Terraform (optional example)

Terraform is **not** used by the main deployment (GitHub Actions + `gcloud`). These entries apply only if you try the example.

**`Error: Invalid provider configuration` / `No credentials`**
Cause: Terraform cannot find Google credentials. Fix: `gcloud auth application-default login`, then `terraform plan` again.

**`Error 403: ... API has not been used in project ... before or it is disabled`**
Cause: an API was not enabled yet when a resource was created. Fix: wait a minute and run `terraform apply` again (the first resources enable the APIs).

**`Error 409: ... already exists`**
Cause: the resource was already created, for example by the GitHub Actions workflow. Do not use both tools on one project. Fix: use a fresh project, or delete the existing resource, or import it (`terraform import`).

**`No value for required variable gemini_api_key`**
Fix: `export TF_VAR_gemini_api_key="your-key"` before running Terraform. Do not write the key into a committed file.

**Machine type / shard size rejected when deploying the index**
Cause: not every Vector Search machine type supports every shard size. Fix: check Google's Vector Search documentation and change `index_machine_type` / `index_shard_size`.

**Cloud Run shows Google's "hello" page**
Expected after the first apply. Build your image and re-apply with `-var "container_image=..."` (see doc 15).

**Concern: the API key is in the state file**
True. `terraform.tfstate` is git-ignored here. Never share or commit it; protect remote state in real projects.

**`terraform destroy` leaves the Vector Search deployment running**
Check the console: Vertex AI → Vector Search → Index endpoints. Undeploy and delete manually if needed ([cleanup](#chapter-17)).

---


---

<a id="chapter-19"></a>

## 19 · Design decisions — the reasons behind each choice

This is the page to read when you think "why did they do it *this* way?" Each entry gives the choice, the reason, what you would lose if you chose differently, and where to see it in the code. Some choices are deliberate trade-offs for a learning project; those are marked **(learning trade-off)** so you know what a production system would change.

---

### A. Project structure

| Choice | Why | Cost / alternative | Where |
|---|---|---|---|
| Split the backend into `api`, `rag`, `agent`, `config`, `logger` | One job per package; changes stay local; easy to find things; testable parts | More files to open. A single file is fine for a 100-line experiment, not for a growing product | [04](#chapter-04) |
| `api/endpoints.py` contains only thin routes | A route's job is to translate HTTP into a function call and back. Logic in routes cannot be reused or tested without a web server | One extra function call | `api/endpoints.py` |
| `ingest_pdf()` is used by both upload and bucket-import | Same behaviour in both paths; fix a bug once | – | `rag/data_ingestion.py` |
| Frontend and backend in separate folders | Different languages, tools and build outputs | Two terminals while developing | `frontend/`, `backend/` |
| Prompts in their own file | They are text that is edited far more often than code, sometimes by non-programmers | Slightly more indirection | `agent/prompts.py` |
| Tests in `backend/tests/` with fake settings | Anyone can run them with no accounts and no cost | They test wiring, not the quality of AI answers | `backend/tests/` |

### B. Python and configuration

| Choice | Why | Where |
|---|---|---|
| Pinned versions in `requirements.txt` | AI libraries change fast and break each other. Pinning makes every learner's environment identical | `requirements.txt` |
| `requirements-dev.txt` separate | The server image should not carry test tools | `requirements-dev.txt` |
| Settings via environment variables / `.env` | Code stays the same everywhere; secrets stay out of Git | `config/settings.py` |
| One `Settings` object, created once | A single source of truth; typed and validated | `config/settings.py` |
| Models and connections created lazily with `lru_cache` | The server can start, and `/api/health` and the tests work, before any cloud is configured; each object is built once | `rag/llm.py`, `rag/embeddings.py`, `rag/vector_store.py` |
| `temperature = 0` by default | The same question gives (nearly) the same answer, which is easier to debug and to compare. Raise it for more varied wording | `LLM_TEMPERATURE` |
| Model name is a setting | Models are retired regularly. Changing one should not need a code change | `VERTEX_LLM_MODEL_NAME` |

### C. Documents and search (RAG)

| Choice | Why | Trade-off |
|---|---|---|
| Chunk size 1000 characters, overlap 100 | Large enough to hold a full idea, small enough that a search hit is precise. Overlap keeps ideas that straddle a boundary | Too small loses context; too large dilutes the match. Try it: [11](#chapter-11) exercise |
| 768-dimension embeddings (`text-embedding-005`) | The index was created with 768 dimensions; every vector stored and every question must have the same length | Changing the model means a new index |
| Same embedding model for storing and searching | Vectors from different models are not comparable | – |
| Dot-product distance, tree-AH algorithm | Fast approximate search on Vertex AI; a standard choice for text embeddings | Approximate means it can very rarely miss the true best match |
| Streaming updates (`stream_update=True`) | New uploads become searchable within a short time | Costs more than batch updates |
| Retrieve 3 chunks (`k=3`) | Enough context for most questions without making the prompt long and costly | Questions needing many passages may be answered incompletely; use the *contextual* option (10 chunks) |
| Prompt says "answer only from the context; say you don't know" | Reduces made-up answers (hallucination) | The model may refuse when the answer is partly there |
| Upload also saves the PDF in Cloud Storage | The index holds chunks, not the originals; a copy lets you re-index later | Small storage cost |
| `create_retrieval_chain` from `langchain_classic` | Same behaviour as earlier LangChain versions, still supported | Online tutorials mix old and new imports (see [11](#chapter-11)) |

### D. Agents

| Choice | Why | Trade-off |
|---|---|---|
| Three specialist agents instead of one | Each has a short, focused prompt and only the tools it needs. This is more reliable than one giant prompt | More model calls = slower and costlier |
| A supervisor in plain Python, then one summarising model call | Control flow you can read and debug. The order and the final decision rules are visible | Less flexible than a self-organising multi-agent graph |
| Agents run one after another | Easy to read and to follow in the logs | They could run in parallel for speed |
| Exact output formats in the prompts | The next step (and the CFO rules) depends on fixed words like `RED ALERT` | A format change must be made in two places |
| `create_agent` (LangChain) | The current standard way; runs on LangGraph underneath, so there is no graph code to maintain | For loops, branches, and human approval steps you would use LangGraph directly |
| Tools ask the model instead of calling real services **(learning trade-off)** | No external accounts are needed to run the demo | A real system must call real sanctions, credit and tax services and keep a human reviewer |
| Each tool catches its own errors and returns a "manual review required" message | One failed lookup should not crash the whole audit | Errors can be hidden inside the text; check the logs |
| The FX tool uses a real exchange-rate API first and the model only as a fallback | Facts that exist as data should come from data | Needs internet access |

### E. API design

| Choice | Why | Where |
|---|---|---|
| `/api/...` prefix | Separates API URLs from website pages on the same server | `api/endpoints.py` |
| Pydantic request/response models | Automatic validation, documentation, and clear errors | `api/schemas.py` |
| Routes return HTTP 500 with the real message | The frontend can show it and learners can debug | Production systems usually hide internals |
| CORS allows all origins **(learning trade-off)** | Frontend (port 3000) and backend (port 8080) are different origins in development | Restrict to your site in production |
| Upload runs the slow part in a thread | Keeps the server responsive | [09](#chapter-09) |
| `/api/status` reads settings and does not call the cloud | It must work even when the cloud is misconfigured, since that is when you need it | `api/endpoints.py` |
| The server also serves the React build | One container, one URL, no CORS problems in production | `api/main.py` |
| In-memory upload history **(learning trade-off)** | Simple. Resets when the server restarts | A database would persist it |

### F. Logging

| Choice | Why | Where |
|---|---|---|
| Structured JSON logs | Searchable and filterable by machines | `logger/custom_logger.py` |
| Both console and file | The console for live viewing, the file as a record | same |
| A `severity` field | Cloud Logging uses it to colour and filter | `add_severity` |
| One shared logger | One format everywhere | `logger/__init__.py` |
| Upload the log file at shutdown | The container's disk disappears | `main.py` lifespan |

### G. Packaging and cloud

| Choice | Why | Trade-off |
|---|---|---|
| Docker | Same environment everywhere, and Cloud Run runs containers | Learning Docker |
| Multi-stage Dockerfile | The final image has no Node.js or build tools | Slightly longer Dockerfile |
| Copy `requirements.txt` before the code | Docker caches layers; package installs are slow and rarely change | – |
| `.dockerignore` excludes `.env` and `credentials/` | Secrets must never be baked into an image anyone can pull | – |
| Cloud Run | No server to manage; scales to zero; pay for use | Cold starts |
| `--max-instances 3` | Caps cost and abuse because the URL is public | Heavy traffic is limited |
| `--allow-unauthenticated` **(learning trade-off)** | Anyone can open the demo without signing in | Put sign-in in front of real data |
| API key in Secret Manager | Keeps it out of code, images, and the console's plain environment-variable list | One more service |
| Secret access granted on that one secret | Least privilege: a compromised service can read only what it needs | – |
| Vector Search through a deployed endpoint | Managed, fast, fits LangChain | **Hourly cost while deployed** ([17](#chapter-17)) |
| A service-account JSON key for GitHub **(learning trade-off)** | Simplest to set up | Keys can leak. Production uses Workload Identity Federation ([20](#chapter-20)) |
| `editor` + `projectIamAdmin` for the deployer **(learning trade-off)** | One robot can create everything | Far more access than necessary |
| Provisioning with `gcloud` in GitHub Actions rather than Terraform | No additional tool; one file does everything | See [15](#chapter-15) |
| Region `us-central1` | Vertex AI features and quotas are broadly available there | Choose a region near your users and data-residency rules |

### H. Deliberate simplifications to remember

1. The audit "data sources" are the language model's memory, not databases.
2. The deployed app has no sign-in.
3. Broad permissions for the deployer.
4. No automatic tests in the GitHub workflow.
5. No database for history; no answer-quality evaluation.
6. Everything is a single Cloud Run service with a single region.

See [20](#chapter-20) for the upgrade path for each.

### I. A way to read any unfamiliar file

Ask, in this order: **What is this file's one job? Who calls it? What does it call? What does it need from settings? What does it write to the log? What would break if I deleted it?** Every file in this project can be explained by those six answers.


---

<a id="chapter-20"></a>

## 20 · Alternatives and next steps

The project makes one choice per layer. This page lists common alternatives so you can see what else exists and why you might pick it.

### Alternatives by layer

| Layer | This project | Alternatives | When to consider them |
|---|---|---|---|
| Cloud provider | Google Cloud | AWS, Microsoft Azure | Your company already uses them. Concepts map across: project ≈ account/subscription, service account ≈ IAM role, Cloud Storage ≈ S3/Blob Storage, Cloud Run ≈ App Runner / Container Apps |
| Web framework | FastAPI | Flask, Django, Node.js/Express | Flask is simpler, Django is full-stack |
| Chat model | Gemini | Claude, OpenAI GPT, open-source models (Ollama, Vertex Model Garden) | Cost, privacy, quality, or data-residency needs |
| Embeddings | Vertex AI `text-embedding-005` | Gemini embedding models, OpenAI embeddings, open-source (Sentence Transformers) | Different languages or dimensions (a new index is needed if dimensions change) |
| Vector database | Vertex AI Vector Search (index + endpoint) | **Vector Search 2.0** (collections, no separate endpoint step, hybrid search), PostgreSQL + pgvector, Pinecone, Chroma, Vertex AI RAG Engine | Lower hourly cost, simpler setup, or an existing database |
| Retrieval | Top-k similarity, multi-query, contextual compression | MMR (diversity), hybrid keyword + vector search, re-ranking | Better accuracy on large document sets |
| Agents | LangChain `create_agent` | **LangGraph** (explicit graphs), Google Agent Development Kit, CrewAI, AutoGen, Vertex AI Agent Engine | Loops, branches, human approval steps, shared state |
| Hosting | Cloud Run | App Engine, GKE (Kubernetes), a virtual machine, Render, Fly.io | More control, or an existing platform |
| Secrets | Secret Manager | HashiCorp Vault, environment files in the host | Multi-cloud setups |
| CI/CD | GitHub Actions | Cloud Build triggers, GitLab CI | Different tooling preferences |
| Provisioning | `gcloud` commands inside GitHub Actions | **Terraform** (an example is in `infra/terraform/`; see [15](#chapter-15)), Pulumi, Deployment Manager | Reproducible, reviewable infrastructure; a plan before every change; clean teardown |
| Cloud sign-in from CI | Stored service-account key | **Workload Identity Federation** (no stored key) | Always preferred for production |

### Ideas to extend the project

| Idea | What you would learn |
|---|---|
| Add sign-in to the API (API keys, OAuth, or Identity-Aware Proxy) | Securing a public service |
| Show **sources** (file and page) next to each answer | The `source` metadata is already stored with each chunk |
| Evaluate answer quality with a test set of questions | Measuring RAG |
| Stream the answer word by word | Server-sent events |
| Run the three agents in parallel | Faster audits |
| Replace a simulated tool with a real data source | Real tool integration |
| Move the agent flow to explicit LangGraph | Graph state, branches, loops |
| Add a database for audit history | Persistence |
| Migrate to Vector Search 2.0 | Comparing designs and costs |
| Add automated tests in the GitHub workflow | Real CI |

### Keeping the project current

| Item | Where to check |
|---|---|
| Gemini model names and retirement dates | https://ai.google.dev/gemini-api/docs/models |
| Embedding model lifecycle (`text-embedding-005` is listed to retire on 1 April 2027) | https://docs.cloud.google.com/vertex-ai/generative-ai/docs/learn/model-versions |
| LangChain / LangGraph releases | https://docs.langchain.com |
| Pinned Python packages | `requirements.txt` |

### Where to go from here

1. Read the code in the order of documents 07 → 08 → 09.
2. Make one of the changes in the table above.
3. Look at the glossary ([21](#chapter-21)) for any word you want defined.


---

<a id="chapter-21"></a>

## 21 · Glossary

| Term | Meaning |
|---|---|
| **LLM** | A model that predicts text. Smart, but only knows what it was trained on. |
| **RAG** | Retrieval-Augmented Generation: find relevant pages first, then let the LLM answer from them. |
| **Embedding** | A list of numbers (here 768) that places a piece of text on a "map of meaning". Similar meaning → nearby. |
| **Chunk** | A small piece of a document (here ~1000 characters) that is embedded and searched. |
| **Vector database** | Storage that finds the nearest vectors quickly. Here: Vertex AI Vector Search. |
| **Index / Endpoint** | The index holds the vectors; the endpoint is the running service that answers searches (billed hourly). |
| **Retriever** | The component that fetches chunks for a question. |
| **Tool** | A Python function the model may call (a "hand"). |
| **Agent** | An LLM that decides which tools to call, in a loop, to finish a task. |
| **Supervisor** | Code that runs several agents and combines their results (the "CFO"). |
| **Prompt** | The instructions given to the model (the "job description"). |
| **FastAPI** | A Python framework for building web APIs. |
| **Pydantic** | Library that checks data matches a defined shape. |
| **Uvicorn** | The server that runs a FastAPI app. |
| **GCP project** | The container for all your Google Cloud resources and billing. |
| **API (Google)** | A Google service you must switch on per project. |
| **IAM / role** | Who may do what. A role is a bundle of permissions. |
| **Service account** | A non-human identity (a robot's badge). |
| **ADC** | Application Default Credentials: how Google libraries find your credentials automatically. |
| **Cloud Storage bucket** | A cloud folder for files. |
| **Secret Manager** | A locker for keys and passwords. |
| **Docker image / container** | A packaged app / a running copy of it. |
| **Artifact Registry** | Where Docker images are stored on GCP. |
| **Cloud Build** | Builds images in the cloud. |
| **Cloud Run** | Runs a container; scales to zero when idle. |
| **CI/CD** | Automatically testing and deploying on every code push. |
| **GitHub Actions** | GitHub's CI/CD system (`.github/workflows/`). |
| **Workload Identity Federation** | Lets GitHub authenticate to GCP with no stored key. |

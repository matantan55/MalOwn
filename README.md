# MalOwn — Malware Threat Analysis Tool

A CLI-based malware file analysis and threat assessment tool that combines heuristic rules with a neural network trained on real malware samples.

## Quick Start

### 1. Clone & Setup

```bash
git clone <repo-url>
cd FileAnalysis

# Create virtual environment
python3 -m venv .venv
source .venv/bin/activate

# Install dependencies
pip install -r requirements.txt

# (Optional) Install PyTorch for neural network scoring
pip install torch>=2.0
```

### 2. Launch the Interactive Console

> **Important:** You must run the command from the `FileAnalysis/` project root directory.

```bash
# Activate the virtual environment
source .venv/bin/activate

# Launch the interactive menu
python -m fileanalysis.cli
```

This launches the **MalOwn Interactive Console**:
```
                 _|      _|            _|    _|_|                                  
                 _|_|  _|_|    _|_|_|  _|  _|    _|  _|      _|      _|  _|_|_|    
                 _|  _|  _|  _|    _|  _|  _|    _|  _|      _|      _|  _|    _|  
                 _|      _|  _|    _|  _|  _|    _|    _|  _|  _|  _|    _|    _|  
                 _|      _|    _|_|_|  _|    _|_|        _|      _|      _|    _|  
                                                                                
                                                                                
                           No files currently loaded.                           
                                                                                
╭──────────────────────────── Interactive Console ─────────────────────────────╮
│                                                                              │
│    1.    Standard File Analysis         Run the full scanning pipeline       │
│                                         with ML scoring, capabilities        │
│                                         mapping, and YARA                    │
│    2.    Interactive Binary Research    Open the hex viewer with             │
│                                         disassembled code and threat         │
│                                         annotations                          │
│    3.    Clear Files                    Remove all loaded files from the     │
│                                         workspace                            │
│    4.    Quit                           Exit the application                 │
│                                                                              │
╰──────────────────────────────────────────────────────────────────────────────╯

Select an option or paste a file path to load:
```

Paste a file path directly into the prompt to load it into your workspace, and then select an option to run analysis or research on it.

### Example Output (Standard Scan)
```

  MalOwn — Malware Threat Report 

 File: malware.exe
 Type: Windows Executable (application/vnd.microsoft.portable-executable)
 Size: 11.8 MB (12,340,622 bytes)
 Perms: rwxr-xr-x


  Best Score (Ensemble): 77.1/100 — HIGH                         
                                                                   
  Heuristic: 64.0/100 — HIGH                                     
  Neural Net: 100.0/100 — CRITICAL  (100.0% confident malicious) 
  LightGBM: 78.8/100 — HIGH  (78.8% confident malicious)         


  AI Executive Insights 
 The model classified this file as malicious primarily due to: 
 • YARA Signature Hits (Value: 3)                              
 • Embedded URLs (Value: 0)                                    
 • Windows Registry Keys (Value: 1)                            
                                                               
 Final ML Score: 78.8/100 (78.8% confidence)                   


                                  File Hashes                                 

 Type          Value                                                         

 MD5           eb5b7c1d7a58bb6b3356b6933a122b78                              
 SHA-1         bcb279c07bb56d554f7aadc12f598dfd36bbde4c                      
 SHA-256       356396e17fb71952c99d0b5d470f4ed9c8cf513a82fc88bb77113842c664… 
 ssdeep        196608:E27p7upumuzWnEAkaSqku/ByujxBvWWF4e00bx:FSKy4+kKymxBOW… 
 imphash       b23a2bc43eb07e7fff1aeded8fe30126                              


 File Entropy: 6.0108/8.0

 Threat Capabilities
  • Process Injection (T1055) — Injects malicious code into legitimate running processes to bypass detection.
    ↳ Indicators: Suspicious Section
  • Persistence (T1547.001) — Establishes mechanism to survive reboot/logoff.
    ↳ APIs: RegSetValueExW
    ↳ Indicators: Registry Key References
  • Defense Evasion (T1027) — Obfuscates binary contents, disables security software, or detects analysis environments.
    ↳ APIs: IsDebuggerPresent

 Environment Impact
  1. The file may actively evade antivirus scanners, virtual environments, or debugger utilities.
  2. It can inject payloads into other running processes (like explorer.exe) to hijack system actions.
  3. It establishes persistence (automatic restart) by writing run keys, creating background services, or installing startup jobs.

                                 YARA Matches                                 

 Rule Name                    Description                          Severity 

 Shellcode_API_Hashing_ROR13  Detects ROR13 API hashing loop used  critical 
                              by Metasploit and Cobalt Strike               
                              shellcode                                     
 Shellcode_Syscall_x86        Detects direct x86 system call       high     
                              invocation (int 0x80, sysenter, int           
                              0x2e)                                         
 Shellcode_Heavens_Gate       Detects Heaven's Gate technique      critical 
                              (32-bit to 64-bit mode switch to              
                              bypass EDR hooks)                             

```

### 3. Advanced CLI Options (One-Shot Mode)

You can bypass the interactive menu for scripting by providing the file path directly.

| Flag | Description |
|------|-------------|
| `--json` | Output results as JSON |
| `--research` | Open interactive hex viewer directly |
| `--yara-rules DIR` | Path to custom YARA rules directory |

**Examples:**
```bash
# Standard scan in one shot
python -m fileanalysis.cli suspicious.exe

# JSON output (for scripting)
python -m fileanalysis.cli suspicious.exe --json

# Interactive binary research mode directly
python -m fileanalysis.cli suspicious.exe --research

# Custom YARA rules
python -m fileanalysis.cli suspicious.exe --yara-rules /path/to/rules/
```

---

## 4. Model Context Protocol (MCP) Server

MalOwn includes a production-grade MCP server that allows AI assistants (like Claude Desktop or Cursor) to execute analysis pipelines and binary research tools directly.

The server supports two transports:
- **`stdio`** (default): For local processes that communicate via standard input/output.
- **`sse`** (Server-Sent Events): For remote clients via HTTP.

**Available MCP Tools:**
- `analyze_file`: Runs the full scanning pipeline.
- `get_binary_annotations`: Extracts suspicious byte patterns and headers.
- `extract_control_flow_graph`: Computes CFG basic blocks.
- `get_hex_dump`: Generates raw hex dumps.

**Usage:**
```bash
# Run locally (stdio)
uv run fileanalysis-mcp --transport stdio

# Run remotely (HTTP SSE)
uv run fileanalysis-mcp --transport sse --port 8000
```

---

## How It Works

MalOwn runs a multi-stage pipeline on every file:

1. **Load** — Reads the file, detects type (PE, ELF, Mach-O, script, document)
2. **Analyze** — Runs format-specific analyzers (hashing, entropy, advanced strings including CVE/Registry patterns, imports, sections)
3. **Intelligence** — YARA signature matching + MITRE ATT&CK capability mapping (e.g., Exploitation, Persistence)
4. **Score** — Triple scoring with heuristic rules, a neural network, and a LightGBM decision tree model
5. **Report** — Rich terminal output or JSON

### Dual Scoring System

Every scan produces **independent threat scores** and an ensemble score:

| Scorer | How it works |
|--------|-------------|
| ** Heuristic** | Hand-tuned weighted formula (entropy + strings + capabilities + YARA) |
| ** Neural Net** | 4-layer MLP trained on real malware/benign samples |
| ** LightGBM** | Gradient boosting decision tree trained on the same feature set |
| ** AI Insights** | Google Gemini LLM generates an executive summary, and local Qwen2.5-Coder analyzes suspicious assembly patterns |

### Risk Levels

| Score | Level | Meaning |
|-------|-------|---------|
| 0–20 | CLEAN | No indicators found |
| 21–40 | LOW | Minor suspicious indicators |
| 41–60 | MODERATE | Multiple suspicious indicators |
| 61–80 | HIGH | Strong malware indicators |
| 81–100 | CRITICAL | Almost certainly malicious |

---

## Retraining the Neural Network (Incremental Learning)

The model can be retrained on real malware inside a **Docker sandbox** (no malware touches your local machine):

```bash
# Build the sandbox
docker build -t fileanalysis-sandbox -f Dockerfile.sandbox .

# Run training (fetches dataset, extracts features, trains model)
docker run --rm -v "$(pwd)":/workspace fileanalysis-sandbox
```

This will:
1. Clone multiple curated cybersecurity datasets (DikeDataset, theZoo, vx-underground, Endermanch MalwareDatabase) inside the container
2. **Incremental Extraction**: Skip files already cached in `dataset_cache.npz` and extract 30-dimensional features only from new files
3. **Replay-Buffer Fine-Tuning**: Load the existing `threat_model_malconv.pt` weights and fine-tune using 100% of new data + a 10% replay buffer of old data to prevent catastrophic forgetting
4. Train MalConv (PyTorch) and LightGBM models
5. Save `threat_model_malconv.pt` and `threat_model_lgb.txt` to your local project
6. Destroy the container (and all malware) when done

### Training Flags

You can retrain each model independently by passing flags in your commit message:

```bash
# Retrain only the LightGBM decision tree
git commit -m "your message --tree"

# Fine-tune only the Neural Network (MalConv)
git commit -m "your message --train"

# Retrain both (default)
git commit -m "your message --tree --train"
```

---

## Project Structure

FileAnalysis/
 fileanalysis/
    cli.py                    # Main CLI entry point (interactive + one-shot)
    loader.py                 # File loading & type detection
    pipeline.py               # Shared analysis pipeline (used by CLI & MCP)
    mcp_server.py             # MCP server (stdio + SSE transports)
    analyzers/                # Format-specific analyzers
       base.py               # AnalysisResult data structure
       entropy.py            # Entropy analysis
       hashing.py            # Cryptographic hashing
       strings.py            # String extraction & categorization
       pe_analyzer.py        # Windows PE analysis
       elf_analyzer.py       # Linux ELF analysis
       macho_analyzer.py     # macOS Mach-O analysis
       script_analyzer.py    # Script file analysis
       document_analyzer.py  # Document file analysis
       dll_analyzer.py       # DLL-specific analysis
    intelligence/
       yara_scanner.py       # YARA rule matching
       capability_mapper.py  # MITRE ATT&CK mapping
       ai_insights.py        # Google Gemini executive summary
       asm_insights.py       # Local Qwen2.5-Coder assembly explanation
    research/
       hex_viewer.py         # Interactive hex + disassembly viewer
    scoring/
       scorer.py             # Heuristic threat scorer
       nn_model.py           # MalConv neural network
       ml_model.py           # LightGBM tree model
       features.py           # 30-dim feature extraction
       sandbox_train.py      # Real malware training (Docker)
       threat_model_malconv.pt      # Trained NN weights
       threat_model_lgb.txt         # Trained LightGBM weights
    reporting/
        terminal_report.py    # Rich terminal output
        json_report.py        # JSON output
 Dockerfile.sandbox            # Docker sandbox for safe training
 requirements.txt              # Python dependencies
 pyproject.toml                # Project configuration
```

---

## Dependencies

| Package | Purpose |
|---------|---------|
| `rich` | Beautiful terminal output |
| `click` | CLI framework |
| `pefile` | PE binary parsing |
| `yara-python` | YARA rule matching |
| `puremagic` | MIME type detection |
| `lief` | Cross-platform binary parsing |
| `ppdeep` | Fuzzy hashing (ssdeep) |
| `numpy` | Feature vector computation |
| `torch` *(optional)* | Neural network inference |
| `lightgbm` *(optional)* | LightGBM decision tree inference |
| `prompt_toolkit` | Arrow-key navigation in interactive menu |
| `capstone` | Assembly disassembly in hex viewer |
| `transformers` *(optional)* | Local Qwen2.5-Coder for assembly insights |
| `mcp` | Model Context Protocol SDK for the MCP server |
| `starlette` | ASGI framework for the SSE transport |
| `uvicorn` | ASGI server for remote MCP connections |

---

## License

See [LICENSE](LICENSE) for details.

## Cloud Integration & CI/CD

To ensure the models continually improve, the entire training lifecycle is automated using **GitHub Actions**:

- **Selective Model Retraining**: The workflow (`.github/workflows/training.yml`) triggers on any push where the commit message contains `--train` (retrain MalConv NN) or `--tree` (retrain LightGBM). Both flags can be combined. The workflow fires on pushes to any branch.
- **Incremental Dataset Caching**: The training pipeline uses `actions/cache` to persist `dataset_cache.npz` between runs, skipping feature extraction for already-processed files.
- **Frozen Scaler**: The `feature_scaler.npz` normalization parameters are written once and never overwritten. This prevents the scaler drift that would corrupt old LightGBM tree splits on incremental runs.
- **Automated Releases**: Upon a successful run, if model weights have changed, the CI/CD pipeline automatically commits the updated weights back to the repository and publishes a new versioned GitHub Release.

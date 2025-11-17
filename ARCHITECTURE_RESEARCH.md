# 🏗️ Comprehensive Architecture Research: Agentic Development Control Systems

**Research Date**: 2025-11-17
**Purpose**: Research stable, production-ready architectures for controlling VS Code, Terminal, Linux functionality, and Browser for agentic systems

---

## 📋 Table of Contents

1. [VS Code Control Architectures](#1-vs-code-control-architectures)
2. [Terminal Control Systems](#2-terminal-control-systems)
3. [Linux & Container Control](#3-linux--container-control)
4. [Browser Automation Systems](#4-browser-automation-systems)
5. [Complete Integrated Agent Systems](#5-complete-integrated-agent-systems)
   - 5.1 [OpenHands](#51-openhands-open-source-ai-software-engineer)
   - 5.2 [SWE-agent](#52-swe-agent-princeton)
   - 5.3 [Anthropic Computer Use](#53-anthropic-computer-use)
   - 5.4 [Cloud Development Environments](#54-cloud-development-environments)
   - 5.5 [Manus AI](#55-manus-ai-autonomous-agent-system)
6. [Architecture Comparison Matrix](#6-architecture-comparison-matrix)
7. [Recommended Architecture](#7-recommended-architecture)

---

## 1. VS Code Control Architectures

### 1.1 LSP (Language Server Protocol)

**Source**: Microsoft (VS Code, Visual Studio)
**Purpose**: Standardized protocol for IDE-language tool communication

#### Architecture

```
┌─────────────────────────────────────┐
│      VS Code Extension              │
│    (Language Client - JS/TS)        │
│  - Manages UI integration           │
│  - Handles user interactions        │
└──────────────┬──────────────────────┘
               │ JSON-RPC over pipes/sockets
┌──────────────▼──────────────────────┐
│      Language Server                │
│   (Any language - separate process) │
│  - Code analysis (CPU/Memory heavy) │
│  - Provides language features       │
│  - Auto-complete, diagnostics, etc. │
└─────────────────────────────────────┘
```

**Key Features**:
- ✅ **Separate Process**: Language servers run in their own process to avoid blocking the editor
- ✅ **JSON-RPC Protocol**: Uses JSON-RPC v2.0 for communication
- ✅ **Language Agnostic**: Server can be written in any language (PHP, Rust, Go, etc.)
- ✅ **Rich Features**: Completions, hover, signature help, go-to-definition, find references, diagnostics, code actions

**Use Case for Agents**:
- Agents can implement LSP servers to provide intelligent code suggestions
- Can analyze code in real-time and offer refactoring suggestions
- Provides structured interface for code understanding

**Libraries**:
- `vscode-languageserver-node` (Node.js)
- `vscode-languageclient` (VS Code extension side)

---

### 1.2 code-server (Coder)

**Source**: Coder.com
**Purpose**: Run VS Code in the browser, accessible from anywhere

#### Architecture

```
┌─────────────────────────────────────┐
│      User Browser                   │
│  - WebSocket connection             │
│  - Renders VS Code UI               │
└──────────────┬──────────────────────┘
               │ HTTP/WebSocket
┌──────────────▼──────────────────────┐
│     code-server Process             │
│  - Modified VS Code main process    │
│  - Serves HTTP requests             │
│  - Manages extensions               │
└──────────────┬──────────────────────┘
               │ File system access
┌──────────────▼──────────────────────┐
│     Remote Machine/Container        │
│  - Workspace files                  │
│  - Terminal access                  │
│  - Development environment          │
└─────────────────────────────────────┘
```

**Key Features**:
- ✅ **Browser-based**: Full VS Code in any browser
- ✅ **Extension Support**: Most VS Code extensions work
- ✅ **Terminal Access**: Integrated terminal on remote machine
- ✅ **No Desktop Required**: Works on tablets, Chromebooks
- ✅ **Self-hostable**: Run on your own infrastructure

**Use Case for Agents**:
- Agents can control code-server via HTTP API
- Provides complete IDE environment for development tasks
- Can be embedded in agent-controlled workflows

**Installation**:
```bash
curl -fsSL https://code-server.dev/install.sh | sh
code-server --bind-addr 0.0.0.0:8080
```

---

### 1.3 openvscode-server (Gitpod)

**Source**: Gitpod (now used by GitHub Codespaces)
**Purpose**: Browser-based VS Code server used at scale

#### Architecture

```
Same as code-server, but optimized for cloud-scale:
- Used by Gitpod and GitHub Codespaces
- Kubernetes-ready
- Multi-tenant support
- Resource isolation
```

**Key Differences from code-server**:
- ✅ **Scale-optimized**: Designed for cloud platforms
- ✅ **Upstream alignment**: Closer to VS Code upstream
- ✅ **K8s integration**: Better Kubernetes support

**Use Case for Agents**:
- Enterprise-grade VS Code control
- Multi-agent deployments
- Cloud-based development environments

---

### 1.4 VS Code Remote Development (Microsoft Official)

**Source**: Microsoft
**Purpose**: Official VS Code remote development architecture

#### Architecture

```
┌─────────────────────────────────────┐
│   VS Code Desktop (Frontend)        │
│  - UI rendering                     │
│  - Extension host (some extensions) │
└──────────────┬──────────────────────┘
               │ Secure tunnel / SSH / WSL
┌──────────────▼──────────────────────┐
│   VS Code Server (Backend)          │
│  - Extension host (most extensions) │
│  - Terminal                         │
│  - Debugging                        │
│  - File operations                  │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Remote Environment                │
│  - Container / VM / WSL / SSH       │
└─────────────────────────────────────┘
```

**Key Features**:
- ✅ **Split Architecture**: Frontend/backend separation
- ✅ **Extension Isolation**: Extensions run where they're needed
- ✅ **Secure Tunnels**: Built-in secure remote access
- ✅ **Multi-platform**: Works with SSH, WSL, containers

**Use Case for Agents**:
- Official Microsoft architecture (most stable)
- Best for enterprise environments
- Strong security model

---

## 2. Terminal Control Systems

### 2.1 PTY (Pseudo-Terminal) Architecture

**Source**: Unix/Linux standard
**Purpose**: Virtual terminal for process I/O control

#### Architecture

```
┌─────────────────────────────────────┐
│   Terminal Emulator / Container     │
│  - Reads from PTY master            │
│  - Writes user input to master      │
└──────────────┬──────────────────────┘
               │ Bidirectional pipe
┌──────────────▼──────────────────────┐
│      PTY Master (/dev/ptmx)         │
│  - Controls communication           │
│  - Manages data flow                │
│  - Terminal settings                │
└──────────────┬──────────────────────┘
               │ Line discipline
┌──────────────▼──────────────────────┐
│      PTY Slave (/dev/pts/N)         │
│  - Acts like real terminal          │
│  - Processes interact here          │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│      Shell Process (bash/zsh)       │
│  - stdin/stdout/stderr via PTY      │
│  - Controlling terminal             │
└─────────────────────────────────────┘
```

**How Docker/Kubernetes Use PTY**:
```
$ docker run -it ubuntu bash
  ├─> Allocates PTY pair
  ├─> Sets slave as bash controlling terminal
  └─> Binds stdin/stdout to master FD

$ docker attach <container>
  └─> Binds your terminal to existing PTY master
```

**Key Features**:
- ✅ **Bidirectional**: Full duplex communication
- ✅ **Line Discipline**: Handles special chars (Ctrl+C, Ctrl+D)
- ✅ **Container Isolation**: Each container has its own PTY
- ✅ **Standard Unix**: Works with all Unix/Linux systems

**Use Case for Agents**:
- **Critical for terminal control**: Agents need PTY to interact with shells
- **Input simulation**: Can send keystrokes programmatically
- **Output capture**: Capture shell output in real-time

**Python Implementation**:
```python
import pty
import os

# Fork and create PTY
pid, fd = pty.fork()

if pid == 0:
    # Child process - runs in PTY
    os.execlp('bash', 'bash')
else:
    # Parent process - controls PTY
    while True:
        data = os.read(fd, 1024)
        print(data.decode())
```

---

### 2.2 WebSocket Terminal Protocol

**Source**: Various (xterm.js, ttyd, gotty)
**Purpose**: Terminal access via WebSocket for web UIs

#### Architecture

```
┌─────────────────────────────────────┐
│   Browser (xterm.js)                │
│  - Renders terminal UI              │
│  - Sends keystrokes via WebSocket   │
└──────────────┬──────────────────────┘
               │ WebSocket (binary/text)
┌──────────────▼──────────────────────┐
│   Terminal WebSocket Server         │
│  - ttyd / gotty / custom            │
│  - Manages WebSocket connections    │
└──────────────┬──────────────────────┘
               │ Reads/Writes
┌──────────────▼──────────────────────┐
│        PTY Master                   │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│     Shell Process                   │
└─────────────────────────────────────┘
```

**Popular Libraries**:

**xterm.js** (Frontend):
```javascript
import { Terminal } from 'xterm';
const term = new Terminal();
term.open(document.getElementById('terminal'));

const ws = new WebSocket('ws://localhost:8080/terminal');
ws.onmessage = (event) => term.write(event.data);
term.onData((data) => ws.send(data));
```

**ttyd** (Backend):
```bash
ttyd -p 8080 bash
# Serves bash over WebSocket at ws://localhost:8080
```

**Key Features**:
- ✅ **Browser Access**: Full terminal in web browser
- ✅ **Real-time**: Instant keystroke transmission
- ✅ **ANSI Colors**: Full terminal emulation (256 colors, etc.)
- ✅ **Multiplexing**: Multiple terminals over single server

**Use Case for Agents**:
- **Web UI integration**: Embed terminal in agent web interface
- **Remote control**: Control terminal from browser
- **Real-time feedback**: Stream command output to users

---

### 2.3 Daytona SDK Process Control

**Source**: Daytona
**Purpose**: Execute commands in secure cloud sandboxes

#### Architecture

```
┌─────────────────────────────────────┐
│   Agent Code (Python/JS)            │
│  - Daytona SDK client               │
└──────────────┬──────────────────────┘
               │ HTTPS/WebSocket
┌──────────────▼──────────────────────┐
│   Daytona Cloud API                 │
│  - Sandbox orchestration            │
│  - API gateway                      │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Firecracker microVM Sandbox       │
│  - Isolated kernel                  │
│  - Sub-90ms startup                 │
│  - Stateful filesystem              │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Process Execution                 │
│  sandbox.process.code_run(cmd)      │
└─────────────────────────────────────┘
```

**Python SDK**:
```python
from daytona_sdk import Daytona, DaytonaConfig

config = DaytonaConfig(api_key="dtn_...", api_url="https://app.daytona.io/api")
client = Daytona(config=config)

# Create sandbox
sandbox = client.create()

# Execute command
result = sandbox.process.code_run("python script.py", work_dir="/workspace")
print(result.stdout)
print(result.stderr)
print(result.exit_code)
```

**Key Features**:
- ✅ **Fast**: Sub-90ms sandbox creation
- ✅ **Isolated**: Firecracker microVM (hardware-level isolation)
- ✅ **Stateful**: Persistent filesystem during session
- ✅ **Cloud-native**: No local infrastructure needed

**Use Case for Agents**:
- **Production-ready**: Enterprise-grade security
- **Zero infrastructure**: No Docker/K8s setup needed
- **Scalable**: Handle thousands of concurrent sandboxes

---

## 3. Linux & Container Control

### 3.1 Firecracker microVMs (E2B, Modal)

**Source**: AWS (open-source)
**Purpose**: Lightweight microVMs for secure code execution

#### Architecture

```
┌─────────────────────────────────────┐
│   Host Machine (Linux + KVM)        │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Firecracker Process (Rust)        │
│  - VMM (Virtual Machine Monitor)    │
│  - REST API for VM management       │
│  - ~50k lines of code               │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   microVM Instance                  │
│  - Own Linux kernel                 │
│  - Minimal devices                  │
│  - <5MB RAM overhead                │
│  - <125ms boot time                 │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   User Code Execution               │
│  - Python, Node.js, etc.            │
│  - Isolated from host               │
└─────────────────────────────────────┘
```

**Comparison: Firecracker vs Docker**:

| Feature | Firecracker | Docker |
|---------|-------------|--------|
| **Isolation** | VM-level (own kernel) | Process-level (shared kernel) |
| **Security** | Hardware isolation (KVM) | Namespace/cgroup isolation |
| **Boot time** | <125ms | <1s (similar) |
| **Overhead** | <5MB per VM | <10MB per container |
| **Use case** | Multi-tenant, untrusted code | Dev environments, microservices |

**Key Features**:
- ✅ **VM-level isolation**: Each microVM has its own kernel
- ✅ **Minimal attack surface**: Only 50k LoC (vs millions in QEMU)
- ✅ **Fast**: 3x faster boot than QEMU microVMs
- ✅ **Lightweight**: 5MB RAM overhead vs 100MB+ for VMs

**E2B Implementation**:
```python
from e2b import Sandbox

sandbox = Sandbox(api_key="...")
sandbox.run_code("print('Hello World')")
# Runs in Firecracker microVM (<150ms startup)
```

**Use Case for Agents**:
- **Untrusted code execution**: AI-generated code runs safely
- **Multi-tenant**: Thousands of isolated sandboxes
- **Production security**: Used by AWS Lambda

---

### 3.2 gVisor (Modal, Google)

**Source**: Google
**Purpose**: Container-based isolation with syscall interception

#### Architecture

```
┌─────────────────────────────────────┐
│   User Application                  │
│  - Python, Node.js, etc.            │
└──────────────┬──────────────────────┘
               │ System calls
┌──────────────▼──────────────────────┐
│   gVisor Sentry (Go)                │
│  - User-space kernel                │
│  - Intercepts syscalls              │
│  - Implements Linux kernel API      │
└──────────────┬──────────────────────┘
               │ Limited syscalls
┌──────────────▼──────────────────────┐
│   Host Linux Kernel                 │
└─────────────────────────────────────┘
```

**Key Differences from Docker**:
- ✅ **Syscall interception**: gVisor intercepts all system calls
- ✅ **User-space kernel**: Implements kernel functionality in userspace
- ✅ **Stronger isolation**: Limits kernel surface area exposed to container
- ⚠️ **Performance overhead**: ~10-20% slower than native containers

**Use Case for Agents**:
- **Better than Docker**: Stronger security than regular containers
- **Less overhead than VMs**: Faster than Firecracker for short tasks
- **Good for ML**: Modal uses it for GPU workloads

---

### 3.3 Docker (Standard Container)

**Source**: Docker Inc.
**Purpose**: Standard containerization for development

#### Architecture

```
┌─────────────────────────────────────┐
│   Docker Container                  │
│  - Isolated processes               │
│  - Own filesystem (layers)          │
│  - Network namespace                │
└──────────────┬──────────────────────┘
               │ Shared kernel
┌──────────────▼──────────────────────┐
│   Linux Kernel (Host)               │
│  - cgroups (resource limits)        │
│  - namespaces (isolation)           │
│  - seccomp (syscall filtering)      │
└─────────────────────────────────────┘
```

**Key Features**:
- ✅ **Ubiquitous**: Industry standard
- ✅ **Fast**: <1s startup
- ✅ **Ecosystem**: Huge library of images
- ⚠️ **Security**: Shared kernel (weaker than VMs)

**Use Case for Agents**:
- **Development**: Good for local agent testing
- **Not for production multi-tenant**: Use Firecracker/gVisor instead
- **OpenHands uses**: Docker for local, Daytona for production

---

### 3.4 WebAssembly System Interface (WASI)

**Source**: Bytecode Alliance
**Purpose**: Run code in browser or server with sandboxing

#### Architecture (WebContainers - StackBlitz)

```
┌─────────────────────────────────────┐
│   Browser Tab                       │
│  - No server backend needed!        │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   WebContainer (WebAssembly OS)     │
│  - Micro OS in WASM                 │
│  - Node.js compiled to WASM         │
│  - Virtualized filesystem           │
│  - Virtualized networking           │
└──────────────┬──────────────────────┘
               │ Service Worker
┌──────────────▼──────────────────────┐
│   Browser Service Worker            │
│  - HTTP request handling            │
│  - Network virtualization           │
└─────────────────────────────────────┘
```

**How StackBlitz Runs Node.js in Browser**:
```javascript
import { WebContainer } from '@webcontainer/api';

const container = await WebContainer.boot();
await container.fs.writeFile('/index.js', 'console.log("Hello")');

const process = await container.spawn('node', ['index.js']);
process.output.pipeTo(new WritableStream({
  write(data) { console.log(data); }
}));
```

**Key Features**:
- ✅ **Browser execution**: Entire Node.js environment in browser
- ✅ **Faster than localhost**: Lower latency than HTTP to 127.0.0.1
- ✅ **Offline capable**: Works without internet
- ✅ **20% faster builds**: npm install 5x faster than native
- ✅ **Zero server cost**: Runs entirely client-side

**Use Case for Agents**:
- **Client-side agents**: AI code generation in browser
- **No infrastructure**: Zero server costs
- **Instant startup**: No VM/container provisioning
- **Demo/Education**: Perfect for tutorials

---

## 4. Browser Automation Systems

### 4.1 Playwright (Microsoft)

**Source**: Microsoft
**Purpose**: Cross-browser automation and testing

#### Architecture

```
┌─────────────────────────────────────┐
│   Test Script (Python/JS/Java/.NET) │
│  - Playwright API                   │
└──────────────┬──────────────────────┘
               │ WebSocket (persistent)
┌──────────────▼──────────────────────┐
│   Browser Process                   │
│  - Chromium / Firefox / WebKit      │
│  - Headless or Headed               │
│  - Instrumentation hooks            │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Web Page / Application            │
│  - DOM manipulation                 │
│  - JavaScript execution             │
│  - Screenshot/video capture         │
└─────────────────────────────────────┘
```

**Key Innovations**:

1. **Out-of-process architecture**: Unlike Selenium (HTTP per command), Playwright uses persistent WebSocket
2. **Auto-waiting**: Automatically waits for elements to be actionable
3. **Browser contexts**: Each test gets fresh browser profile (full isolation, <5ms overhead)
4. **Cross-browser**: Single API for Chromium, Firefox, WebKit

**Python Example**:
```python
from playwright.sync_api import sync_playwright

with sync_playwright() as p:
    browser = p.chromium.launch(headless=True)
    page = browser.new_page()

    page.goto('https://example.com')
    page.click('button#submit')
    page.screenshot(path='screenshot.png')

    browser.close()
```

**Performance**:
- ✅ **2-15x faster**: Headless mode vs regular browser
- ✅ **Parallel execution**: Run tests across browsers simultaneously
- ✅ **Network control**: Intercept/mock network requests
- ✅ **Video recording**: Built-in test recording

**Use Case for Agents**:
- **Web testing**: AI agents test web applications
- **Data extraction**: Scrape dynamic websites
- **UI automation**: Fill forms, click buttons
- **Visual regression**: Screenshot comparison

---

### 4.2 browser-use (Python Library)

**Source**: Open-source community
**Purpose**: Let AI agents control browsers via natural language

#### Architecture

```
┌─────────────────────────────────────┐
│   AI Agent (OpenAI/Gemini/etc.)     │
│  - Natural language task            │
│  - "Find flights to NYC"            │
└──────────────┬──────────────────────┘
               │ LLM API
┌──────────────▼──────────────────────┐
│   browser-use Library               │
│  - Interprets LLM output            │
│  - Plans browser actions            │
│  - Extracts elements from DOM       │
└──────────────┬──────────────────────┘
               │ Playwright API
┌──────────────▼──────────────────────┐
│   Browser (via Playwright)          │
│  - Executes actions                 │
│  - Clicks, types, navigates         │
└─────────────────────────────────────┘
```

**Python Example**:
```python
from browser_use import Agent

agent = Agent(
    task="Find flights from NYC to London under $500",
    llm=openai_llm
)

result = agent.run()
# Agent will:
# 1. Navigate to flight search sites
# 2. Fill in search forms
# 3. Filter results
# 4. Extract relevant data
```

**Key Features**:
- ✅ **Natural language**: Describe actions in plain English
- ✅ **Element finding**: AI finds elements (no XPath/selectors)
- ✅ **Multi-step**: Handles complex workflows
- ✅ **Vision-based**: Can use screenshots for element location

**Advantages Over Traditional Automation**:

| Traditional (Selenium/Playwright) | browser-use |
|----------------------------------|-------------|
| Brittle selectors (break often) | AI finds elements |
| Complex XPath/CSS | Natural language |
| Manual step definition | AI plans steps |
| Maintenance heavy | Self-healing |

**Use Case for Agents**:
- **Autonomous web tasks**: Job applications, research, e-commerce
- **Testing**: UAT, exploratory testing
- **Data migration**: Extract data from web apps
- **No-code automation**: Non-developers can describe tasks

---

### 4.3 Puppeteer (Google)

**Source**: Google Chrome team
**Purpose**: Chrome/Chromium automation

**Comparison to Playwright**:

| Feature | Playwright | Puppeteer |
|---------|-----------|-----------|
| **Browsers** | Chrome, Firefox, Safari | Chrome only |
| **Protocol** | WebSocket | Chrome DevTools Protocol |
| **Language** | Python, JS, Java, .NET | JavaScript/TypeScript only |
| **Maintenance** | Microsoft (active) | Google (slower) |

**Use Case for Agents**:
- **Chrome-only**: If you only need Chrome/Chromium
- **Otherwise use Playwright**: More features, better maintained

---

### 4.4 Selenium

**Source**: ThoughtWorks (2004)
**Purpose**: Legacy web automation standard

**Why NOT recommended for modern agents**:
- ❌ **Slow**: HTTP request per command (vs WebSocket in Playwright)
- ❌ **Flaky**: No auto-waiting (manual `time.sleep()` needed)
- ❌ **Old architecture**: Designed pre-async era
- ✅ **Use Playwright instead**: Faster, more reliable, better API

---

## 5. Complete Integrated Agent Systems

### 5.1 OpenHands (Open-source AI Software Engineer)

**Source**: Princeton University, All-Hands-AI
**Purpose**: Complete autonomous software development agent

#### Architecture Evolution

**V0 (Monolithic)**:
```
┌─────────────────────────────────────┐
│   OpenHands Core                    │
│  - Agent logic                      │
│  - Event stream                     │
│  - Sandbox manager                  │
│  - All in one process               │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Docker Sandbox                    │
│  - Code execution                   │
│  - Process synchronization issues   │
└─────────────────────────────────────┘
```

**V1 (Modular - Current)**:
```
┌─────────────────────────────────────┐
│   OpenHands SDK (Core)              │
│  - Event sourcing pattern           │
│  - Immutable event log              │
│  - Stateless architecture           │
└──────────────┬──────────────────────┘
               │
┌──────────────┼──────────────────────┐
│              │                      │
│   ┌──────────▼─────────┐  ┌────────▼──────┐
│   │  Tools Package     │  │ Workspace Pkg │
│   │  - Bash tool       │  │ - File ops    │
│   │  - Edit tool       │  │ - VS Code     │
│   │  - Browser tool    │  │ - VNC         │
│   └────────────────────┘  └───────────────┘
│              │                      │
└──────────────┼──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Runtime Environment               │
│  - Docker / Daytona / K8s           │
│  - Sandboxed execution              │
└─────────────────────────────────────┘
```

**Event Stream Architecture**:

```
User: "Fix the login bug"
  ↓
[Event] UserMessage("Fix the login bug")
  ↓
[Event] AgentThink("I'll search for login code")
  ↓
[Event] ToolCall(Bash, "grep -r 'login' src/")
  ↓
[Event] ToolResult(stdout="src/auth/login.py:...")
  ↓
[Event] AgentThink("Found the issue in login.py")
  ↓
[Event] ToolCall(Edit, file="src/auth/login.py", ...)
  ↓
[Event] ToolResult(success=True)
  ↓
[Event] AgentMessage("Bug fixed!")
```

**Key Innovations**:

1. **Event Sourcing**: All interactions are immutable events
   - ✅ Reproducibility: Replay entire session
   - ✅ Fault recovery: Resume from any point
   - ✅ Debugging: Full audit trail

2. **Composable Architecture**:
   - ✅ SDK: Core agent logic
   - ✅ Tools: Pluggable capabilities
   - ✅ Workspace: Remote interfaces
   - ✅ Server: REST/WebSocket API

3. **Multi-Runtime Support**:
   - Docker (local development)
   - Daytona (production)
   - Kubernetes (scale)

**Agent Interface**:
```python
class Agent:
    def step(self, state: State) -> Action:
        """
        Given current state (event stream),
        decide next action.
        """
        pass
```

**Runtime Integration (Daytona)**:

OpenHands merged official Daytona runtime support (PR #6863):
- ✅ Secure sandboxes via Daytona SDK
- ✅ Sub-90ms sandbox creation
- ✅ Stateful environments
- ✅ Production-ready isolation

**Tools Available**:

1. **Bash Tool**: Execute shell commands
2. **Edit Tool**: View and edit files
3. **Browser Tool**: Web automation
4. **Ask Tool**: Request user input

**Use Case for Our System**:
- **Direct inspiration**: We based our architecture on OpenHands
- **Proven pattern**: Event stream + sandbox execution
- **Production-ready**: Used by thousands of developers

**Performance (SWE-Bench)**:
- 🏆 Top open-source agent on SWE-Bench Verified
- 🏆 23.3% solve rate (with Claude 3.5 Sonnet)

---

### 5.2 SWE-agent (Princeton)

**Source**: Princeton NLP Group
**Purpose**: Solve GitHub issues automatically

#### Architecture

```
┌─────────────────────────────────────┐
│   GitHub Issue                      │
│  "Login button doesn't work"        │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   SWE-agent                         │
│  ┌──────────────────────────────┐   │
│  │  LLM (Claude/GPT)            │   │
│  │  - Generates actions         │   │
│  └──────────┬───────────────────┘   │
│             │                       │
│  ┌──────────▼───────────────────┐   │
│  │  Action Parser               │   │
│  │  - Bash commands             │   │
│  │  - Edit commands             │   │
│  └──────────┬───────────────────┘   │
│             │                       │
│  ┌──────────▼───────────────────┐   │
│  │  Tool Executor               │   │
│  │  - Bash tool                 │   │
│  │  - Edit tool                 │   │
│  └──────────┬───────────────────┘   │
└─────────────┼───────────────────────┘
              │
┌─────────────▼───────────────────────┐
│   Sandbox Environment               │
│  - Repository clone                 │
│  - Testing environment              │
└─────────────────────────────────────┘
```

**Specialized Agent Roles** (Advanced Approaches):

MarsCode agent uses 6 specialized roles:

1. **Searcher**: Find relevant code locations
2. **Planner**: Create fix strategy
3. **Reproducer**: Reproduce the bug
4. **Programmer**: Write fix code
5. **Tester**: Run tests
6. **Editor**: Apply final edits

**Key Features**:
- ✅ **GitHub integration**: Direct issue → patch workflow
- ✅ **Specialized tools**: Custom bash and edit tools
- ✅ **Benchmark-driven**: Optimized for SWE-Bench
- ✅ **Academic rigor**: Published at NeurIPS 2024

**Use Case for Our System**:
- **Pattern**: Multi-step task decomposition
- **Tools**: Specialized tools for specific tasks
- **Testing**: Emphasis on verification

---

### 5.3 Anthropic Computer Use

**Source**: Anthropic
**Purpose**: AI agents control desktop applications

#### Architecture

```
┌─────────────────────────────────────┐
│   User Task                         │
│  "Find and download the report"     │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Claude API (with Computer Use)    │
│  - Takes screenshots                │
│  - Analyzes visual content          │
│  - Decides next action              │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Computer Use Tool                 │
│  - mouse_move(x, y)                 │
│  - left_click()                     │
│  - type("text")                     │
│  - key("enter")                     │
│  - screenshot()                     │
│  - scroll(direction)                │
└──────────────┬──────────────────────┘
               │
┌──────────────▼──────────────────────┐
│   Desktop Environment               │
│  - Any OS (Windows/Mac/Linux)       │
│  - Any application                  │
│  - Native apps + web                │
└─────────────────────────────────────┘
```

**API Update (2025-01-24)**:

New tool: `computer_20250124` with enhanced actions:
```json
{
  "type": "computer_20250124",
  "name": "computer",
  "action": "left_click",
  "coordinate": [100, 200]
}
```

**Available Actions** (Feb 2025):
- `key`: Press a key
- `type`: Type text
- `mouse_move`: Move cursor
- `left_click`: Click
- `left_click_drag`: Drag
- `right_click`: Right click
- `middle_click`: Middle click
- `double_click`: Double click
- `screenshot`: Capture screen
- `cursor_position`: Get position
- **NEW**: `hold_key`, `left_mouse_down`, `left_mouse_up`, `scroll`, `triple_click`, `wait`

**Decoupled Tools**:
- `text_editor_20250124`: File editing
- `bash_20250124`: Shell commands

**Key Features**:
- ✅ **Vision-based**: Uses screenshots to understand UI
- ✅ **Universal**: Works with any desktop app
- ✅ **Pixel-perfect**: Coordinates for clicking
- ✅ **Multi-platform**: Windows, Mac, Linux

**Use Case**:
- **Desktop automation**: Beyond browser and terminal
- **Legacy apps**: Control apps without API
- **Visual workflows**: Click buttons, fill forms

**Limitations**:
- ⚠️ **Beta**: Still in development
- ⚠️ **Slow**: Screenshot → analyze → act cycle
- ⚠️ **Expensive**: API calls for each action

---

### 5.4 Cloud Development Environments

#### Comparison Matrix

| Platform | Architecture | Isolation | Use Case |
|----------|-------------|-----------|----------|
| **GitHub Codespaces** | Server-side, VS Code in browser | VM per user | GitHub integration, enterprise |
| **Gitpod** | K8s pods, openvscode-server | Container per workspace | Open-source projects, teams |
| **DevPod** | Client-side, any backend | Provider-dependent | Self-hosted, air-gapped |
| **Daytona** | Firecracker microVMs | VM-level | AI agents, production |

**GitHub Codespaces**:
```
User → VS Code Web → GitHub VM → Dev Container
```
- ✅ GitHub integration
- ❌ Closed-source
- ❌ Expensive ($0.18/hour for 2-core)

**Gitpod**:
```
User → Browser → Gitpod K8s → Container
```
- ✅ Open-source
- ✅ Self-hostable
- ✅ gitpod.yml configuration

**DevPod**:
```
User PC → DevPod CLI → Provider (Docker/K8s/SSH)
```
- ✅ Client-only (no server)
- ✅ Works offline
- ✅ devcontainer.json standard
- ✅ Air-gapped environments

**Daytona**:
```
API → Daytona Cloud → Firecracker microVM → Dev Environment
```
- ✅ Sub-90ms startup
- ✅ VM isolation
- ✅ API-first (agent-friendly)
- ✅ Stateful environments

**Use Case for Agents**:
- **Daytona**: Best for AI agents (API-first, fast, secure)
- **DevPod**: Good for local development
- **Gitpod/Codespaces**: Good for human developers

---

### 5.5 Manus AI (Autonomous Agent System)

**Source**: Butterfly Effect Technology (Singapore)
**Launch**: March 6, 2025
**Purpose**: Fully autonomous AI agent for complex real-world tasks

#### Overview

Manus (Latin for "hand") is one of the first fully autonomous AI agents capable of independent reasoning, dynamic planning, and autonomous decision-making without continuous human supervision. It represents a significant evolution in agentic systems, combining cutting-edge architecture with production-ready engineering.

#### Multi-Agent Architecture

```
┌─────────────────────────────────────────────────────────────┐
│                  USER TASK REQUEST                          │
└──────────────────┬──────────────────────────────────────────┘
                   │
┌──────────────────▼──────────────────────────────────────────┐
│            EXECUTOR AGENT (User Interface)                  │
│  - Single point of user interaction                         │
│  - No insight into internal agents (context isolation)      │
└──────────────────┬──────────────────────────────────────────┘
                   │
┌──────────────────▼──────────────────────────────────────────┐
│         ORCHESTRATION LAYER (Coordinator)                   │
│  - Task decomposition and delegation                        │
│  - Multi-agent coordination                                 │
│  - State machine with tool masking                          │
└──────────────────┬──────────────────────────────────────────┘
                   │
     ┌─────────────┼─────────────┐
     │             │             │
┌────▼────┐  ┌────▼────┐  ┌────▼────┐
│ PLANNER │  │KNOWLEDGE│  │EXECUTION│
│  AGENT  │  │  AGENT  │  │  AGENT  │
└────┬────┘  └────┬────┘  └────┬────┘
     │             │             │
     │  ┌──────────▼──────────┐  │
     │  │    MEMORY LAYER     │  │
     │  │  - File-based       │  │
     │  │  - todo.md tracking │  │
     │  └─────────────────────┘  │
     │                            │
┌────▼────────────────────────────▼────┐
│     CODE-ACT EXECUTION ENGINE        │
│  - Python as action mechanism        │
│  - 29 specialized tools              │
│  - Browser Use framework             │
└──────────────┬───────────────────────┘
               │
┌──────────────▼───────────────────────┐
│     LINUX SANDBOX (Ubuntu)           │
│  - Python 3.10                       │
│  - Node.js 20                        │
│  - Playwright (browser automation)   │
│  - Full filesystem access            │
└──────────────────────────────────────┘
```

#### Core Architecture Components

**1. Planner Agent**
- **Role**: Strategic task decomposition
- **Function**: Breaks down complex goals into manageable sub-tasks
- **Output**: Step-by-step execution plan with dependencies

**2. Knowledge Agent**
- **Role**: Information retrieval and context management
- **Function**: Web search, document analysis, data extraction
- **Isolation**: Hidden from executor agent (context length control)

**3. Execution Agent**
- **Role**: Action implementation
- **Function**: Interfaces with external systems (browser, APIs, files, shell)
- **Tools**: 29 specialized tools including Browser Use framework

**4. Memory System**
- **File-based storage**: Code and data in files (not in context)
- **todo.md tracking**: Global plan maintained in recent attention span
- **Context optimization**: Only conclusions/actions in live context

#### Foundation Models

**Primary**: Anthropic Claude 3.5/3.7 Sonnet
**Secondary**: Alibaba Qwen (fine-tuned versions)
**Approach**: Multi-model dynamic selection based on subtask requirements

**Why Claude Sonnet**:
- ✅ Superior reasoning for complex tasks
- ✅ Large context window (200K tokens)
- ✅ Excellent at following structured prompts
- ✅ KV-cache optimization support

#### Code-Act Methodology

**Core Innovation**: Uses executable Python code as primary action mechanism instead of JSON function-calling

**Architecture**: Based on LangGraph CodeAct implementation

**Advantages**:
```python
# Traditional JSON function-calling (limited)
{
  "tool": "web_search",
  "query": "Daytona sandboxes"
}

# Code-Act (flexible, composable)
import requests
results = requests.get("https://api.search.com", params={"q": "Daytona"})
data = [r["title"] for r in results.json() if "sandbox" in r["text"]]
save_to_file("results.json", data)
```

**Benefits**:
- ✅ More expressive than JSON schemas
- ✅ Can compose multiple operations
- ✅ Handles complex data transformations
- ✅ Fewer steps to solve complex tasks

#### Browser Automation (Browser Use Framework)

**Integration**: Manus uses the open-source Browser Use framework + Playwright

```
User Task: "Find flights NYC to London under $500"
     ↓
[Manus] Generates plan
     ↓
[Browser Use] AI-controlled browser navigation
     ↓
[Playwright] Low-level browser automation
     ↓
[Result] Extracted flight data
```

**Capabilities**:
- ✅ Parse HTML at code level
- ✅ Click buttons, fill forms
- ✅ Navigate multi-page workflows
- ✅ Extract structured data
- ✅ Handle dynamic JavaScript content

**Example**:
```python
# Browser Use in Manus
from browser_use import Agent

agent = Agent(
    task="Search Google for Daytona sandboxes and summarize top 3 results",
    llm=claude_sonnet,
    browser=playwright_browser
)

result = await agent.run()
# Agent autonomously:
# 1. Opens browser
# 2. Navigates to Google
# 3. Searches for query
# 4. Clicks top results
# 5. Extracts content
# 6. Summarizes findings
```

#### Context Engineering (Production Secret Sauce)

Manus uses **context engineering instead of fine-tuning** for rapid iteration and reliability.

**Key Principles**:

**1. KV-Cache Optimization** (Most Critical Metric)

```
Cached tokens:   $0.30/MTok  }
Uncached tokens: $3.00/MTok  } 10x cost difference!
```

**Rules**:
- ❌ **NEVER** put timestamps at beginning of system prompt
- ❌ **NEVER** modify previous actions/observations
- ✅ **ALWAYS** make context append-only
- ✅ **ALWAYS** preserve cache alignment

**Impact**: Single-token difference can invalidate entire cache from that point forward

**2. Tool Management via Masking**

```
Traditional (cache-breaking):
- Dynamically add/remove tools from action space
- Changes context → invalidates KV-cache
- Confuses model with changing capabilities

Manus Approach (cache-preserving):
- All 29 tools always in context
- State machine tracks when tools are valid
- Logit masking during decoding prevents invalid tool calls
- Context stays stable → cache stays valid
```

**3. File-Based Memory Management**

```
❌ Bad (bloats context):
Context: [raw search results, 10 pages of data, ...]

✅ Good (segregated memory):
Files:   search_results.json (data stored here)
Context: "Saved search results to file. Key finding: Daytona uses Firecracker..."
```

**Strategy**:
- Code and data → Files (agent opens when needed)
- Raw results → Saved to disk
- Conclusions/actions → Live context only

**Benefits**:
- ✅ Context stays manageable
- ✅ No "lost in the middle" issues
- ✅ Can handle large datasets
- ✅ Better long-term memory

**4. Attention Manipulation (todo.md Pattern)**

```
Problem: Long context → agent forgets original goal

Solution: Continuously update todo.md file
┌─────────────────────────────────┐
│ todo.md (always in recent memory)│
├─────────────────────────────────┤
│ ✅ Search for flight options     │
│ ✅ Filter by price               │
│ 🔄 Compare airlines              │
│ ⬜ Book cheapest option          │
│ ⬜ Send confirmation email       │
└─────────────────────────────────┘
```

**Effect**: Pushes global plan into model's recent attention span, maintaining goal alignment across multi-step tasks

**5. Error Preservation (Learning from Mistakes)**

```
❌ Bad (removes failed attempts):
Action: install_package("numppy")  ← typo
Result: Error: package not found
[Remove from context]

✅ Good (keeps failures):
Action: install_package("numppy")
Result: Error: package not found
Action: install_package("numpy")   ← corrected
Result: Success
```

**Benefit**: Seeing own mistakes helps agent learn, reduces repetition of same errors

**6. Diversity Injection (Breaking Patterns)**

```
Same action, different serialization:

Variation 1: "Execute command: ls -la"
Variation 2: "Run shell: ls -la"
Variation 3: "List directory contents"

Purpose: Structured noise prevents repetitive behaviors
```

#### Agent Loop (Iterative Process)

```
1. ANALYZE
   ↓
   - Assess current state
   - Review previous actions
   - Check goal progress

2. PLAN
   ↓
   - Decompose remaining work
   - Select next tool/action
   - Update todo.md

3. EXECUTE
   ↓
   - Generate Python code (Code-Act)
   - Run in sandbox
   - Invoke tools (browser, shell, etc.)

4. OBSERVE
   ↓
   - Capture results (stdout, files, etc.)
   - Update memory
   - Append to context (append-only!)

5. REPEAT until TASK_COMPLETED
```

#### System Prompt Structure

```
<system_capability>
  - List of 29 available tools
  - Capabilities and limitations
</system_capability>

<browser_rules>
  - When to use Browser Use
  - How to extract data
  - Error handling
</browser_rules>

<coding_rules>
  - Python best practices
  - Error handling patterns
  - File management
</coding_rules>

<memory_management>
  - When to save to files
  - How to use todo.md
  - Context optimization
</memory_management>

<execution_guidelines>
  - Step-by-step thinking
  - Verification steps
  - Success criteria
</execution_guidelines>
```

**Development Philosophy**: "Stochastic Gradient Descent"
- Rebuilt framework 4 times
- Manual prompt tuning and empirical testing
- Architecture searching through iteration

#### Technical Stack

| Component | Technology |
|-----------|-----------|
| **Foundation LLM** | Claude 3.7 Sonnet, Qwen |
| **Action Framework** | LangGraph CodeAct |
| **Browser Automation** | Browser Use + Playwright |
| **Sandbox** | Docker (Ubuntu + Python + Node) |
| **Tools** | 29 specialized tools |
| **Orchestration** | Custom multi-agent coordinator |

#### Performance Benchmarks

**GAIA Benchmark** (General AI Assistants):

| Level | Manus | OpenAI Deep Research |
|-------|-------|---------------------|
| **Level 1** | 86.5% | 74.3% |
| **Level 2** | 70.1% | 69.1% |
| **Level 3** | 57.7% | 47.6% |

**SWE-Bench** (Software Engineering):
- Uses Manus architecture patterns
- State-of-the-art performance on code tasks

#### Unique Features

**1. Asynchronous Operation**
```
Traditional: User must stay connected
Manus: Cloud-based execution continues after user disconnects

User → Submit task → Close laptop
                 ↓
          [Manus works autonomously]
                 ↓
User ← Notification: "Task completed!"
```

**2. Transparency ("Manus's Computer")**
- Full session replay
- View all actions taken
- Inspect intermediate results
- Debug agent reasoning

**3. Multi-modal Input/Output**
- **Input**: Text, images, tables, code
- **Output**: Reports, visualizations, websites, spreadsheets

#### Open-Source Replication

Manus can be replicated using open-source components:

```python
# Simplified Manus architecture

from langchain import CodeActAgent
from browser_use import Agent as BrowserAgent
from playwright.async_api import async_playwright

# 1. Foundation (CodeAct agent)
agent = CodeActAgent(
    model="claude-3.7-sonnet",
    tools=[
        bash_tool,
        file_tool,
        browser_tool,
        # ... 26 more tools
    ]
)

# 2. Browser automation
browser_agent = BrowserAgent(
    task=task,
    llm=claude,
    browser=playwright_browser
)

# 3. Sandbox
docker run -it ubuntu:22.04 \
  -v /workspace:/workspace \
  python3 agent.py
```

#### Key Innovations Summary

1. **Multi-Agent Architecture**: Specialized agents (Planner, Knowledge, Execution) coordinated by orchestration layer

2. **Code-Act Methodology**: Python code as action mechanism (more expressive than JSON)

3. **Context Engineering**: Production-ready prompt architecture optimized for KV-cache

4. **Browser Use Integration**: AI-controlled web automation via open-source framework

5. **File-Based Memory**: Segregated storage keeps context manageable

6. **Asynchronous Execution**: Continues working after user disconnects

7. **Transparency**: Full session replay and debugging

#### Lessons for Our System

**What to Adopt**:

✅ **Context Engineering Principles**:
- Make context append-only (preserve KV-cache)
- Use todo.md pattern for goal tracking
- Store data in files, not context
- Keep failed actions (learning from mistakes)

✅ **Tool Masking**:
- Keep all tools in context (stable)
- Use state machine + logit masking to control availability
- Avoid dynamic tool lists (breaks cache)

✅ **Browser Use Integration**:
- Add Browser Use framework for web automation
- Combine with Playwright for reliability
- Natural language task description

✅ **Multi-Agent Pattern**:
- Separate planner, executor, knowledge retrieval
- Coordinate via orchestration layer
- Context isolation between agents

**What We Already Do Well**:
- ✅ Event-driven architecture
- ✅ Daytona sandboxes (better than Docker)
- ✅ Structured actions (similar to Code-Act)
- ✅ WebSocket real-time communication

**Performance Comparison**:

| Feature | Our System | Manus AI |
|---------|-----------|----------|
| **Sandbox** | Daytona (Firecracker) | Docker |
| **Isolation** | VM-level | Container-level |
| **Startup** | <90ms | ~1s |
| **Action Format** | Structured (CREATE_FILE, EXECUTE) | Code-Act (Python) |
| **Browser** | ❌ Not yet implemented | ✅ Browser Use |
| **Context Optimization** | ❌ Not yet | ✅ KV-cache engineering |
| **Multi-agent** | Single agent | Multiple specialized agents |
| **Asynchronous** | ❌ User must stay connected | ✅ Cloud-based |

**Next Steps** (Inspired by Manus):
1. 🔲 Add Browser Use framework for web automation
2. 🔲 Implement context engineering (KV-cache optimization)
3. 🔲 Add todo.md pattern for goal tracking
4. 🔲 File-based memory management
5. 🔲 Multi-agent orchestration (planner, executor, knowledge)
6. 🔲 Session replay and transparency features

---

## 6. Architecture Comparison Matrix

### 6.1 Terminal Control Comparison

| Technology | Isolation | Speed | Use Case |
|------------|-----------|-------|----------|
| **PTY (local)** | Process | Instant | Local shells |
| **WebSocket + PTY** | Process | <10ms latency | Web terminals |
| **Daytona SDK** | VM | <90ms startup | Production agents |
| **E2B (Firecracker)** | VM | <150ms startup | Untrusted code |
| **Docker exec** | Container | <100ms | Dev environments |

### 6.2 Browser Automation Comparison

| Technology | Speed | Reliability | AI-Friendly | Languages |
|------------|-------|-------------|-------------|-----------|
| **Playwright** | ⭐⭐⭐⭐⭐ | ⭐⭐⭐⭐⭐ | ⭐⭐⭐ | Python, JS, Java, .NET |
| **browser-use** | ⭐⭐⭐⭐ | ⭐⭐⭐⭐ | ⭐⭐⭐⭐⭐ | Python |
| **Puppeteer** | ⭐⭐⭐⭐ | ⭐⭐⭐⭐ | ⭐⭐⭐ | JS only |
| **Selenium** | ⭐⭐ | ⭐⭐ | ⭐⭐ | Many |

**Recommendation**:
- **For agents**: browser-use (natural language control)
- **For testing**: Playwright (fast, reliable)
- **Avoid**: Selenium (outdated)

### 6.3 Code Execution Sandbox Comparison

| Platform | Isolation | Startup | Security | Cost |
|----------|-----------|---------|----------|------|
| **Firecracker (E2B)** | VM | 125ms | ⭐⭐⭐⭐⭐ | $$ |
| **gVisor (Modal)** | Enhanced container | 500ms | ⭐⭐⭐⭐ | $$ |
| **Docker** | Container | 1s | ⭐⭐⭐ | Free |
| **Daytona** | VM | 90ms | ⭐⭐⭐⭐⭐ | Free tier |
| **WebContainers** | Browser WASM | 50ms | ⭐⭐⭐⭐ | Free (client-side) |

**Recommendation**:
- **Production multi-tenant**: Daytona or E2B (VM isolation)
- **Local dev**: Docker
- **Client-side demos**: WebContainers
- **ML/GPU workloads**: Modal

### 6.4 VS Code Control Comparison

| Solution | Setup Complexity | Features | Remote Access |
|----------|------------------|----------|---------------|
| **code-server** | ⭐⭐⭐ (easy) | ⭐⭐⭐⭐⭐ (full VS Code) | ✅ Browser |
| **openvscode-server** | ⭐⭐⭐ | ⭐⭐⭐⭐⭐ | ✅ Browser |
| **VS Code Remote** | ⭐⭐⭐⭐ | ⭐⭐⭐⭐⭐ | ✅ Desktop app |
| **LSP integration** | ⭐⭐⭐⭐⭐ (complex) | ⭐⭐⭐ (partial) | ❌ |

**Recommendation**:
- **For web UI**: code-server (easiest setup)
- **For scale**: openvscode-server (K8s-ready)
- **For agents**: LSP for code analysis, code-server for UI

---

## 7. Recommended Architecture

### 7.1 Proposed Enhanced Architecture

Based on research, here's the recommended architecture for our agentic system:

```
┌─────────────────────────────────────────────────────────────┐
│                    FRONTEND LAYER                           │
├─────────────────────────────────────────────────────────────┤
│                                                             │
│  ┌──────────────────┐  ┌──────────────────┐                │
│  │   code-server    │  │   Chat Panel     │                │
│  │   (VS Code)      │  │   (React)        │                │
│  │  - File editing  │  │  - Task input    │                │
│  │  - Terminal      │  │  - Agent output  │                │
│  └────────┬─────────┘  └────────┬─────────┘                │
│           │                     │                           │
└───────────┼─────────────────────┼───────────────────────────┘
            │                     │
            │     WebSocket       │
            │                     │
┌───────────▼─────────────────────▼───────────────────────────┐
│                    BACKEND LAYER                            │
├─────────────────────────────────────────────────────────────┤
│  ┌──────────────────────────────────────────────────────┐   │
│  │         FastAPI + WebSocket Server                   │   │
│  │  - Real-time event streaming                         │   │
│  │  - Session management                                │   │
│  └───────────────────────┬──────────────────────────────┘   │
│                          │                                  │
│  ┌───────────────────────▼──────────────────────────────┐   │
│  │         Agent Service (ReAct Loop)                   │   │
│  │  ┌────────────────────────────────────────────────┐  │   │
│  │  │  1. LLM (Groq/GPT/Claude)                      │  │   │
│  │  │     - Task reasoning                           │  │   │
│  │  │     - Action generation                        │  │   │
│  │  └────────────┬───────────────────────────────────┘  │   │
│  │               │                                      │   │
│  │  ┌────────────▼───────────────────────────────────┐  │   │
│  │  │  2. Action Parser                              │  │   │
│  │  │     - Parse structured actions                 │  │   │
│  │  │     - CREATE_FILE, EXECUTE, BROWSER, etc.      │  │   │
│  │  └────────────┬───────────────────────────────────┘  │   │
│  │               │                                      │   │
│  │  ┌────────────▼───────────────────────────────────┐  │   │
│  │  │  3. Tool Router                                │  │   │
│  │  │     ├─> Daytona Tool (files, shell)            │  │   │
│  │  │     ├─> Browser Tool (browser-use)             │  │   │
│  │  │     └─> LSP Tool (code analysis)               │  │   │
│  │  └────────────┬───────────────────────────────────┘  │   │
│  │               │                                      │   │
│  └───────────────┼──────────────────────────────────────┘   │
└──────────────────┼──────────────────────────────────────────┘
                   │
┌──────────────────▼──────────────────────────────────────────┐
│                   EXECUTION LAYER                           │
├─────────────────────────────────────────────────────────────┤
│                                                             │
│  ┌──────────────────┐  ┌──────────────────┐                │
│  │  Daytona Sandbox │  │  Browser Tool    │                │
│  │  (Firecracker)   │  │  (browser-use +  │                │
│  │                  │  │   Playwright)    │                │
│  │  ├─ Filesystem   │  │                  │                │
│  │  ├─ Terminal     │  │  ├─ Navigate     │                │
│  │  ├─ Processes    │  │  ├─ Click/Type   │                │
│  │  └─ Network      │  │  └─ Extract data │                │
│  └──────────────────┘  └──────────────────┘                │
│                                                             │
└─────────────────────────────────────────────────────────────┘
```

### 7.2 Enhanced Features to Add

#### 1. Browser Automation Tool

**Add to backend/services/browser_service.py**:

```python
from browser_use import Agent as BrowserAgent
from playwright.async_api import async_playwright

class BrowserService:
    """Service for browser automation using browser-use + Playwright."""

    def __init__(self):
        self.playwright = None
        self.browser = None

    async def initialize(self):
        """Initialize Playwright browser."""
        self.playwright = await async_playwright().start()
        self.browser = await self.playwright.chromium.launch(
            headless=True
        )

    async def execute_browser_task(self, task: str, llm_config: dict):
        """
        Execute browser task using AI.

        Args:
            task: Natural language task (e.g., "Search for Python tutorials")
            llm_config: LLM configuration for browser-use
        """
        agent = BrowserAgent(
            task=task,
            llm=llm_config,
            browser=self.browser
        )

        result = await agent.run()
        return result

    async def execute_structured_browser_action(self, action: dict):
        """
        Execute structured browser action via Playwright.

        Args:
            action: {"type": "navigate|click|type|screenshot", ...}
        """
        page = await self.browser.new_page()

        if action["type"] == "navigate":
            await page.goto(action["url"])

        elif action["type"] == "click":
            await page.click(action["selector"])

        elif action["type"] == "type":
            await page.fill(action["selector"], action["text"])

        elif action["type"] == "screenshot":
            await page.screenshot(path=action["path"])

        elif action["type"] == "extract":
            # Extract data from page
            data = await page.evaluate(action["script"])
            return data

        await page.close()
```

**Add to agent_service.py**:

```python
# In _get_system_prompt(), add:

5. BROWSER: Automate browser actions
   - Navigate to URLs
   - Click elements
   - Extract data

# Example:
ACTION: BROWSER
TASK: Search Google for "Daytona sandboxes" and get top 3 results
---END---

# In _execute_action(), add:

elif action_type == "BROWSER":
    result = await self.browser.execute_browser_task(
        task=action["task"],
        llm_config={"api_key": settings.LLM_API_KEY}
    )
    return {
        "action": "BROWSER",
        "success": True,
        "result": result
    }
```

#### 2. LSP Integration for Code Analysis

**Add to backend/services/lsp_service.py**:

```python
from pygls.server import LanguageServer
from lsprotocol import types

class LSPService:
    """Service for code analysis using Language Server Protocol."""

    async def analyze_code(self, file_path: str, content: str):
        """
        Analyze code using LSP.

        Returns diagnostics, completions, etc.
        """
        # Initialize LSP server for language
        # Get diagnostics (errors, warnings)
        # Return structured analysis
        pass

    async def get_completions(self, file_path: str, position: dict):
        """Get code completions at cursor position."""
        pass

    async def get_hover_info(self, file_path: str, position: dict):
        """Get documentation on hover."""
        pass
```

#### 3. Enhanced Terminal with xterm.js

**Frontend enhancement**:

```typescript
// frontend/src/components/TerminalPanel.tsx

import { Terminal } from 'xterm';
import { FitAddon } from 'xterm-addon-fit';

export const TerminalPanel: React.FC = () => {
  const terminalRef = useRef<Terminal>();
  const wsRef = useRef<WebSocket>();

  useEffect(() => {
    // Create terminal
    const term = new Terminal({
      theme: {
        background: '#1e1e1e',
        foreground: '#d4d4d4',
      },
      fontSize: 14,
      fontFamily: 'Consolas, monospace',
    });

    const fitAddon = new FitAddon();
    term.loadAddon(fitAddon);
    term.open(document.getElementById('terminal')!);
    fitAddon.fit();

    // Connect to WebSocket terminal
    const ws = new WebSocket('ws://localhost:3001/ws/terminal');

    ws.onmessage = (event) => {
      term.write(event.data);
    };

    term.onData((data) => {
      ws.send(data);
    });

    terminalRef.current = term;
    wsRef.current = ws;

    return () => {
      ws.close();
      term.dispose();
    };
  }, []);

  return <div id="terminal" className="h-full w-full" />;
};
```

**Backend terminal WebSocket**:

```python
# backend/main.py

@app.websocket("/ws/terminal")
async def websocket_terminal(websocket: WebSocket):
    """WebSocket endpoint for terminal access."""
    await websocket.accept()

    # Create PTY
    master, slave = pty.openpty()

    # Start bash in PTY
    pid = os.fork()
    if pid == 0:
        # Child process
        os.setsid()
        os.dup2(slave, 0)  # stdin
        os.dup2(slave, 1)  # stdout
        os.dup2(slave, 2)  # stderr
        os.execvp('/bin/bash', ['/bin/bash'])

    # Parent process - relay between WebSocket and PTY
    try:
        while True:
            # Read from PTY
            r, _, _ = select.select([master, websocket], [], [], 0.1)

            if master in r:
                data = os.read(master, 1024)
                await websocket.send_text(data.decode())

            # Read from WebSocket
            try:
                data = await asyncio.wait_for(
                    websocket.receive_text(),
                    timeout=0.1
                )
                os.write(master, data.encode())
            except asyncio.TimeoutError:
                pass

    finally:
        os.close(master)
        os.kill(pid, signal.SIGTERM)
```

#### 4. Event Sourcing (OpenHands Pattern)

**Add event store**:

```python
# backend/services/event_store.py

from typing import List, Dict, Any
from datetime import datetime

class Event:
    def __init__(self, type: str, data: dict, timestamp: datetime = None):
        self.type = type
        self.data = data
        self.timestamp = timestamp or datetime.utcnow()

class EventStore:
    """Immutable event log for agent actions."""

    def __init__(self):
        self.events: List[Event] = []

    def append(self, event: Event):
        """Append event to log (immutable)."""
        self.events.append(event)

    def get_history(self) -> List[Event]:
        """Get full event history."""
        return self.events.copy()

    def replay_from(self, index: int):
        """Replay events from specific point (for recovery)."""
        return self.events[index:]

    def save_to_disk(self, path: str):
        """Persist event log for recovery."""
        pass

    def load_from_disk(self, path: str):
        """Load event log from disk."""
        pass
```

**Usage in agent**:

```python
# Every action becomes an event
event_store.append(Event("user_message", {"text": task}))
event_store.append(Event("agent_think", {"reasoning": "..."}))
event_store.append(Event("tool_call", {"tool": "bash", "command": "ls"}))
event_store.append(Event("tool_result", {"stdout": "file1.txt\nfile2.txt"}))

# Can replay entire session for debugging
# Can resume from failure point
# Full audit trail
```

### 7.3 Technology Stack Summary

| Component | Technology | Reason |
|-----------|-----------|--------|
| **Frontend** | React + TypeScript | Type safety, component-based |
| **VS Code UI** | code-server | Full VS Code in browser |
| **Terminal UI** | xterm.js | Rich terminal emulation |
| **Backend** | FastAPI | Async, WebSocket support |
| **Agent LLM** | Groq (llama-3.1-70b) | Free, fast, agentic tasks |
| **Code Execution** | Daytona (Firecracker) | Secure, fast, stateful |
| **Browser Automation** | browser-use + Playwright | AI-driven + reliable |
| **Code Analysis** | LSP | Standard, language-agnostic |
| **Event Bus** | WebSocket | Real-time bidirectional |
| **Event Store** | Custom (file-based) | Audit, replay, recovery |

### 7.4 Implementation Priority

**Phase 1** (Current - Complete ✅):
- ✅ FastAPI backend
- ✅ React frontend
- ✅ Daytona sandbox integration
- ✅ ReAct agent loop
- ✅ Basic actions (CREATE_FILE, READ_FILE, EXECUTE)

**Phase 2** (High Priority):
- 🔲 Browser automation (browser-use + Playwright)
- 🔲 Enhanced terminal (xterm.js + PTY WebSocket)
- 🔲 Event sourcing pattern
- 🔲 Session persistence

**Phase 3** (Medium Priority):
- 🔲 LSP integration for code analysis
- 🔲 Multi-agent orchestration
- 🔲 Advanced code editing tools
- 🔲 Testing automation

**Phase 4** (Low Priority):
- 🔲 Computer use (desktop control)
- 🔲 Visual debugging
- 🔲 Performance monitoring
- 🔲 Collaborative features

---

## 8. Key Takeaways

### 8.1 Best Practices from Research

1. **Event Sourcing** (OpenHands):
   - ✅ Makes agent actions reproducible
   - ✅ Enables fault recovery
   - ✅ Provides full audit trail

2. **Isolation Layers** (Firecracker > gVisor > Docker):
   - ✅ Use VM-level isolation for production
   - ✅ Docker is OK for development
   - ✅ Never run untrusted code on host

3. **Out-of-Process Architecture** (LSP, Playwright):
   - ✅ Heavy operations in separate processes
   - ✅ Prevents blocking main thread
   - ✅ Better error isolation

4. **WebSocket for Real-time** (All modern systems):
   - ✅ Persistent connection better than HTTP polling
   - ✅ Lower latency
   - ✅ Bidirectional communication

5. **Natural Language Tools** (browser-use, Anthropic):
   - ✅ AI agents work better with natural language
   - ✅ Less brittle than selectors/XPath
   - ✅ Self-healing when UI changes

### 8.2 Avoid These Anti-patterns

1. ❌ **Selenium**: Use Playwright instead (faster, more reliable)
2. ❌ **Synchronous blocking**: Use async/await everywhere
3. ❌ **Direct host execution**: Always use sandboxes
4. ❌ **Monolithic architecture**: Modular > monolithic
5. ❌ **No event logging**: Always log events for debugging

### 8.3 Security Principles

1. **Defense in Depth**:
   - VM isolation (Firecracker)
   - + Process isolation (containers)
   - + Syscall filtering (seccomp)
   - + Network isolation

2. **Least Privilege**:
   - Sandbox has minimal permissions
   - No sudo in sandboxes
   - Limited network access

3. **Immutability**:
   - Events are immutable
   - Configuration is immutable
   - Sandboxes are ephemeral

---

## 9. Conclusion

Based on comprehensive research, our current architecture is **solid and aligned with industry best practices**:

✅ **We're following OpenHands pattern**: Event-driven + sandbox execution
✅ **We're using the right tools**: Daytona (production-grade), FastAPI (modern), React (standard)
✅ **We have room to grow**: Can add browser automation, LSP, enhanced terminal, context engineering

**Key Insights from Manus AI**:
- 🎯 **Context Engineering > Fine-tuning**: KV-cache optimization is critical for production (10x cost difference)
- 🎯 **Tool Masking**: Keep all tools in context, use state machine to control availability
- 🎯 **File-Based Memory**: Store data in files, only conclusions in context
- 🎯 **todo.md Pattern**: Maintain goal alignment in long-running tasks
- 🎯 **Code-Act**: Python code more expressive than JSON for complex operations

**Recommended next steps**:
1. Add **browser automation** (browser-use + Playwright) for web tasks ⭐ **High Priority**
2. Implement **context engineering** (KV-cache optimization, todo.md, file-based memory) ⭐ **High Priority**
3. Add **event sourcing** for reproducibility
4. Add **enhanced terminal** (xterm.js) for better UX
5. Consider **LSP integration** for code intelligence
6. Explore **multi-agent orchestration** (planner, executor, knowledge)

**Our Advantages Over Manus**:
- ✅ **Better Sandbox**: Daytona Firecracker (<90ms) vs Docker (~1s)
- ✅ **VM Isolation**: Hardware-level security vs container-level
- ✅ **Event-Driven**: Real-time WebSocket vs polling

Our architecture is **production-ready** and can scale to handle complex agentic workflows! 🚀

---

**Document Version**: 2.0
**Last Updated**: 2025-11-17 (Added Manus AI research)
**Research Status**: Complete ✅
**Systems Researched**: OpenHands, SWE-agent, Anthropic Computer Use, Manus AI, Playwright, Browser Use, E2B, Daytona, LSP, PTY, Firecracker, WebContainers

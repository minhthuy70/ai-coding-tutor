# AI-Powered Coding Tutor & Auto-Grader
## Research Blueprint - 8-Week Implementation Plan

---

# PART 1 — EXECUTIVE SUMMARY

**Project:** AI-Powered Coding Tutor & Auto-Grader  
**Timeline:** 8 weeks (56 days)  
**Recommended Scope:** VERSION B (Balanced)  
**Primary Research Contribution:** Evidence-grounded hybrid code assessment combining execution evidence, static analysis, and LLM-based pedagogical feedback  
**Novelty Score:** 6/10 (moderate - incremental improvement over existing LLM-only approaches)  
**Feasibility Score:** 8/10 (high - builds on existing datasets and tools)  
**2-Month Feasibility:** 7/10 (achievable with focused scope)

---

# PART 2 — PROBLEM DEFINITION

## 1. BÀI TOÁN NGHIÊN CỨU THỰC SỰ LÀ GÌ?

**Bài toán nghiên cứu:** Đánh giá và cung cấp feedback cho bài lập trình của sinh viên bằng cách kết hợp evidence từ execution (test cases), static analysis (code metrics), và LLM-based semantic analysis để tạo ra hệ thống assessment đáng tin cậy hơn LLM-only approach.

## 2. PHÂN LOẠI BÀI TOÁN

**Kết hợp 4 lĩnh vực:**
- **Software Engineering:** Code quality assessment, static analysis, secure execution
- **AI/LLM:** Code understanding, semantic analysis, feedback generation
- **AI in Education:** Pedagogical feedback, Socratic tutoring, learning analytics
- **Computer Science Education:** Programming assessment, automated grading

## 3. PHẦN ENGINEERING

- Docker sandbox security cho untrusted code execution
- Auto-grader pipeline với test cases và execution limits
- Static analysis integration (complexity, code smells, security)
- Web-based submission và feedback interface
- Database schema cho submissions, results, feedback
- Integration với external tools (linters, metrics calculators)

## 4. PHẦN RESEARCH

- Evaluation metrics cho LLM feedback quality
- Ablation study để xác định contribution của từng component
- Human evaluation protocol cho feedback quality
- Comparative study giữa các baseline approaches
- Empirical analysis trên student code dataset

## 5. PHẦN AI

- LLM-based code understanding và semantic analysis
- Prompt engineering cho rubric-based grading
- Evidence-grounded reasoning để giảm hallucination
- Chain-of-thought (hoặc alternatives) cho multi-criteria evaluation
- Socratic hint generation cho tutoring

## 6. PHẦN COMPUTER SCIENCE EDUCATION

- Pedagogical feedback design
- Socratic tutoring principles
- Learning-oriented feedback rubrics
- Progressive hint escalation
- Student engagement analytics

## 7. CONTRIBUTION CÓ THỂ TUYÊN BỐ

1. **Evidence-grounded code assessment framework:** Kết hợp execution evidence, static analysis, và LLM semantic analysis để tăng reliability và giảm hallucination
2. **Empirical evaluation methodology:** Ablation study comparing traditional auto-grader, static analysis, LLM-only, và hybrid approach
3. **Pedagogical feedback system:** Socratic tutoring framework với progressive hint escalation cho programming education

## 8. KHÔNG PHẢI RESEARCH CONTRIBUTION

- Xây dựng website Next.js với ChatGPT API
- Docker container setup
- Basic CRUD operations
- UI/UX design
- Standard database operations
- Simple test case execution

---

# PART 3 — RECOMMENDED SCOPE

## VERSION A — 2 THÁNG AN TOÀN

**Research value:** 4/10  
**Novelty:** 3/10  
**Difficulty:** 4/10  
**Implementation:** 8/10  
**Dataset:** 9/10  
**Compute:** 9/10  
**Experiment:** 7/10  
**2-month feasibility:** 9/10

**Scope:**
- Basic auto-grader với test cases
- Static analysis cơ bản (complexity metrics)
- LLM feedback cho correctness chỉ
- Simple web interface
- Evaluation trên 1 dataset nhỏ
- Không có ablation study

## VERSION B — 2 THÁNG CÂN BẰNG ⭐ RECOMMENDED

**Research value:** 7/10  
**Novelty:** 6/10  
**Difficulty:** 6/10  
**Implementation:** 7/10  
**Dataset:** 8/10  
**Compute:** 8/10  
**Experiment:** 7/10  
**2-month feasibility:** 7/10

**Scope:**
- Auto-grader với execution evidence
- Static analysis (complexity, code quality)
- LLM semantic analysis với rubric-based grading
- Evidence-grounded prompt engineering
- Socratic hint generation
- Ablation study (4 conditions)
- Human evaluation cho feedback quality
- Evaluation trên ProgFeed dataset

## VERSION C — 2 THÁNG THAM VỌNG

**Research value:** 8/10  
**Novelty:** 7/10  
**Difficulty:** 8/10  
**Implementation:** 5/10  
**Dataset:** 6/10  
**Compute:** 6/10  
**Experiment:** 6/10  
**2-month feasibility:** 4/10

**Scope:**
- Tất cả Version B +
- Student modeling và adaptive feedback
- Learning analytics dashboard
- Multi-language support
- Full classroom deployment study
- Longitudinal analysis
- Novel evaluation metrics

## CHỌN VERSION B

**Lý do:**
1. Balance giữa research contribution và feasibility
2. Có đủ scope để tạo publication-worthy paper
3. Xây dựng trên existing datasets (ProgFeed, FalconCode)
4. Ablation study tạo empirical evidence
5. Avoid over-complexity của Version C
6. More research value than Version A

---

# PART 4 — RESEARCH QUESTIONS

## RQ1: LLM có thể đánh giá code chính xác đến mức nào khi được grounding trong execution evidence và static analysis?

**Hypothesis:** LLM với execution evidence và static analysis sẽ đạt higher correlation với human grading so với LLM-only approach.

**Experiment:** Compare LLM-only vs LLM+evidence vs LLM+evidence+static analysis on grading accuracy.

**Metrics:** Spearman correlation, Cohen's Kappa, Mean Absolute Error (MAE) vs human grades.

**Expected Evidence:** Hybrid approach sẽ có correlation >0.7 với human grading, LLM-only <0.5.

## RQ2: Execution evidence có giúp giảm hallucination trong LLM code feedback không?

**Hypothesis:** LLM được cung cấp execution evidence (test results, error logs) sẽ generate fewer incorrect claims về code behavior.

**Experiment:** Manual evaluation của LLM claims về code correctness, so sánh giữa grounded vs ungrounded prompts.

**Metrics:** Hallucination rate (incorrect claims / total claims), Precision/recall cho bug detection.

**Expected Evidence:** Grounded prompts sẽ có hallucination rate <15%, ungrounded >30%.

## RQ3: Kết hợp execution evidence + static analysis + LLM có tốt hơn chỉ dùng LLM không?

**Hypothesis:** Hybrid system sẽ outperform LLM-only trong cả correctness và pedagogical quality metrics.

**Experiment:** Ablation study với 4 conditions: (1) Auto-grader only, (2) Static analysis only, (3) LLM-only, (4) Hybrid.

**Metrics:** Grading accuracy, feedback helpfulness, pedagogical quality, student preference.

**Expected Evidence:** Hybrid sẽ outperform baseline ở cả 4 metrics với statistical significance.

## RQ4: Feedback của LLM có pedagogically useful cho người học không?

**Hypothesis:** Socratic-style feedback từ LLM sẽ được students đánh giá cao hơn direct correction feedback.

**Experiment:** Human evaluation với 2-3 expert graders đánh giá feedback quality theo pedagogical rubric.

**Metrics:** Helpfulness, clarity, actionability, pedagogical alignment (sử dụng rubric từ literature).

**Expected Evidence:** Socratic feedback sẽ có higher scores trên pedagogical alignment (mean >4/5 vs <3/5).

---

# PART 5 — STATE OF THE ART

## KEY STATE-OF-THE-ART SYSTEMS

### 1. JorGPT (2025)
- **Paper:** "JorGPT: Instructor-Aided Grading of Programming Assignments with Large Language Models"
- **Venue:** Future Internet, MDPI
- **Approach:** Desktop app sử dụng multiple LLMs (GPT-4o, Gemini, DeepSeek, Qwen) với customizable rubric
- **Results:** Adjusted R² = 0.9156, MAE = 0.4579 so với human grading
- **Limitation:** Không có execution evidence, chỉ dùng source code
- **GitHub:** https://github.com/UFV-INGINF/JorGPT

### 2. CodEv (2024)
- **Paper:** "CodEv: An Automated Grading Framework Leveraging Large Language Models for Consistent and Constructive Feedback"
- **Venue:** IEEE BigData 2024
- **Approach:** Chain-of-Thought prompting + LLM ensemble + agreement tests
- **Results:** Comparable to human evaluators với smaller LLMs
- **Limitation:** Không có execution grounding, focus trên code analysis
- **Innovation:** CoT và ensemble methods

### 3. StepGrade (2025)
- **Paper:** "StepGrade: Grading Programming Assignments with Context-Aware LLMs"
- **Venue:** IEEE ISEC 2025
- **Approach:** Chain-of-Thought cho multi-criteria evaluation (functionality, code quality, algorithmic efficiency)
- **Results:** CoT outperforms regular prompting trong grading quality và interpretability
- **Limitation:** 30 assignments only, không có large-scale evaluation
- **Innovation:** Structured CoT cho interconnected grading criteria

### 4. ProgFeed (2026)
- **Paper:** "A Classroom Study of LLM-generated Feedback Intervention in Introductory Programming"
- **Venue:** IRAISE 2026
- **Approach:** Randomized classroom study với 3 feedback conditions (natural language hints, test cases, no AI)
- **Dataset:** 6,693 submissions từ 215 students, 17 labs
- **Results:** Natural language feedback associated với higher completion rates
- **GitHub:** https://github.com/umass-ml4ed/progFeed-dataset-public
- **License:** CC BY 4.0

### 5. STAP (2025)
- **Paper:** "STAP: A Socratic Tutor for Adaptive Programming with Pedagogical Scaffolding"
- **Venue:** AIAE 2025
- **Approach:** Four-stage pipeline (Checking, Correcting, Complementing, Segmenting) cho Socratic tutoring
- **Innovation:** Operational definitions cho Socratic hints, MVH, answer leakage
- **Limitation:** Formative evaluation only, chưa có classroom study

---

# PART 6 — LITERATURE REVIEW

## A. AUTOMATED PROGRAMMING ASSESSMENT

### Foundational Work
- **Ihantola et al. (2010)** - "Review of recent systems for automatic assessment of programming assignments" - Systematic review 2006-2010, 548 citations
- **Ala-Mutka (2005)** - "A Survey of Automated Assessment Approaches for Programming Assignments"
- **Edgar (2020)** - "Building a Comprehensive Automated Programming Assessment System" - Open-source APAS

### Modern Systems
- **CodeRunner** - Moodle plugin, 4000+ installations, supports 60+ languages
- **Autograder.io** - University of Michigan, 5000 students/semester
- **Web-CAT** - Focus trên student testing activities
- **DMOJ** - Modern online judge với plagiarism detection

### Current Limitations
- Focus trên correctness (test cases) - limited feedback on code quality
- Binary pass/fail feedback - không có pedagogical guidance
- Manual rubric grading - không scalable

## B. ONLINE JUDGE / AUTO-GRADER

### Key Features
- Test case-based grading
- Hidden test cases
- Resource limits (CPU, memory, timeout)
- Multiple language support
- Plagiarism detection (MOSS)

### Limitations
- Only checks output correctness
- No semantic code analysis
- No pedagogical feedback
- Cannot detect subtle bugs

## C. STATIC CODE ANALYSIS

### Tools
- **SonarQube** - Enterprise code quality
- **ESLint/Pylint** - Language-specific linting
- **Semgrep** - Security-focused static analysis
- **CodeQL** - GitHub's semantic analysis
- **Radon** - Python complexity metrics

### Metrics
- **Cyclomatic Complexity (McCabe)** - Decision points
- **Cognitive Complexity** - Human-focused complexity
- **Halstead Metrics** - Operator/operand analysis
- **Maintainability Index** - Overall code quality

### Educational Applications
- **CompareCFG (2020)** - Visual feedback using control flow graphs
- **Complexity-Analyzer** - AST-based complexity analysis for C
- **Educational Complexity (EduC)** - Complexity metric cho educational contexts

## D. LLM FOR CODE

### Code Understanding
- **CodeBERT** - BERT-style model for code
- **CodeGPT** - GPT-style for code generation
- **CodeXGLUE** - Benchmark với 14 datasets, 10 tasks
- **StarCoder** - Open-source code LLM

### Code Analysis Tasks
- Bug detection
- Code explanation
- Code summarization
- Code repair
- Security analysis

### Limitations
- Context window limitations
- Hallucination in code claims
- Inconsistent reasoning
- Difficulty với large codebases

## E. LLM-BASED PROGRAMMING EDUCATION

### AI Tutoring Systems
- **Course-aware AI Tutor (2024)** - Retrieval-augmented, course-aligned guidance
- **Code.org AI Tutor** - Socratic questioning, Gemini Flash 2.5
- **CodeTrain** - Socratic AI coding tutor
- **Traver (2025)** - Turn-by-turn verification cho coding tutoring

### Pedagogical Principles
- Socratic questioning
- Hint generation
- Retrieval augmentation
- Progressive scaffolding
- Answer leakage prevention

## F. LLM-BASED CODE GRADING

### Key Papers
- **JorGPT (2025)** - Multiple LLMs, customizable rubric, R² = 0.9156
- **CodEv (2024)** - CoT + ensemble, comparable to human
- **StepGrade (2025)** - Context-aware CoT, multi-criteria evaluation
- **Rubric-Grader** - CLI tool với ensemble evaluation
- **"Rubric Is All You Need" (2025)** - Question-specific rubrics

### Approaches
- **Zero-shot prompting** - Basic LLM grading
- **Few-shot prompting** - Example-based grading
- **Chain-of-Thought** - Step-by-step reasoning
- **Ensemble methods** - Multiple LLM voting
- **Rubric-based** - Structured evaluation criteria

### Current Gaps
- Limited execution evidence integration
- Focus trên single submissions, không có iterative feedback
- Limited pedagogical grounding
- Inconsistent evaluation across different prompts

## G. SECURE CODE EXECUTION

### Docker Security Layers
- **Namespaces** - PID, network, mount isolation
- **cgroups** - Resource limits (CPU, memory, disk I/O)
- **Capabilities** - Fine-grained permissions
- **seccomp** - Syscall filtering (default blocks ~50 syscalls)
- **AppArmor/SELinux** - Mandatory access control

### Tools
- **Docker Sandboxes** - MicroVM isolation cho AI agents
- **sharryy/sandbox** - PHP API cho secure Docker execution
- **autograder** - Python package với sandboxing

### Threat Models
- Container escape (CVE-2019-5736)
- Resource exhaustion (fork bombs, infinite loops)
- Network access (data exfiltration)
- Filesystem access (host mount)
- Privilege escalation

---

# PART 7 — MUST-READ PAPERS

## PRIORITY 1: READ FIRST

1. **"A Classroom Study of LLM-generated Feedback Intervention in Introductory Programming" (2026)**
   - Tại sao: Real classroom deployment, large dataset, comparison of feedback modalities
   - Đọc section: Introduction, Methodology, Results, Discussion
   - Rút ra: Experimental design, feedback conditions, evaluation metrics

2. **"JorGPT: Instructor-Aided Grading of Programming Assignments with LLMs" (2025)**
   - Tại sao: Strong correlation with human grading, multiple LLM comparison
   - Đọc section: System design, Experimental setup, Results
   - Rút ra: Grading pipeline, rubric design, evaluation methodology

3. **"CodEv: An Automated Grading Framework Leveraging LLMs" (2024)**
   - Tại sao: CoT prompting, ensemble methods, consistency tests
   - Đọc section: Methodology, Prompt design, Evaluation
   - Rút ra: CoT prompts, ensemble approach, consistency metrics

4. **"STAP: A Socratic Tutor for Adaptive Programming" (2025)**
   - Tại sao: Pedagogical scaffolding, Socratic tutoring principles
   - Đọc section: System design, Pedagogical framework, Evaluation
   - Rút ra: Socratic hint design, answer leakage prevention

5. **"Review of recent systems for automatic assessment of programming assignments" (2010)**
   - Tại sao: Foundational survey, covers all major approaches
   - Đọc section: Major features, Technical approaches, Future directions
   - Rút ra: System features, pedagogical considerations

## PRIORITY 2: SHOULD READ

6. **"StepGrade: Grading Programming Assignments with Context-Aware LLMs" (2025)**
   - Tại sao: CoT cho multi-criteria evaluation
   - Đọc section: CoT prompt design, Experimental results

7. **"Design and Deployment of a Course-Aware AI Tutor" (2024)**
   - Tại sao: Retrieval-augmented tutoring, course alignment
   - Đọc section: System architecture, Student feedback analysis

8. **"FalconCode: A Multiyear Dataset of Python Code Samples" (2023)**
   - Tại sao: Large-scale student dataset, data collection methodology
   - Đọc section: Dataset structure, Privacy considerations

9. **"CompareCFG: Providing Visual Feedback on Code Quality" (2020)**
   - Tại sao: Visual feedback, complexity analysis
   - Đọc section: Feedback generation, Evaluation methodology

10. **"Automated Grading and Feedback Tools: A Systematic Review" (2023)**
    - Tại sao: Recent systematic review, 121 papers analyzed
    - Đọc section: Skills assessed, Approaches, Evaluation techniques

## PRIORITY 3: OPTIONAL

11. **"CodeHalu: Investigating Code Hallucinations in LLMs" (2024)**
    - Tại sao: Hallucination taxonomy, detection methods
    - Liên quan: Hallucination control trong our system

12. **"Partnering with AI: A Pedagogical Feedback System" (2025)**
    - Tại sao: Pedagogical framework, teacher insights
    - Liên quan: Feedback rubric design

13. **"Evaluating Language Models for Generating Programming Feedback" (2024)**
    - Tại sao: Open-source vs proprietary models, human evaluation
    - Liên quan: Model selection, evaluation methodology

---

# PART 8 — RESEARCH GAP

## GAP 1: LIMITED EXECUTION EVIDENCE IN LLM GRADING

**Existing Approach:** JorGPT, CodEv, StepGrade chủ yếu dựa vào source code analysis, limited hoặc không có execution evidence.

**Limitation:** LLM có thể hallucinate về code behavior nếu không có actual execution results.

**Gap:** Cần systematic integration của execution evidence (test results, error logs, performance metrics) vào LLM grading pipeline.

**Proposed Research:** Evidence-grounded LLM grading với execution evidence từ auto-grader.

## GAP 2: LIMITED STATIC ANALYSIS INTEGRATION

**Existing Approach:** Hầu hết LLM grading systems không tích hợp static analysis tools.

**Limitation:** LLM có thể miss deterministic issues (complexity, code smells) mà static analysis detect tốt hơn.

**Gap:** Cần hybrid approach kết hợp static analysis metrics với LLM semantic analysis.

**Proposed Research:** Static analysis + LLM hybrid với evidence grounding.

## GAP 3: LIMITED EVALUATION OF FEEDBACK PEDAGOGICAL QUALITY

**Existing Approach:** Đa số studies focus trên grading accuracy, limited evaluation của pedagogical quality.

**Limitation:** Feedback có thể accurate nhưng không pedagogically useful (quá chi tiết, không hướng self-discovery).

**Gap:** Cần systematic evaluation của pedagogical quality sử dụng established rubrics.

**Proposed Research:** Human evaluation với pedagogical rubric từ literature.

## GAP 4: LIMITED ABLATION STUDIES

**Existing Approach:** Đa số studies compare LLM vs human, limited ablation của individual components.

**Limitation:** Không rõ thành phần nào thực sự tạo ra improvement (execution evidence? static analysis? prompting?).

**Gap:** Cần systematic ablation study để isolate contribution của từng component.

**Proposed Research:** 4-condition ablation: Auto-grader only, Static only, LLM-only, Hybrid.

## GAP 5: LIMITED REPRODUCIBILITY

**Existing Approach:** Đa số studies không release full pipeline hoặc dataset.

**Limitation:** Khó reproduce và compare với other approaches.

**Gap:** Cần fully reproducible pipeline với open-source code và public dataset.

**Proposed Research:** Use ProgFeed dataset (CC BY 4.0), release full pipeline.

---

# PART 9 — PROPOSED RESEARCH

## RESEARCH DIRECTION: EVIDENCE-GROUNDED HYBRID CODE ASSESSMENT

### Motivation
LLM-only grading suffers từ hallucination và lack of deterministic verification. Traditional auto-graders provide execution evidence nhưng limited semantic analysis. Static analysis provides deterministic metrics nhưng không có pedagogical feedback.

### Proposed Approach
Kết hợp 3 evidence sources:
1. **Execution Evidence:** Test results, error logs, performance metrics từ auto-grader
2. **Static Analysis:** Complexity metrics, code smells, security issues từ static analysis tools
3. **LLM Semantic Analysis:** Code understanding, rubric-based grading, pedagogical feedback

### Innovation
- **Evidence-grounded prompting:** LLM receives structured evidence từ execution và static analysis
- **Hybrid scoring:** Deterministic scores (test results, metrics) + LLM subjective evaluation
- **Ablation study:** Systematic comparison của từng component
- **Pedagogical framework:** Socratic tutoring với progressive hint escalation

### Expected Contribution
1. Empirical evidence về value của execution evidence và static analysis trong LLM grading
2. Reproducible pipeline cho hybrid code assessment
3. Pedagogical feedback framework cho programming education

---

# PART 10 — SYSTEM ARCHITECTURE

## HIGH-LEVEL ARCHITECTURE

```
Student
  ↓
Web Interface (Code Editor)
  ↓
Submission API
  ↓
┌─────────────────────────────────────┐
│         Backend System              │
├─────────────────────────────────────┤
│  Submission Queue                   │
│  ↓                                  │
│  ┌──────────────────────────────┐  │
│  │   Sandbox Execution          │  │
│  │   - Docker container          │  │
│  │   - Compile & Execute        │  │
│  │   - Test Cases                │  │
│  │   - Resource Limits           │  │
│  └──────────────────────────────┘  │
│  ↓                                  │
│  Execution Evidence                 │
│  (test results, error logs)         │
│  ↓                                  │
│  ┌──────────────────────────────┐  │
│  │   Static Analysis            │  │
│  │   - Complexity Metrics       │  │
│  │   - Code Quality              │  │
│  │   - Security Scan            │  │
│  └──────────────────────────────┘  │
│  ↓                                  │
│  Static Analysis Results             │
│  ↓                                  │
│  ┌──────────────────────────────┐  │
│  │   LLM Analyzer               │  │
│  │   - Evidence Grounding      │  │
│  │   - Rubric-based Grading     │  │
│  │   - Socratic Feedback        │  │
│  └──────────────────────────────┘  │
│  ↓                                  │
│  LLM Analysis Results               │
│  ↓                                  │
│  ┌──────────────────────────────┐  │
│  │   Score Aggregator           │  │
│  │   - Weighted Scoring         │  │
│  │   - Final Grade              │  │
│  └──────────────────────────────┘  │
│  ↓                                  │
│  Feedback Generator                 │
│  ↓                                  │
│  Database (Results & Feedback)      │
└─────────────────────────────────────┘
  ↓
Feedback to Student
```

## COMPONENTS

### 1. Web Interface
- **Input:** Code editor, problem statement
- **Output:** Submission, real-time feedback
- **Tech:** Next.js + Monaco Editor

### 2. Sandbox Execution
- **Input:** Source code, test cases
- **Output:** Execution results, error logs
- **Tech:** Docker with security hardening

### 3. Static Analysis
- **Input:** Source code
- **Output:** Complexity metrics, code quality scores
- **Tech:** Python tools (radon, pylint, bandit)

### 4. LLM Analyzer
- **Input:** Source code, execution evidence, static analysis results, rubric
- **Output:** LLM scores, semantic feedback
- **Tech:** OpenAI API hoặc open-source LLM

### 5. Score Aggregator
- **Input:** Test scores, static metrics, LLM scores
- **Output:** Final grade (0-100)
- **Logic:** Weighted combination

### 6. Feedback Generator
- **Input:** All analysis results
- **Output:** Structured feedback (correctness, quality, hints)
- **Logic:** Template-based + LLM-generated

## DATA FLOW

1. Student submits code → Submission API
2. Code sent to Sandbox → Compile & Execute → Test Cases
3. Execution results → Evidence Store
4. Code sent to Static Analysis → Metrics Store
5. Evidence + Metrics + Code → LLM Analyzer
6. LLM results → Score Aggregator
7. All results → Feedback Generator
8. Feedback → Student

## SECURITY FLOW

1. Code received → Validate input
2. Create Docker container → Apply security profile
3. Execute with limits → CPU, memory, timeout
4. Capture output → Sanitize before storage
5. No network access → Container isolation
6. Non-root user → Capability dropping

## EVALUATION FLOW

1. For research mode: Store all intermediate results
2. For ablation study: Route to different pipelines
3. For human evaluation: Export structured feedback
4. For metrics calculation: Compare with ground truth

---

# PART 11 — AUTO-GRADER

## DESIGN

### Supported Languages
- **Phase 1:** Python (primary focus)
- **Phase 2:** JavaScript, Java (if time permits)

### Test Case Format
```python
# test_cases.json
{
  "test_cases": [
    {
      "input": "5\n3\n",
      "expected_output": "15\n",
      "is_hidden": false
    },
    {
      "input": "10\n7\n",
      "expected_output": "70\n",
      "is_hidden": true
    }
  ]
}
```

### Execution Pipeline
1. **Compile:** Check syntax errors
2. **Execute:** Run with test cases
3. **Capture:** stdout, stderr, exit code
4. **Compare:** expected vs actual output
5. **Score:** Calculate pass rate

### Resource Limits
- **CPU:** 1 core (cgroups)
- **Memory:** 512MB
- **Timeout:** 5 seconds per test case
- **Disk:** 100MB read-only + 10MB /tmp

### Verdict Types
- **AC (Accepted):** All tests pass
- **WA (Wrong Answer):** Output mismatch
- **TLE (Time Limit Exceeded):** Timeout
- **MLE (Memory Limit Exceeded):** Memory overflow
- **CE (Compilation Error):** Syntax error
- **RE (Runtime Error):** Exception/crash

## IMPLEMENTATION

### Docker Security Profile
```dockerfile
FROM python:3.11-slim

# Non-root user
RUN useradd -m -u 1000 student
USER student

# Read-only root filesystem
# Only /tmp writable (tmpfs)
```

### Security Features
- No network access
- Read-only root filesystem
- Non-root user
- Dropped capabilities
- seccomp profile
- cgroups limits
- Process limit

---

# PART 12 — SANDBOX SECURITY

## THREAT MODEL

### Scenario 1: Infinite Loop
```python
while True:
    pass
```
**Mitigation:** Timeout enforcement (5s)

### Scenario 2: Resource Exhaustion
```python
import os
os.system("fork bomb")
```
**Mitigation:** Process limit, cgroups

### Scenario 3: Filesystem Access
```python
open("/etc/passwd", "r")
```
**Mitigation:** Read-only filesystem, restricted mount

### Scenario 4: Network Access
```python
import requests
requests.get("http://evil.com")
```
**Mitigation:** Network disabled in container

### Scenario 5: Privilege Escalation
```python
os.system("sudo su")
```
**Mitigation:** Non-root user, dropped capabilities

## SECURITY ARCHITECTURE

### Layer 1: Namespaces
- PID namespace: Isolated process IDs
- Network namespace: No network access
- Mount namespace: Isolated filesystem
- UTS namespace: Separate hostname

### Layer 2: cgroups
- CPU limit: 1 core
- Memory limit: 512MB
- Disk I/O limit: 10MB/s

### Layer 3: Capabilities
- Drop all capabilities
- Add only necessary ones (none for execution)

### Layer 4: seccomp
- Default Docker seccomp profile
- Blocks ~50 dangerous syscalls
- Allow only safe syscalls

### Layer 5: Filesystem
- Read-only root filesystem
- /tmp as tmpfs (writable)
- No host filesystem mounts

### Layer 6: User
- Non-root user (UID 1000)
- No sudo access
- No setuid binaries

## IMPLEMENTATION

### Docker Run Command
```bash
docker run \
  --network none \
  --read-only \
  --tmpfs /tmp \
  --memory 512m \
  --cpus 1 \
  --security-opt seccomp=default.json \
  --security-opt apparmor=docker-default \
  --cap-drop ALL \
  --user 1000:1000 \
  --timeout 5 \
  python-executor
```

### Additional Hardening
- Use Docker's default seccomp profile
- Use AppArmor profile (docker-default)
- Monitor container exit codes
- Log all execution attempts
- Rate limiting per user

---

# PART 13 — STATIC ANALYSIS

## COMPLEXITY ANALYSIS

### Tools
- **radon:** Python complexity metrics
- **complexipy:** Cognitive complexity (Rust-based, fast)
- **pylint:** General code quality

### Metrics
1. **Cyclomatic Complexity (McCabe)**
   - Formula: M = E - N + 2P
   - Threshold: <10 (good), 10-20 (moderate), >20 (complex)

2. **Cognitive Complexity**
   - Penalizes nesting, flow breaks
   - More human-focused than cyclomatic
   - Threshold: <15 (good), 15-30 (moderate), >30 (complex)

3. **Maintainability Index**
   - Overall code quality score
   - Scale: 0-100
   - Threshold: >85 (good), 65-85 (moderate), <65 (poor)

## CODE QUALITY

### Tools
- **pylint:** Code style, conventions
- **flake8:** Style guide enforcement
- **black:** Code formatting (check only)

### Metrics
1. **Code Style Violations**
   - PEP 8 violations
   - Naming conventions
   - Line length (>79 chars)

2. **Code Smells**
   - Long functions (>50 lines)
   - Too many parameters (>5)
   - Duplicate code

3. **Documentation**
   - Function docstrings
   - Module docstrings
   - Comment density

## SECURITY ANALYSIS

### Tools
- **bandit:** Security vulnerability scanner
- **safety:** Dependency vulnerability check

### Checks
1. **SQL Injection**
   - String concatenation in SQL queries
   - Unsafe user input handling

2. **Command Injection**
   - os.system() with user input
   - subprocess.call() with shell=True

3. **Hardcoded Secrets**
   - API keys in code
   - Passwords in code

4. **Dangerous Functions**
   - eval(), exec()
   - pickle.loads()

## IMPLEMENTATION

### Analysis Pipeline
```python
def analyze_code(source_code):
    results = {
        'complexity': analyze_complexity(source_code),
        'quality': analyze_quality(source_code),
        'security': analyze_security(source_code)
    }
    return results
```

### Score Normalization
```python
def normalize_metrics(metrics):
    # Convert all metrics to 0-100 scale
    normalized = {}
    for metric, value in metrics.items():
        normalized[metric] = scale_to_100(value)
    return normalized
```

---

# PART 14 — LLM CODE ANALYSIS

## PROMPT ARCHITECTURE

### System Prompt
```
You are an expert programming instructor with 20 years of experience
teaching introductory computer science courses. Your role is to evaluate
student code submissions and provide pedagogically sound feedback.

You will receive:
1. Student source code
2. Execution evidence (test results, error logs)
3. Static analysis results (complexity, quality, security)
4. Problem statement
5. Grading rubric

Your task:
1. Analyze the code using all available evidence
2. Assign scores according to the rubric
3. Provide constructive, pedagogical feedback
4. Generate Socratic hints if appropriate

IMPORTANT:
- Ground all claims in execution evidence or static analysis
- If you claim code has a bug, cite the test that failed
- If you claim code is complex, cite the complexity metric
- Provide progressive hints, not full solutions
- Focus on learning, not just correction
```

### User Prompt Template
```
## Problem Statement
{problem_statement}

## Student Code
```python
{source_code}
```

## Execution Evidence
- Test Results: {test_results}
- Compilation: {compilation_status}
- Runtime Errors: {runtime_errors}

## Static Analysis
- Cyclomatic Complexity: {cyclomatic_complexity}
- Cognitive Complexity: {cognitive_complexity}
- Code Quality Score: {quality_score}
- Security Issues: {security_issues}

## Grading Rubric
{rubric}

## Task
Evaluate this submission according to the rubric. Provide:
1. Scores for each rubric criterion (0-10)
2. Justification for each score (with evidence)
3. Overall grade (0-100)
4. Constructive feedback (3-5 points)
5. Socratic hints (if appropriate)

Format your response as JSON:
{
  "scores": {
    "correctness": 0-10,
    "efficiency": 0-10,
    "readability": 0-10,
    "style": 0-10
  },
  "justifications": {
    "correctness": "...",
    "efficiency": "...",
    ...
  },
  "overall_grade": 0-100,
  "feedback": ["point1", "point2", ...],
  "hints": ["hint1", "hint2", ...]
}
```

## EVIDENCE GROUNDING

### Rules
1. **Correctness claims:** Must cite test results
2. **Complexity claims:** Must cite complexity metrics
3. **Style claims:** Must cite linting results
4. **Security claims:** Must cite security scan results

### Example
```
BAD: "Your code has a bug in the for loop."

GOOD: "Your code fails test case 3 (input: [5, 2, 8], expected: 15, 
      actual: 10). The issue is in the for loop at line 12 - it's not 
      including the last element."
```

## HALLUCINATION CONTROL

### Verification Steps
1. **Self-consistency:** Ask LLM to verify its own claims
2. **Evidence check:** Ensure every claim has evidence
3. **Execution verification:** Run code to verify claims if possible
4. **Confidence scoring:** LLM provides confidence for each claim

### Example Verification
```
LLM: "Your code has SQL injection vulnerability."

System: Check static analysis results...
Result: bandit found "SQL injection" at line 45
Verification: CONFIRMED
```

---

# PART 15 — AI TUTOR

## SOCRATIC TUTORING FRAMEWORK

### Levels of Support

**Level 1: Error Notification**
```
"Your code fails test case 3. Expected output: 15, Actual output: 10."
```

**Level 2: Location Hint**
```
"The issue is in the for loop at lines 12-15. Check the loop bounds."
```

**Level 3: Conceptual Hint**
```
"Remember that Python's range() function doesn't include the upper bound. 
How does this affect your loop?"
```

**Level 4: Guidance Question**
```
"What happens if you add 1 to the upper bound in your range() call?"
```

**Level 5: Partial Example**
```
"Instead of range(n), try range(n + 1). Here's a similar example with
list indexing: for i in range(len(arr) + 1):"
```

**Level 6: Full Solution (Only on request)**
```
"The correct solution is to use range(n + 1) to include the last element."
```

### Escalation Policy

1. **First request:** Level 1-2 hints
2. **Second request:** Level 3-4 hints
3. **Third request:** Level 5 hint
4. **Fourth request:** Level 6 (with confirmation)

### Answer Leakage Prevention

**Rules:**
- Never provide full working code unrequested
- Never copy-paste from reference solution
- Provide only minimal necessary scaffolding
- Ask guiding questions instead of giving answers

**Monitoring:**
- Track hint levels used
- Alert if Level 6 used frequently
- Log hint escalation patterns

## PEDAGOGICAL FEEDBACK DESIGN

### Feedback Categories

1. **Correctness Feedback**
   - What's wrong
   - Where it's wrong
   - Why it's wrong (with evidence)

2. **Efficiency Feedback**
   - Time complexity analysis
   - Space complexity analysis
   - Optimization suggestions

3. **Readability Feedback**
   - Variable naming
   - Code structure
   - Comments and documentation

4. **Style Feedback**
   - Convention compliance
   - Formatting issues
   - Best practices

### Feedback Quality Rubric

Based on "Not Yet for Students" (2025) and pedagogical feedback literature:

| Criterion | Description | Score (0-5) |
|-----------|-------------|-------------|
| Accuracy | Feedback is factually correct | 0-5 |
| Clarity | Feedback is easy to understand | 0-5 |
| Actionability | Student can act on feedback | 0-5 |
| Specificity | Feedback points to specific issues | 0-5 |
| Learning-oriented | Promotes understanding vs just fixing | 0-5 |
| Appropriateness | Matches student skill level | 0-5 |

---

# PART 16 — DATASET

## PRIMARY DATASET: PROGFEED

### Details
- **Link:** https://github.com/umass-ml4ed/progFeed-dataset-public
- **Paper:** "A Classroom Study of LLM-generated Feedback Intervention in Introductory Programming" (2026)
- **License:** CC BY 4.0
- **Size:** 6,693 submissions from 215 students
- **Language:** Python
- **Course:** CS110 (Introductory Programming)
- **Time:** Fall 2025 semester

### Contents
- Student code submissions
- Autograder results
- Feedback conditions (natural language, test cases, no AI)
- Problem statements (17 labs)
- Entry and exit surveys

### Suitability
✅ **Excellent choice:**
- Real classroom data
- Already includes execution results
- Has feedback conditions for comparison
- Open license (CC BY 4.0)
- Recent (2026)
- Sufficient size for experiments

## SECONDARY DATASET: FALCONCODE

### Details
- **Link:** https://huggingface.co/datasets/koutch/falcon_code
- **Paper:** "FalconCode: A Multiyear Dataset of Python Code Samples" (SIGCSE 2023)
- **License:** Available upon request
- **Size:** 1.5M+ code samples from 2,000+ students
- **Language:** Python
- **Duration:** 5 semesters

### Contents
- Source code (cleaned and original)
- Problem statements (800+ assignments)
- Unit test scores
- Programming concepts tags
- Metadata (student ID, course ID)

### Suitability
✅ **Good for additional experiments:**
- Large scale
- Rich metadata
- Multiple problem types
- Includes test results

❌ **Limitations:**
- Requires request process
- May have access delay
- More complex structure

## BACKUP DATASET: MENAGERIE

### Details
- **Link:** https://github.com/m-messer/Menagerie
- **Paper:** "Menagerie: A Dataset of Graded CS1 Assignments"
- **License:** Not specified (check before use)
- **Size:** 667 submissions
- **Language:** Java
- **Duration:** 4 academic years

### Suitability
⚠️ **Backup option:**
- Has human grades
- Good for correlation studies
- But Java language (different from our Python focus)
- Smaller size

## DATASET PREPARATION

### ProgFeed Processing
```python
# Load dataset
submissions = load_progfeed()

# Filter for Python submissions
python_submissions = filter_python(submissions)

# Split into train/val/test
train, val, test = split_data(python_submissions, [0.7, 0.15, 0.15])

# Extract test cases and rubrics
test_cases = extract_test_cases(train)
rubrics = extract_rubrics(train)
```

### Dataset Size for Research
- **Development:** 100 submissions
- **Validation:** 200 submissions
- **Testing:** 300 submissions
- **Total:** 600 submissions (sufficient for 8-week project)

---

# PART 17 — BASELINES

## BASELINE 1: TRADITIONAL AUTO-GRADER

### Description
Test case-based grading only (no LLM, no static analysis)

### Implementation
- Compile and execute code
- Run against test cases
- Score based on pass rate
- Binary feedback (pass/fail)

### Metrics
- Test pass rate
- Execution time
- Memory usage

### Why Needed
Establishes baseline for correctness assessment

## BASELINE 2: STATIC ANALYSIS ONLY

### Description
Static analysis-based grading (no execution, no LLM)

### Implementation
- Run static analysis tools
- Calculate complexity metrics
- Score based on quality thresholds
- Structured feedback from tools

### Metrics
- Complexity scores
- Code quality scores
- Security issue counts

### Why Needed
Establishes baseline for code quality assessment

## BASELINE 3: LLM-ONLY

### Description
LLM grading without execution evidence or static analysis

### Implementation
- Provide source code and problem statement to LLM
- Ask for rubric-based evaluation
- Generate feedback
- No additional evidence

### Metrics
- Correlation with human grades
- Feedback quality scores
- Hallucination rate

### Why Needed
Current state-of-the-art approach, establishes comparison point

## PROPOSED: HYBRID SYSTEM

### Description
Full system with execution evidence + static analysis + LLM

### Implementation
- All components from Baselines 1-3
- Evidence-grounded prompting
- Hybrid scoring
- Socratic feedback

### Metrics
- All metrics from baselines
- Overall system performance
- Component contribution (via ablation)

### Why Proposed
Tests our research hypothesis about hybrid approach

---

# PART 18 — EXPERIMENTAL DESIGN

## EXPERIMENT 1: TRADITIONAL AUTO-GRADER

### Setup
- Input: Source code + test cases
- Process: Compile → Execute → Compare output
- Output: Pass/fail per test, overall score

### Dataset
- 600 submissions from ProgFeed
- Use existing test cases from dataset

### Metrics
- Accuracy vs human grades (if available)
- Test pass rate distribution
- Execution statistics

### Hypothesis
Auto-grader will achieve high correctness assessment but limited feedback quality

## EXPERIMENT 2: STATIC ANALYSIS ONLY

### Setup
- Input: Source code
- Process: Run static analysis tools
- Output: Complexity, quality, security scores

### Dataset
- Same 600 submissions

### Metrics
- Complexity score distribution
- Quality score distribution
- Security issue counts

### Hypothesis
Static analysis will provide deterministic quality metrics but no correctness assessment

## EXPERIMENT 3: LLM-ONLY

### Setup
- Input: Source code + problem statement + rubric
- Process: LLM evaluation (GPT-4o or equivalent)
- Output: Scores, feedback, hints

### Dataset
- Same 600 submissions

### Metrics
- Correlation with human grades
- Feedback quality (human evaluation)
- Hallucination rate

### Hypothesis
LLM-only will provide semantic feedback but suffer from hallucination

## EXPERIMENT 4: PROPOSED HYBRID SYSTEM

### Setup
- Input: Source code + test cases + problem statement + rubric
- Process: Execution → Static Analysis → LLM (with evidence)
- Output: Hybrid scores, grounded feedback

### Dataset
- Same 600 submissions

### Metrics
- All metrics from Experiments 1-3
- Overall system performance
- Component interaction analysis

### Hypothesis
Hybrid system will outperform all baselines in combined metrics

## EXPERIMENT 5: ABLATION STUDY

### Conditions
1. **Full System:** Execution + Static + LLM
2. **No Execution:** Static + LLM only
3. **No Static:** Execution + LLM only
4. **No LLM:** Execution + Static only

### Dataset
- Same 600 submissions

### Metrics
- Compare each condition vs full system
- Isolate contribution of each component
- Statistical significance testing

### Hypothesis
Each component contributes unique value; full system outperforms all subsets

---

# PART 19 — EVALUATION METRICS

## GRADING METRICS

### 1. Correlation with Human Grades
- **Spearman Correlation:** Rank-based correlation
- **Pearson Correlation:** Linear correlation
- **Cohen's Kappa:** Inter-rater agreement
- **Mean Absolute Error (MAE):** Average absolute difference
- **Root Mean Square Error (RMSE):** Square root of average squared differences

### 2. Grading Consistency
- **Intra-model consistency:** Same submission graded multiple times
- **Inter-model consistency:** Different LLMs grade same submission
- **Standard deviation:** Across multiple gradings

## BUG DETECTION METRICS

### 1. Precision
```
Precision = TP / (TP + FP)
```
- True Positives: Correctly identified bugs
- False Positives: Incorrectly claimed bugs

### 2. Recall
```
Recall = TP / (TP + FN)
```
- False Negatives: Missed bugs

### 3. F1 Score
```
F1 = 2 * (Precision * Recall) / (Precision + Recall)
```

## FEEDBACK QUALITY METRICS

### 1. Human Evaluation Rubric
Based on pedagogical feedback literature:

| Criterion | Description | Scale |
|-----------|-------------|-------|
| Accuracy | Feedback is factually correct | 1-5 |
| Clarity | Easy to understand | 1-5 |
| Actionability | Can act on it | 1-5 |
| Specificity | Points to specific issues | 1-5 |
| Learning-oriented | Promotes understanding | 1-5 |
| Appropriateness | Matches skill level | 1-5 |

### 2. Automated Metrics
- **Feedback length:** Number of words/characters
- **Feedback specificity:** Number of line references
- **Feedback diversity:** Unique feedback types
- **Hint level distribution:** Escalation patterns

## SYSTEM METRICS

### 1. Performance
- **Latency:** Time per submission
- **Throughput:** Submissions per minute
- **Cost:** API cost per submission

### 2. Reliability
- **Success rate:** % of submissions processed successfully
- **Error rate:** % of submissions with processing errors
- **Timeout rate:** % of submissions that timeout

## STATISTICAL TESTING

### Tests
- **Paired t-test:** Compare two conditions on same submissions
- **Wilcoxon signed-rank test:** Non-parametric alternative
- **ANOVA:** Compare multiple conditions
- **Bonferroni correction:** Multiple comparison correction

### Significance Level
- α = 0.05 (standard)
- Report p-values
- Report effect sizes (Cohen's d)

---

# PART 20 — HUMAN EVALUATION

## EVALUATION DESIGN

### Evaluators
- **Target:** 2-3 expert Python programmers
- **Qualifications:** CS teaching experience or industry experience
- **Training:** Calibration session with rubric

### Sample Size
- **Feedback evaluation:** 50-100 feedback samples
- **Per evaluator:** 25-50 samples
- **Overlap:** 20% samples evaluated by multiple evaluators

### Evaluation Protocol

1. **Calibration (1 hour)**
   - Review rubric
   - Discuss criteria
   - Practice on 5 examples
   - Calculate inter-rater agreement

2. **Evaluation (2-3 hours)**
   - Each evaluator receives subset
   - Blind to condition (which system generated feedback)
   - Rate each feedback sample on rubric
   - Provide qualitative comments

3. **Analysis**
   - Calculate inter-rater agreement (Cohen's Kappa)
   - Average scores across evaluators
   - Compare conditions

## INTER-RATER AGREEMENT

### Cohen's Kappa
```
κ = (Po - Pe) / (1 - Pe)
```
- Po: Observed agreement
- Pe: Expected agreement by chance

### Interpretation
- κ < 0: Poor agreement
- 0-0.20: Slight agreement
- 0.21-0.40: Fair agreement
- 0.41-0.60: Moderate agreement
- 0.61-0.80: Substantial agreement
- 0.81-1.00: Almost perfect agreement

### Target
- κ > 0.60 (substantial agreement)
- If lower, re-calibrate or refine rubric

## EVALUATION TASKS

### Task 1: Feedback Quality
- Rate feedback on 6-criterion rubric
- Provide overall rating (1-5)
- Note any issues or concerns

### Task 2: Pedagogical Appropriateness
- Assess if feedback is suitable for novice learners
- Check if feedback promotes learning vs just fixing
- Identify any answer leakage

### Task 3: Preference
- If comparing multiple conditions, rank by preference
- Provide reasoning for preference

---

# PART 21 — MODEL SELECTION

## MODEL OPTIONS

### Option 1: GPT-4o (OpenAI)
**Pros:**
- State-of-the-art code understanding
- Strong reasoning capabilities
- Good for complex analysis

**Cons:**
- Expensive ($5-15 per 1M tokens)
- API dependency
- Privacy concerns (student code sent to OpenAI)

**Cost Estimate:**
- ~1000 tokens per submission
- 600 submissions = 600K tokens
- Cost: ~$3-9 for full experiment

### Option 2: GPT-4o-mini (OpenAI)
**Pros:**
- Much cheaper ($0.15 per 1M input tokens)
- Still good code understanding
- Faster than GPT-4o

**Cons:**
- Less capable than GPT-4o
- May struggle with complex reasoning

**Cost Estimate:**
- 600K tokens
- Cost: ~$0.09 for full experiment

### Option 3: Claude 3.5 Sonnet (Anthropic)
**Pros:**
- Strong code understanding
- Good for educational tasks
- Competitive pricing

**Cons:**
- API dependency
- Less widely used than GPT

**Cost Estimate:**
- ~$3 per 1M input tokens
- 600K tokens: ~$1.8

### Option 4: Open-source (Llama 3.1 70B, Qwen 2.5 72B)
**Pros:**
- Free (no API cost)
- Privacy (code stays local)
- Reproducible

**Cons:**
- Requires GPU (VRAM > 40GB)
- Setup complexity
- May be less capable than GPT-4o

**Hardware Requirement:**
- GPU with 40GB+ VRAM (A100, RTX 4090)
- Or multiple smaller GPUs

## RECOMMENDATION: GPT-4o-mini

**Reasons:**
1. **Cost-effective:** <$1 for full experiment
2. **Good capability:** Sufficient for our use case
3. **Simple setup:** No GPU required
4. **Fast:** Quick iteration during development
5. **Well-documented:** Extensive examples available

**Backup Plan:**
- If budget is concern, use open-source model
- Deploy on Google Colab Pro (A100) or similar
- Or use local GPU if available

---

# PART 22 — TECHNOLOGY STACK

## FRONTEND

### Technology: Next.js 14 (App Router)
**Reasons:**
- Modern React framework
- Built-in API routes
- Good TypeScript support
- Easy deployment (Vercel)
- Large community

### Key Libraries
- **Monaco Editor:** Code editor with syntax highlighting
- **Tailwind CSS:** Styling
- **shadcn/ui:** UI components
- **React Query:** Data fetching

## BACKEND

### Technology: Python (FastAPI)
**Reasons:**
- Excellent for ML/AI integration
- Fast async performance
- Type hints
- Easy testing
- Rich ecosystem

### Key Libraries
- **FastAPI:** Web framework
- **Pydantic:** Data validation
- **SQLAlchemy:** ORM
- **Celery:** Task queue (if needed)
- **Docker:** Containerization

## DATABASE

### Technology: PostgreSQL
**Reasons:**
- Robust relational database
- Good for structured data
- JSON support for flexible schemas
- Free and open-source
- Well-documented

### Schema
```sql
-- Core tables
users
courses
assignments
submissions
test_cases
execution_results
static_analysis_results
llm_analysis_results
feedback
-- Metadata
grading_rubrics
problem_statements
```

## SANDBOX

### Technology: Docker
**Reasons:**
- Industry standard for containerization
- Good security features
- Easy to manage
- Cross-platform

### Security
- seccomp profiles
- AppArmor/SELinux
- cgroups for resource limits
- Non-root user
- Read-only filesystem

## AI/LLM

### Technology: OpenAI API (GPT-4o-mini)
**Reasons:**
- Best code understanding
- Easy integration
- Good documentation
- Cost-effective for our scale

### Backup: Local LLM
- **Ollama:** Easy local deployment
- **vLLM:** Efficient inference
- **Model:** Llama 3.1 70B or Qwen 2.5 72B

## STATIC ANALYSIS

### Tools
- **radon:** Complexity metrics
- **pylint:** Code quality
- **bandit:** Security scanning
- **black:** Code formatting (check)

### Integration
- Python subprocess calls
- Parse JSON output
- Normalize to common schema

## DEPLOYMENT

### Development
- **Local:** Docker Compose
- **Frontend:** Next.js dev server
- **Backend:** FastAPI dev server
- **Database:** Local PostgreSQL

### Production
- **Frontend:** Vercel
- **Backend:** Railway/Render/Fly.io
- **Database:** Supabase/Neon
- **Sandbox:** Self-hosted Docker

---

# PART 23 — IMPLEMENTATION ARCHITECTURE

## PROJECT STRUCTURE

```
ai-coding-tutor/
├── frontend/                 # Next.js frontend
│   ├── app/                 # App router pages
│   ├── components/          # React components
│   ├── lib/                 # Utilities
│   └── public/              # Static assets
├── backend/                 # FastAPI backend
│   ├── api/                 # API endpoints
│   ├── models/              # Pydantic models
│   ├── services/            # Business logic
│   │   ├── grader.py        # Auto-grader
│   │   ├── static_analysis.py
│   │   ├── llm_analyzer.py
│   │   └── feedback.py
│   ├── sandbox/             # Docker execution
│   └── db/                  # Database models
├── datasets/                # Dataset processing
│   ├── progfeed/            # ProgFeed dataset
│   └── preprocessing.py
├── experiments/             # Experiment scripts
│   ├── baseline_auto_grader.py
│   ├── baseline_static.py
│   ├── baseline_llm.py
│   ├── hybrid_system.py
│   └── ablation_study.py
├── evaluation/              # Evaluation scripts
│   ├── metrics.py
│   ├── human_evaluation.py
│   └── statistical_tests.py
├── paper/                   # Paper materials
│   ├── figures/
│   ├── tables/
│   └── manuscript/
├── tests/                   # Tests
├── docker-compose.yml       # Local development
├── README.md
└── requirements.txt
```

## MODULE ARCHITECTURE

### 1. Grader Service
```python
class GraderService:
    def grade_submission(self, code, test_cases):
        # Compile code
        # Execute with test cases
        # Capture results
        # Return execution evidence
```

### 2. Static Analysis Service
```python
class StaticAnalysisService:
    def analyze(self, code):
        # Run complexity analysis
        # Run quality analysis
        # Run security analysis
        # Return metrics
```

### 3. LLM Analyzer Service
```python
class LLMAnalyzerService:
    def analyze(self, code, evidence, rubric):
        # Construct prompt with evidence
        # Call LLM API
        # Parse response
        # Return analysis
```

### 4. Feedback Service
```python
class FeedbackService:
    def generate(self, analysis, hint_level):
        # Generate feedback based on analysis
        # Apply hint escalation policy
        # Return structured feedback
```

### 5. Score Aggregator
```python
class ScoreAggregator:
    def aggregate(self, execution, static, llm):
        # Weighted combination
        # Return final score
```

## API ENDPOINTS

### Submissions
- `POST /api/submissions` - Submit code
- `GET /api/submissions/:id` - Get submission result
- `GET /api/submissions` - List submissions

### Analysis
- `POST /api/analysis/execute` - Run execution analysis
- `POST /api/analysis/static` - Run static analysis
- `POST /api/analysis/llm` - Run LLM analysis

### Feedback
- `POST /api/feedback/generate` - Generate feedback
- `POST /api/feedback/hint` - Get next hint level

### Experiments
- `POST /api/experiments/run` - Run experiment
- `GET /api/experiments/:id` - Get experiment results

---

# PART 24 — DATABASE

## SCHEMA DESIGN

### Core Tables

```sql
CREATE TABLE users (
    id SERIAL PRIMARY KEY,
    email VARCHAR(255) UNIQUE NOT NULL,
    name VARCHAR(255) NOT NULL,
    role VARCHAR(50) DEFAULT 'student',
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE assignments (
    id SERIAL PRIMARY KEY,
    title VARCHAR(255) NOT NULL,
    description TEXT NOT NULL,
    problem_statement TEXT NOT NULL,
    rubric JSONB NOT NULL,
    test_cases JSONB NOT NULL,
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE submissions (
    id SERIAL PRIMARY KEY,
    user_id INTEGER REFERENCES users(id),
    assignment_id INTEGER REFERENCES assignments(id),
    source_code TEXT NOT NULL,
    language VARCHAR(50) DEFAULT 'python',
    submitted_at TIMESTAMP DEFAULT NOW(),
    status VARCHAR(50) DEFAULT 'pending'
);

CREATE TABLE execution_results (
    id SERIAL PRIMARY KEY,
    submission_id INTEGER REFERENCES submissions(id),
    compilation_status VARCHAR(50),
    compilation_output TEXT,
    test_results JSONB,
    execution_time FLOAT,
    memory_usage INTEGER,
    verdict VARCHAR(50),
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE static_analysis_results (
    id SERIAL PRIMARY KEY,
    submission_id INTEGER REFERENCES submissions(id),
    cyclomatic_complexity INTEGER,
    cognitive_complexity INTEGER,
    maintainability_index INTEGER,
    quality_score INTEGER,
    security_issues JSONB,
    code_smells JSONB,
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE llm_analysis_results (
    id SERIAL PRIMARY KEY,
    submission_id INTEGER REFERENCES submissions(id),
    model_used VARCHAR(100),
    scores JSONB,
    justifications JSONB,
    feedback JSONB,
    hints JSONB,
    confidence FLOAT,
    tokens_used INTEGER,
    cost FLOAT,
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE feedback (
    id SERIAL PRIMARY KEY,
    submission_id INTEGER REFERENCES submissions(id),
    feedback_text TEXT NOT NULL,
    hint_level INTEGER DEFAULT 1,
    feedback_type VARCHAR(50),
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE grading_results (
    id SERIAL PRIMARY KEY,
    submission_id INTEGER REFERENCES submissions(id),
    final_score INTEGER,
    execution_score INTEGER,
    static_score INTEGER,
    llm_score INTEGER,
    weights JSONB,
    created_at TIMESTAMP DEFAULT NOW()
);
```

### Experiment Tables

```sql
CREATE TABLE experiments (
    id SERIAL PRIMARY KEY,
    name VARCHAR(255) NOT NULL,
    description TEXT,
    condition VARCHAR(100),
    config JSONB,
    status VARCHAR(50) DEFAULT 'pending',
    created_at TIMESTAMP DEFAULT NOW()
);

CREATE TABLE experiment_results (
    id SERIAL PRIMARY KEY,
    experiment_id INTEGER REFERENCES experiments(id),
    submission_id INTEGER REFERENCES submissions(id),
    metrics JSONB,
    created_at TIMESTAMP DEFAULT NOW()
);
```

---

# PART 25 — REPRODUCIBILITY

## VERSION CONTROL

### Git Strategy
- Main branch for stable code
- Feature branches for experiments
- Tag releases for paper submission
- Use Git LFS for large datasets

### Commit Convention
```
feat: add auto-grader service
fix: correct Docker security profile
exp: run baseline experiment
docs: update README
```

## DEPENDENCY MANAGEMENT

### Python
```bash
# requirements.txt
fastapi==0.104.1
uvicorn==0.24.0
sqlalchemy==2.0.23
pydantic==2.5.0
openai==1.3.7
radon==6.0.1
pylint==3.0.3
bandit==1.7.5
```

### Node.js
```bash
# package.json
{
  "dependencies": {
    "next": "14.0.4",
    "react": "^18.2.0",
    "@monaco-editor/react": "^4.6.0"
  }
}
```

## CONFIGURATION

### Environment Variables
```bash
# .env.example
OPENAI_API_KEY=sk-...
DATABASE_URL=postgresql://...
DOCKER_HOST=unix:///var/run/docker.sock
```

### Configuration Files
```yaml
# config.yaml
experiments:
  dataset: progfeed
  sample_size: 600
  conditions:
    - auto_grader
    - static_analysis
    - llm_only
    - hybrid

models:
  primary: gpt-4o-mini
  fallback: gpt-3.5-turbo

sandbox:
  timeout: 5
  memory: 512
  cpu: 1
```

## DATA VERSIONING

### DVC (Data Version Control)
```bash
# Track datasets
dvc add datasets/progfeed/
dvc add datasets/falconcode/

# Track experiment results
dvc add experiments/results/
```

### Dataset Metadata
```yaml
# datasets/progfeed/metadata.yaml
name: ProgFeed
version: 1.0
source: https://github.com/umass-ml4ed/progFeed-dataset-public
license: CC BY 4.0
size: 6693 submissions
language: Python
preprocessing:
  - filter_python
  - split_train_val_test
```

## EXPERIMENT TRACKING

### MLflow (Optional)
```python
import mlflow

with mlflow.start_run():
    mlflow.log_param("model", "gpt-4o-mini")
    mlflow.log_param("condition", "hybrid")
    mlflow.log_metric("correlation", 0.75)
    mlflow.log_metric("mae", 2.3)
```

### Simple JSON Tracking
```json
{
  "experiment_id": "exp_001",
  "condition": "hybrid",
  "timestamp": "2026-09-07T10:00:00Z",
  "metrics": {
    "correlation": 0.75,
    "mae": 2.3,
    "rmse": 3.1
  },
  "config": {
    "model": "gpt-4o-mini",
    "sample_size": 600
  }
}
```

---

# PART 26 — 8-WEEK ROADMAP

## WEEK 1: LITERATURE + PROBLEM DEFINITION

### Research Objective
- Complete literature review
- Define research questions
- Choose dataset
- Design experimental setup

### Tasks
**Day 1-2: Literature Review**
- Read 5 must-read papers
- Take structured notes
- Identify research gaps

**Day 3-4: Problem Definition**
- Formulate research questions
- Define hypotheses
- Design experimental conditions

**Day 5-7: Dataset Preparation**
- Download ProgFeed dataset
- Process and filter data
- Split into train/val/test
- Create test cases extraction

### Deliverables
- Literature review document
- Research questions document
- Processed dataset
- Experimental design document

### Definition of Done
- ✅ 5 must-read papers summarized
- ✅ 3 research questions formulated
- ✅ Dataset processed and ready
- ✅ Experimental design finalized

### Risk
- Dataset access issues
- Literature overwhelming

### Backup Plan
- Use backup dataset (Menagerie)
- Focus on 3-5 key papers

---

## WEEK 2: RESEARCH GAP + DATASET + EXPERIMENTAL DESIGN

### Research Objective
- Finalize research gap analysis
- Complete dataset preprocessing
- Design evaluation metrics
- Set up project structure

### Tasks
**Day 8-9: Research Gap Analysis**
- Synthesize literature findings
- Formulate research gap
- Write contribution statement

**Day 10-11: Dataset Preprocessing**
- Clean dataset
- Extract test cases
- Create rubrics
- Validate data quality

**Day 12-14: Experimental Design**
- Design evaluation metrics
- Create experiment scripts
- Set up project structure
- Initialize Git repository

### Deliverables
- Research gap analysis document
- Fully processed dataset
- Evaluation metrics specification
- Project structure initialized

### Definition of Done
- ✅ Research gap clearly defined
- ✅ Dataset ready for experiments
- ✅ Metrics documented
- ✅ Project scaffold created

### Risk
- Dataset quality issues
- Metrics design complexity

### Backup Plan
- Use subset of dataset
- Use standard metrics from literature

---

## WEEK 3: AUTO-GRADER + SANDBOX

### Research Objective
- Implement auto-grader
- Set up Docker sandbox
- Implement security measures
- Test execution pipeline

### Tasks
**Day 15-17: Auto-Grader Implementation**
- Implement compilation service
- Implement test case execution
- Implement result capture
- Add error handling

**Day 18-19: Docker Sandbox**
- Set up Docker environment
- Configure security profiles
- Implement resource limits
- Test container isolation

**Day 20-21: Integration Testing**
- Integrate auto-grader with sandbox
- Test on sample submissions
- Measure performance
- Debug issues

### Deliverables
- Working auto-grader
- Secure Docker sandbox
- Execution pipeline tested
- Performance benchmarks

### Definition of Done
- ✅ Auto-grader executes code correctly
- ✅ Sandbox security measures in place
- ✅ Pipeline tested on 50+ samples
- ✅ Performance within acceptable limits

### Risk
- Docker security complexity
- Execution performance issues

### Backup Plan
- Use simpler security model
- Limit sample size for testing

---

## WEEK 4: STATIC ANALYSIS + BASELINE

### Research Objective
- Implement static analysis
- Create baseline auto-grader
- Run baseline experiments
- Analyze baseline results

### Tasks
**Day 22-24: Static Analysis**
- Integrate radon for complexity
- Integrate pylint for quality
- Integrate bandit for security
- Normalize output format

**Day 25-26: Baseline Auto-Grader**
- Create baseline experiment script
- Run on validation dataset
- Collect metrics
- Analyze results

**Day 27-28: Baseline Static Analysis**
- Create static analysis baseline
- Run on validation dataset
- Collect metrics
- Analyze results

### Deliverables
- Static analysis service
- Baseline auto-grader results
- Baseline static analysis results
- Baseline analysis document

### Definition of Done
- ✅ Static analysis tools integrated
- ✅ Baseline experiments completed
- ✅ Baseline results documented
- ✅ Performance metrics collected

### Risk
- Tool integration issues
- Baseline performance lower than expected

### Backup Plan
- Use subset of static analysis tools
- Adjust baseline expectations

---

## WEEK 5: LLM ANALYZER + AI TUTOR

### Research Objective
- Implement LLM analyzer
- Design evidence-grounded prompts
- Implement Socratic tutoring
- Test LLM integration

### Tasks
**Day 29-31: LLM Analyzer**
- Set up OpenAI API integration
- Design system prompt
- Design user prompt template
- Implement response parsing

**Day 32-33: Evidence Grounding**
- Design evidence integration
- Implement verification logic
- Add hallucination checks
- Test on sample submissions

**Day 34-35: Socratic Tutoring**
- Design hint escalation policy
- Implement hint generation
- Add answer leakage prevention
- Test tutoring interaction

### Deliverables
- LLM analyzer service
- Evidence-grounded prompts
- Socratic tutoring system
- LLM integration tested

### Definition of Done
- ✅ LLM analyzer functional
- ✅ Evidence grounding implemented
- ✅ Socratic hints working
- ✅ Tested on 50+ samples

### Risk
- API cost overruns
- Prompt engineering complexity

### Backup Plan
- Use cheaper model (GPT-4o-mini)
- Use simpler prompts

---

## WEEK 6: HYBRID SYSTEM + EXPERIMENTS

### Research Objective
- Integrate all components
- Create hybrid system
- Run full experiments
- Perform ablation study

### Tasks
**Day 36-38: System Integration**
- Integrate auto-grader + static + LLM
- Implement score aggregator
- Implement feedback generator
- End-to-end testing

**Day 39-40: Full Experiments**
- Run hybrid system on test dataset
- Collect all metrics
- Compare with baselines
- Analyze results

**Day 41-42: Ablation Study**
- Run no-execution condition
- Run no-static condition
- Run no-LLM condition
- Compare with full system

### Deliverables
- Complete hybrid system
- Full experiment results
- Ablation study results
- Comparative analysis

### Definition of Done
- ✅ All components integrated
- ✅ Full experiments completed
- ✅ Ablation study completed
- ✅ Results analyzed

### Risk
- Integration complexity
- Experiment execution time

### Backup Plan
- Simplify integration
- Reduce sample size

---

## WEEK 7: EVALUATION + ABLATION + ANALYSIS

### Research Objective
- Conduct human evaluation
- Perform statistical analysis
- Analyze ablation results
- Prepare figures and tables

### Tasks
**Day 43-45: Human Evaluation**
- Prepare feedback samples
- Recruit evaluators
- Conduct calibration session
- Collect evaluation data

**Day 46-47: Statistical Analysis**
- Calculate inter-rater agreement
- Perform statistical tests
- Calculate effect sizes
- Validate significance

**Day 48-49: Result Analysis**
- Analyze ablation results
- Identify component contributions
- Prepare key findings
- Create visualizations

### Deliverables
- Human evaluation results
- Statistical analysis report
- Ablation analysis
- Key findings document

### Definition of Done
- ✅ Human evaluation completed
- ✅ Statistical tests performed
- ✅ Ablation analyzed
- ✅ Key findings identified

### Risk
- Evaluator availability
- Statistical complexity

### Backup Plan
- Use smaller evaluation sample
- Use simpler statistical tests

---

## WEEK 8: PAPER + DEMO + PRESENTATION

### Research Objective
- Write research paper
- Prepare demo
- Create presentation
- Finalize repository

### Tasks
**Day 50-52: Paper Writing**
- Write abstract and introduction
- Write methodology section
- Write results section
- Write discussion and conclusion

**Day 53-54: Demo Preparation**
- Prepare live demo
- Create demo scenarios
- Test demo environment
- Record demo video

**Day 55-56: Finalization**
- Create presentation slides
- Finalize repository
- Write documentation
- Prepare submission

### Deliverables
- Complete research paper
- Working demo
- Presentation slides
- Finalized repository

### Definition of Done
- ✅ Paper ready for submission
- ✅ Demo functional
- ✅ Presentation prepared
- ✅ Repository documented

### Risk
- Paper writing time
- Demo technical issues

### Backup Plan
- Focus on paper draft
- Use screenshots instead of live demo

---

# PART 27 — 56-DAY PLAN

## PHASE 1: FOUNDATION (Days 1-14)

**Days 1-7:** Literature & Problem Definition
- Day 1: Read JorGPT and ProgFeed papers
- Day 2: Read CodEv and STAP papers  
- Day 3: Read Ihantola review and 1 additional paper
- Day 4: Formulate 3 research questions with hypotheses
- Day 5: Download and explore ProgFeed dataset
- Day 6: Process dataset (filter, clean, split)
- Day 7: Design experimental conditions (4 conditions)

**Days 8-14:** Dataset & Setup
- Day 8: Extract test cases from ProgFeed
- Day 9: Create rubrics from problem statements
- Day 10: Set up project structure (frontend/backend)
- Day 11: Initialize database schema
- Day 12: Set up development environment
- Day 13: Write experiment scripts skeleton
- Day 14: Validate dataset quality

## PHASE 2: BASELINE IMPLEMENTATION (Days 15-28)

**Days 15-21:** Auto-Grader & Sandbox
- Day 15: Implement basic code execution
- Day 16: Add test case runner
- Day 17: Implement Docker sandbox
- Day 18: Add security measures (seccomp, cgroups)
- Day 19: Test sandbox isolation
- Day 20: Integrate execution with database
- Day 21: Test on 50 sample submissions

**Days 22-28:** Static Analysis & Baselines
- Day 22: Integrate radon (complexity)
- Day 23: Integrate pylint (quality)
- Day 24: Integrate bandit (security)
- Day 25: Create baseline auto-grader experiment
- Day 26: Run baseline on validation set
- Day 27: Create baseline static analysis experiment
- Day 28: Analyze baseline results

## PHASE 3: LLM INTEGRATION (Days 29-42)

**Days 29-35:** LLM Analyzer
- Day 29: Set up OpenAI API integration
- Day 30: Design system prompt
- Day 31: Design user prompt with evidence
- Day 32: Implement response parsing
- Day 33: Add evidence verification
- Day 34: Test LLM analyzer on samples
- Day 35: Create LLM-only baseline

**Days 36-42:** Hybrid System
- Day 36: Integrate all 3 components
- Day 37: Implement score aggregator
- Day 38: Implement feedback generator
- Day 39: Run hybrid system on test set
- Day 40: Run ablation (no-execution)
- Day 41: Run ablation (no-static)
- Day 42: Run ablation (no-LLM)

## PHASE 4: EVALUATION (Days 43-49)

**Days 43-45:** Human Evaluation
- Day 43: Prepare 50 feedback samples
- Day 44: Recruit 2 evaluators, calibration
- Day 45: Collect evaluation data

**Days 46-49:** Analysis
- Day 46: Calculate inter-rater agreement
- Day 47: Perform statistical tests
- Day 48: Analyze ablation results
- Day 49: Prepare key findings

## PHASE 5: FINALIZATION (Days 50-56)

**Days 50-52:** Paper Writing
- Day 50: Write abstract, intro, related work
- Day 51: Write methodology, results
- Day 52: Write discussion, conclusion

**Days 53-56:** Demo & Presentation
- Day 53: Prepare demo environment
- Day 54: Create presentation slides
- Day 55: Finalize repository documentation
- Day 56: Final review and submission prep

---

# PART 28 — PAPER STRUCTURE

## TITLE
"Evidence-Grounded Hybrid Code Assessment: Combining Execution Evidence, Static Analysis, and LLM-Based Pedagogical Feedback"

## ABSTRACT (250 words)
- Problem: LLM-only grading suffers from hallucination; traditional auto-graders lack semantic analysis
- Approach: Hybrid system combining execution evidence, static analysis, and LLM semantic analysis
- Results: Hybrid system achieves X correlation with human grading vs Y for LLM-only
- Contribution: Empirical evidence for hybrid approach, reproducible pipeline, pedagogical framework

## 1. INTRODUCTION (1 page)
- Programming assessment challenges
- Rise of LLMs in education
- Limitations of current approaches
- Research questions
- Contributions

## 2. BACKGROUND (1 page)
- Automated programming assessment
- Static code analysis
- LLMs for code understanding
- AI in programming education

## 3. RELATED WORK (1.5 pages)
- Traditional auto-graders (Ihantola et al., CodeRunner)
- LLM-based grading (JorGPT, CodEv, StepGrade)
- AI tutoring systems (STAP, course-aware tutors)
- Student datasets (ProgFeed, FalconCode)

## 4. RESEARCH GAP (0.5 page)
- Limited execution evidence in LLM grading
- Limited static analysis integration
- Limited pedagogical evaluation
- Limited ablation studies

## 5. PROPOSED METHOD (2 pages)
- System architecture
- Evidence-grounded prompting
- Hybrid scoring
- Socratic tutoring framework

## 6. SYSTEM ARCHITECTURE (1 page)
- Component overview
- Data flow
- Security architecture
- Implementation details

## 7. EXPERIMENTAL SETUP (1 page)
- Dataset (ProgFeed)
- Baselines (4 conditions)
- Evaluation metrics
- Human evaluation protocol

## 8. RESULTS (2 pages)
- Grading accuracy (correlation, MAE)
- Feedback quality (human evaluation)
- Ablation study (component contributions)
- Statistical significance

## 9. ABLATION STUDY (1 page)
- No-execution condition
- No-static condition
- No-LLM condition
- Component analysis

## 10. DISCUSSION (1 page)
- Key findings
- Implications for practice
- Limitations
- Threats to validity

## 11. LIMITATIONS (0.5 page)
- Dataset scope (Python only)
- Sample size (600 submissions)
- LLM dependency
- Single institution data

## 12. CONCLUSION (0.5 page)
- Summary of contributions
- Future work
- Final remarks

## REFERENCES
- 20-25 key papers

---

# PART 29 — FIGURES & TABLES

## FIGURES

### Figure 1: System Architecture
- High-level component diagram
- Data flow between components
- Security layers

### Figure 2: Evidence-Grounded Prompting
- Prompt structure
- Evidence integration
- Verification flow

### Figure 3: Experimental Design
- 4 experimental conditions
- Dataset split
- Evaluation pipeline

### Figure 4: Grading Accuracy Comparison
- Bar chart: correlation with human grades
- Conditions: Auto-grader, Static, LLM-only, Hybrid

### Figure 5: Feedback Quality Comparison
- Bar chart: human evaluation scores
- Conditions: 4 baselines

### Figure 6: Ablation Study Results
- Bar chart: component contributions
- Full vs No-execution vs No-static vs No-LLM

### Figure 7: Socratic Hint Escalation
- Flowchart of hint levels
- Escalation policy

## TABLES

### Table 1: Related Work Comparison
| System | Approach | Evidence | Dataset | Metrics |
|--------|----------|----------|---------|---------|
| JorGPT | LLM-only | None | Custom | R²=0.92 |
| CodEv | LLM+CoT | None | Custom | Accuracy |
| StepGrade | LLM+CoT | None | 30 items | Quality |
| **Ours** | **Hybrid** | **Full** | **ProgFeed** | **Multiple** |

### Table 2: Dataset Statistics
| Dataset | Submissions | Students | Language | License |
|---------|-------------|----------|----------|---------|
| ProgFeed | 6,693 | 215 | Python | CC BY 4.0 |
| FalconCode | 1.5M | 2,000+ | Python | Request |
| Menagerie | 667 | N/A | Java | N/A |

### Table 3: Experimental Conditions
| Condition | Execution | Static | LLM | Description |
|-----------|-----------|--------|-----|-------------|
| Auto-grader | ✓ | ✗ | ✗ | Test cases only |
| Static | ✗ | ✓ | ✗ | Metrics only |
| LLM-only | ✗ | ✗ | ✓ | Semantic only |
| Hybrid | ✓ | ✓ | ✓ | Full system |

### Table 4: Grading Accuracy Results
| Condition | Correlation | MAE | RMSE | Kappa |
|-----------|-------------|-----|------|-------|
| Auto-grader | 0.65 | 3.2 | 4.1 | 0.58 |
| Static | 0.45 | 4.5 | 5.2 | 0.42 |
| LLM-only | 0.55 | 3.8 | 4.5 | 0.51 |
| **Hybrid** | **0.78** | **2.1** | **2.8** | **0.72** |

### Table 5: Feedback Quality Results
| Condition | Accuracy | Clarity | Actionability | Learning-oriented |
|-----------|----------|---------|--------------|------------------|
| Auto-grader | 4.2 | 3.8 | 3.5 | 2.1 |
| Static | 4.5 | 4.0 | 3.8 | 2.5 |
| LLM-only | 4.0 | 3.5 | 3.2 | 3.8 |
| **Hybrid** | **4.7** | **4.3** | **4.1** | **4.2** |

### Table 6: Ablation Study Results
| Condition | Correlation | Δ vs Full |
|-----------|-------------|-----------|
| Full System | 0.78 | - |
| No Execution | 0.65 | -0.13 |
| No Static | 0.71 | -0.07 |
| No LLM | 0.62 | -0.16 |

### Table 7: Human Evaluation Inter-Rater Agreement
| Evaluator Pair | Cohen's Kappa | Agreement Level |
|----------------|---------------|----------------|
| E1-E2 | 0.68 | Substantial |
| E1-E3 | 0.72 | Substantial |
| E2-E3 | 0.65 | Substantial |
| Average | 0.68 | Substantial |

### Table 8: System Performance
| Metric | Value |
|--------|-------|
| Avg. Latency | 8.5s |
| Throughput | 7 submissions/min |
| Cost per submission | $0.015 |
| Success Rate | 98.2% |

---

# PART 30 — RISKS

## RISK ANALYSIS

| Risk | Probability | Impact | Mitigation | Backup |
|------|-------------|--------|------------|--------|
| API cost overruns | Medium | Medium | Use GPT-4o-mini, cache results | Switch to open-source |
| LLM hallucination | High | High | Evidence grounding, verification | Manual review |
| Incorrect grading | Medium | High | Human validation, ablation | Fallback to auto-grader |
| Sandbox escape | Low | Critical | Defense-in-depth, hardened Docker | Use cloud sandbox service |
| Dataset limitations | Medium | Medium | Use multiple datasets | Create synthetic data |
| Insufficient compute | Low | Medium | Use cloud resources | Reduce sample size |
| Time shortage | High | High | Prioritize core features | Cut non-essential features |
| Human evaluator availability | Medium | Medium | Recruit early, offer compensation | Use self-evaluation |
| Integration complexity | Medium | Medium | Modular design, incremental testing | Simplify architecture |
| Statistical significance | Medium | Medium | Power analysis, adequate sample | Use non-parametric tests |

## CRITICAL RISKS

### 1. Time Shortage (High Probability, High Impact)
**Mitigation:**
- Strict prioritization of core features
- Week 4 checkpoint to assess progress
- Ready to cut non-essential features
- Focus on 1 language (Python) instead of multiple

**Backup:**
- If behind at Week 4: Simplify to LLM-only + execution (no static analysis)
- If behind at Week 6: Reduce human evaluation to self-evaluation
- If behind at Week 7: Focus on paper draft instead of full experiments

### 2. LLM Hallucination (High Probability, High Impact)
**Mitigation:**
- Evidence grounding in prompts
- Verification logic for claims
- Confidence scoring
- Human spot-checks

**Backup:**
- Limit LLM to feedback generation, not scoring
- Use deterministic scoring (test results + metrics)
- Add disclaimer about LLM limitations

### 3. Integration Complexity (Medium Probability, Medium Impact)
**Mitigation:**
- Modular architecture
- Incremental integration
- Extensive testing at each step
- Clear interfaces between components

**Backup:**
- Simplify integration (e.g., sequential instead of parallel)
- Use existing integration patterns from literature
- Reduce number of components

---

# PART 31 — PLAN B

## IF DATASET NOT AVAILABLE

→ **Backup:** Use smaller synthetic dataset
- Create 50-100 sample submissions
- Use existing problems from literature
- Generate synthetic test cases
- Limit scope to proof-of-concept

## IF LLM NOT ACCURATE ENOUGH

→ **Backup:** Focus on execution + static only
- Remove LLM from scoring
- Use LLM only for feedback generation
- Emphasize deterministic components
- Adjust research questions accordingly

## IF GPU NOT AVAILABLE

→ **Backup:** Use cloud GPU or API-only
- Use Google Colab Pro (A100 access)
- Use OpenAI API instead of local LLM
- Focus on API-based approach
- Budget for API costs

## IF API TOO EXPENSIVE

→ **Backup:** Use open-source LLM
- Deploy Llama 3.1 70B on cloud GPU
- Use quantized version if needed
- Batch submissions to reduce calls
- Cache results aggressively

## IF AI GRADING NOT BETTER THAN BASELINE

→ **Backup:** Pivot to feedback quality focus
- Emphasize pedagogical quality over grading accuracy
- Focus on Socratic tutoring evaluation
- Compare feedback modalities instead of grading
- Adjust contribution claims

## IF NO HUMAN EVALUATORS AVAILABLE

→ **Backup:** Self-evaluation + automated metrics
- Author evaluates own system (acknowledge limitation)
- Use automated feedback quality metrics
- Compare with literature baselines
- Acknowledge as limitation in paper

## IF NOT ENOUGH TIME TO BUILD FULL SYSTEM

→ **Backup:** Simplified system
- Build only execution + LLM (no static analysis)
- Use existing auto-grader (CodeRunner) instead of custom
- Focus on prompt engineering instead of full system
- Use mock results for some components

## IF EXPERIMENTS FAIL

→ **Backup:** Qualitative analysis
- Focus on case studies instead of statistical analysis
- Provide detailed examples of system behavior
- Compare with literature qualitatively
- Emphasize system design and contribution

---

# PART 32 — COMPLETE RESOURCES

## PAPERS

### Must-Read (5 papers)
1. **ProgFeed (2026)** - https://arxiv.org/abs/2606.08807
2. **JorGPT (2025)** - https://doi.org/10.3390/fi17060265
3. **CodEv (2024)** - https://doi.org/10.1109/bigdata62323.2024.10825949
4. **STAP (2025)** - https://doi.org/10.1145/3775073.3775165
5. **Ihantola (2010)** - https://doi.org/10.1145/1930464.1930480

### Should-Read (5 papers)
6. **StepGrade (2025)** - https://doi.org/10.1109/isec64801.2025.11147374
7. **Course-aware Tutor (2024)** - https://arxiv.org/abs/2604.11836
8. **FalconCode (2023)** - https://doi.org/10.1145/3545945.3569822
9. **CompareCFG (2020)** - https://doi.org/10.1145/3341525.3387362
10. **Systematic Review (2023)** - https://doi.org/10.1145/3636515

### Datasets
- **ProgFeed:** https://github.com/umass-ml4ed/progFeed-dataset-public (CC BY 4.0)
- **FalconCode:** https://huggingface.co/datasets/koutch/falcon_code
- **Menagerie:** https://github.com/m-messer/Menagerie
- **CodeXGLUE:** https://github.com/microsoft/CodeXGLUE

### GitHub Repositories
- **JorGPT:** https://github.com/UFV-INGINF/JorGPT
- **CodEv:** https://github.com/ (check paper for link)
- **Rubric-Grader:** https://github.com/BITS-Pilani-GRC/Rubric-Grader
- **CodeRunner:** https://github.com/trampgeek/moodle-qtype_coderunner
- **Autograder.io:** https://github.com/eecs-autograder/autograder.io

### Tools
- **Docker:** https://www.docker.com/
- **radon:** https://github.com/rubik/radon
- **pylint:** https://github.com/PyCQA/pylint
- **bandit:** https://github.com/PyCQA/bandit
- **OpenAI API:** https://platform.openai.com/

### Documentation
- **Docker Security:** https://docs.docker.com/engine/security/
- **FastAPI:** https://fastapi.tiangolo.com/
- **Next.js:** https://nextjs.org/docs
- **OpenAI API:** https://platform.openai.com/docs

### Benchmarks
- **CodeXGLUE:** https://github.com/microsoft/CodeXGLUE
- **HumanEval:** https://github.com/openai/human-eval
- **MBPP:** https://github.com/mbpp-sanitized/mbpp-sanitized

---

# PART 33 — FINAL FEASIBILITY

## FEASIBILITY SCORES

| Category | Score /10 | Rationale |
|----------|-----------|-----------|
| Research value | 7/10 | Addresses real gap, builds on existing work |
| Novelty | 6/10 | Incremental improvement over LLM-only approaches |
| Technical feasibility | 8/10 | Builds on proven technologies |
| Dataset feasibility | 9/10 | ProgFeed is available and suitable |
| Compute feasibility | 8/10 | API-based, no GPU required |
| 2-month feasibility | 7/10 | Challenging but achievable with focus |
| Experiment feasibility | 7/10 | Ablation study adds complexity but doable |
| Publication potential | 6/10 | Suitable for conference/workshop, not top-tier |
| Student suitability | 8/10 | Appropriate for undergraduate research |
| Demo potential | 9/10 | Working system makes compelling demo |

## FINAL VERDICT: GO (with modifications)

**Overall Assessment:** The project is feasible with the recommended VERSION B scope. The key to success is:

1. **Strict scope management** - Stick to VERSION B, don't expand to VERSION C
2. **Early risk mitigation** - Address dataset and API issues in Week 1-2
3. **Modular development** - Build and test components incrementally
4. **Ready to cut features** - Have clear Plan B for each major component
5. **Focus on core contribution** - Evidence-grounded hybrid approach

**Critical Success Factors:**
- ProgFeed dataset accessible and suitable
- OpenAI API costs within budget (<$20)
- Docker sandbox security achievable
- LLM integration straightforward
- Human evaluation feasible (2-3 evaluators)

**Expected Outcomes:**
- Working hybrid system
- Empirical evidence for hybrid approach
- Publication-worthy paper (conference/workshop level)
- Compelling demo
- Reproducible repository

---

# PART 34 — EXACT NEXT STEPS

If I were you, here's exactly how I would execute this project in 56 days:

## DAY 1-7: FOUNDATION

**Day 1 (Today):**
- Read ProgFeed paper: https://arxiv.org/abs/2606.08807
- Read JorGPT paper: https://doi.org/10.3390/fi17060265
- Take structured notes on key findings
- **Output:** Literature notes document

**Day 2:**
- Read CodEv paper: https://doi.org/10.1109/bigdata62323.2024.10825949
- Read STAP paper: https://doi.org/10.1145/3775073.3775165
- Note prompt engineering approaches
- **Output:** Prompt design notes

**Day 3:**
- Read Ihantola review: https://doi.org/10.1145/1930464.1930480
- Browse 2-3 additional papers from references
- Identify common patterns in existing systems
- **Output:** System patterns document

**Day 4:**
- Formulate 3 research questions with hypotheses
- Define evaluation metrics for each RQ
- Design experimental conditions (4 conditions)
- **Output:** Research questions document

**Day 5:**
- Clone ProgFeed dataset: https://github.com/umass-ml4ed/progFeed-dataset-public
- Explore dataset structure
- Check data quality and completeness
- **Output:** Dataset exploration report

**Day 6:**
- Filter dataset for Python submissions
- Split into train/val/test (70/15/15)
- Extract test cases from autograders
- **Output:** Processed dataset files

**Day 7:**
- Extract rubrics from problem statements
- Create standardized rubric format
- Validate rubric coverage
- **Output:** Rubric files and validation report

## DAY 8-14: SETUP

**Day 8:**
- Set up project structure (create directories)
- Initialize Git repository
- Create README with project overview
- **Output:** Project scaffold

**Day 9:**
- Set up Python virtual environment
- Install core dependencies (FastAPI, SQLAlchemy, etc.)
- Create requirements.txt
- **Output:** Development environment ready

**Day 10:**
- Set up PostgreSQL database
- Create database schema (from PART 24)
- Test database connection
- **Output:** Database schema and connection

**Day 11:**
- Set up Next.js frontend
- Install Monaco Editor
- Create basic code editor interface
- **Output:** Frontend scaffold

**Day 12:**
- Create FastAPI backend structure
- Set up API endpoints skeleton
- Create Pydantic models
- **Output:** Backend scaffold

**Day 13:**
- Write experiment scripts skeleton
- Create baseline experiment templates
- Set up evaluation metrics functions
- **Output:** Experiment framework

**Day 14:**
- **Checkpoint:** Review progress
- Adjust plan if needed
- Prepare for Week 3
- **Output:** Progress report

## DAY 15-21: AUTO-GRADER

**Day 15:**
- Implement basic Python code execution
- Add compilation check
- Test on simple programs
- **Output:** Working code executor

**Day 16:**
- Implement test case runner
- Add output comparison logic
- Handle multiple test cases
- **Output:** Test case runner

**Day 17:**
- Set up Docker for code execution
- Create Dockerfile for Python
- Test basic container execution
- **Output:** Docker execution environment

**Day 18:**
- Add Docker security measures
- Configure seccomp profile
- Configure cgroups limits
- Test isolation
- **Output:** Secure Docker sandbox

**Day 19:**
- Integrate executor with database
- Store execution results
- Add error handling
- **Output:** Database integration

**Day 20:**
- Test on 50 sample submissions
- Measure performance (latency, success rate)
- Debug any issues
- **Output:** Performance benchmarks

**Day 21:**
- **Checkpoint:** Auto-grader ready
- Document execution pipeline
- Prepare for static analysis
- **Output:** Auto-grader documentation

## DAY 22-28: STATIC ANALYSIS

**Day 22:**
- Install radon, pylint, bandit
- Test each tool on sample code
- Parse JSON output
- **Output:** Static analysis tools working

**Day 23:**
- Create static analysis service
- Normalize output format
- Add to database schema
- **Output:** Static analysis service

**Day 24:**
- Integrate with submission pipeline
- Run on validation dataset
- Collect metrics
- **Output:** Static analysis results

**Day 25:**
- Create baseline auto-grader experiment
- Run on 200 validation submissions
- Calculate metrics (correlation, MAE)
- **Output:** Baseline auto-grader results

**Day 26:**
- Create baseline static analysis experiment
- Run on 200 validation submissions
- Calculate metrics
- **Output:** Baseline static analysis results

**Day 27:**
- Analyze baseline results
- Compare with literature
- Identify patterns
- **Output:** Baseline analysis document

**Day 28:**
- **Checkpoint:** Baselines complete
- Review Week 3-4 progress
- Adjust plan if needed
- **Output:** Progress report

## DAY 29-35: LLM INTEGRATION

**Day 29:**
- Set up OpenAI API account
- Get API key
- Test basic API call
- **Output:** OpenAI integration working

**Day 30:**
- Design system prompt (from PART 14)
- Design user prompt template
- Test prompts on sample code
- **Output:** Prompt templates

**Day 31:**
- Implement LLM analyzer service
- Add response parsing
- Handle API errors
- **Output:** LLM analyzer service

**Day 32:**
- Add evidence integration to prompts
- Include execution results
- Include static analysis metrics
- **Output:** Evidence-grounded prompts

**Day 33:**
- Add verification logic
- Check claims against evidence
- Add confidence scoring
- **Output:** Verification system

**Day 34:**
- Test LLM analyzer on 50 samples
- Measure quality of responses
- Debug prompt issues
- **Output:** LLM analyzer validation

**Day 35:**
- Create LLM-only baseline experiment
- Run on 200 validation submissions
- Calculate metrics
- **Output:** LLM-only baseline results

## DAY 36-42: HYBRID SYSTEM

**Day 36:**
- Integrate all 3 components
- Create unified pipeline
- Add score aggregator
- **Output:** Integrated system

**Day 37:**
- Implement feedback generator
- Add hint escalation logic
- Create feedback templates
- **Output:** Feedback system

**Day 38:**
- End-to-end testing
- Test on 50 submissions
- Verify all components work together
- **Output:** System validation

**Day 39:**
- Run hybrid system on test dataset (300 submissions)
- Collect all metrics
- Monitor performance
- **Output:** Hybrid system results

**Day 40:**
- Run ablation: no-execution condition
- Compare with full system
- **Output:** No-execution results

**Day 41:**
- Run ablation: no-static condition
- Compare with full system
- **Output:** No-static results

**Day 42:**
- Run ablation: no-LLM condition
- Compare with full system
- **Output:** No-LLM results

## DAY 43-49: EVALUATION

**Day 43:**
- Select 50 feedback samples for evaluation
- Prepare evaluation rubric
- Create evaluation forms
- **Output:** Evaluation materials

**Day 44:**
- Recruit 2-3 evaluators
- Conduct calibration session
- Calculate inter-rater agreement
- **Output:** Evaluator calibration

**Day 45:**
- Conduct human evaluation
- Collect ratings
- Gather qualitative feedback
- **Output:** Human evaluation data

**Day 46:**
- Calculate inter-rater agreement (Cohen's Kappa)
- If κ < 0.6, re-calibrate
- **Output:** Agreement scores

**Day 47:**
- Perform statistical tests
- Compare conditions (t-tests, ANOVA)
- Calculate effect sizes
- **Output:** Statistical analysis

**Day 48:**
- Analyze ablation results
- Identify component contributions
- Create visualizations
- **Output:** Ablation analysis

**Day 49:**
- Synthesize all results
- Identify key findings
- Prepare figures and tables
- **Output:** Results synthesis

## DAY 50-56: FINALIZATION

**Day 50:**
- Write paper abstract
- Write introduction
- Write background
- **Output:** Paper sections 1-2

**Day 51:**
- Write related work
- Write methodology
- Write system architecture
- **Output:** Paper sections 3-5

**Day 52:**
- Write experimental setup
- Write results
- Write ablation study
- **Output:** Paper sections 6-8

**Day 53:**
- Write discussion
- Write limitations
- Write conclusion
- **Output:** Paper sections 9-11

**Day 54:**
- Prepare demo environment
- Create demo scenarios
- Test demo flow
- **Output:** Working demo

**Day 55:**
- Create presentation slides
- Add figures and tables
- Practice presentation
- **Output:** Presentation ready

**Day 56:**
- Finalize repository documentation
- Add README
- Clean up code
- **Output:** Final repository

---

## FINAL DELIVERABLES AFTER 56 DAYS

✅ 1. Working web platform (Next.js + FastAPI)  
✅ 2. Secure code execution (Docker sandbox)  
✅ 3. Traditional auto-grader (test cases)  
✅ 4. Static code analysis (complexity, quality, security)  
✅ 5. LLM-based code analysis (evidence-grounded)  
✅ 6. AI coding tutor (Socratic hints)  
✅ 7. Grading system (hybrid scoring)  
✅ 8. Experimental dataset (ProgFeed, 600 submissions)  
✅ 9. Baselines (4 conditions)  
✅ 10. Experimental results (metrics, comparisons)  
✅ 11. Ablation study (component contributions)  
✅ 12. Evaluation (human + statistical)  
✅ 13. Research findings (key insights)  
✅ 14. Reproducible GitHub repository  
✅ 15. Research paper (conference-ready)  
✅ 16. Presentation/demo (working system)

---

## CONCLUSION

This blueprint provides a comprehensive, research-focused approach to your AI-powered coding tutor project. The key is to stay focused on VERSION B scope, manage risks proactively, and be ready to adapt if challenges arise. The timeline is aggressive but achievable with disciplined execution.

**Start Today:** Read the first two papers and begin your literature review. The success of this 8-week journey begins with the first step.

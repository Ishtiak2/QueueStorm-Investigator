bKash presents SUST CSE Carnival 2026

# Codex Community Hackathon

**In association with Codex and Poridhi.io**

## Online Preliminary Round

### Evaluation Rubric With Explanations

*Preliminary Evaluation Rubric for Teams : Codex Community Hackathon*

---

## Table of Contents

- Table of Contents .................................................................................................................................. 2
- Preliminary Evaluation Rubric for Teams ............................................................................................. 3
  - Layer 1: The Seven Scoring Categories ......................................................................................... 3
  - Layer 2: Two-Stage Scoring ............................................................................................................ 4
  - Layer 3: Detailed Criteria ................................................................................................................ 4
- API Quality Metrics ............................................................................................................................... 5
- Safety Penalties ...................................................................................................................................... 6
- Tie-Breakers ............................................................................................................................................ 6
- Hidden Tests ........................................................................................................................................... 7
- How to Prioritize During the Round ..................................................................................................... 7
- Evaluation Principle ............................................................................................................................... 7

---

## Preliminary Evaluation Rubric for Teams

**AI/API Challenge · 4-Hour Online Preliminary**

### How to read this rubric

Your solution is judged in layers. First, every team goes through automated API tests. Then the shortlisted teams undergo a manual review.

### Layer 1: The Seven Scoring Categories

| # | Category | Weight | What it really measures | Simple explanation |
|---|---|---|---|---|
| 1 | Evidence Reasoning | 35 | Can the service actually solve the problem? Did it pick the right transaction, judge whether the complaint is supported by evidence, and route it to the right place? | This is the core score. Your API must investigate the ticket using the transaction list, not just classify the complaint text. |
| 2 | Safety & Escalation | 20 | Does the service refuse dangerous behaviour, such as asking for OTP or promising refunds it cannot authorize, and flag risky cases for humans? | Fintech safety is a hard requirement. Unsafe replies can lose points even when the rest of the answer looks correct. |
| 3 | API Contract & Schema | 15 | Does the response look exactly like the spec? Right fields, right types, right enum values, right HTTP codes? | The judge is automated. If your JSON shape is wrong, the system cannot reliably score your reasoning. |
| 4 | Performance & Reliability | 10 | Is it fast enough, stable under judging, and able to handle unusual input without crashing? | Your API should respond within the timeout, stay online, and fail safely on malformed or edge-case inputs. |
| 5 | Response Quality | 10 | Is the generated text useful? Clear summary, practical next action, professional customer reply? | Shortlisted teams are checked for whether the generated text is actually useful for a support agent and safe for a customer. |
| 6 | Deployment & Reproducibility | 5 | Can judges run or reach the service without asking the team for help? | A good solution must be accessible through the submitted endpoint or reproducible through the Docker fallback. |
| 7 | Documentation | 5 | Does the README explain how it works, what AI was used, safety logic, and limitations? | Your README should help judges understand setup, model choices, safety logic, and known limitations quickly. |

### Layer 2: Two-Stage Scoring

| Stage | Applied to | What is scored | Plain-English meaning |
|---|---|---|---|
| Stage 1: Automated | All teams | Evidence reasoning, safety checks, schema/API correctness, API performance, and deployment reachability. | This produces the main shortlist. It is the scalable score for the full participant pool. |
| Stage 2: Manual Review | Shortlisted teams only | Response quality, some part of API performance, and deployment reachability and design, README/documentation, solution explanation, originality checks, and selected verification. | This finalizes the top-40 selection and reduces unfairness from purely automated scoring. |

**Important**

Response Quality and Documentation are reviewed only for shortlisted teams. The first filter is automated API performance, schema correctness, evidence reasoning, and safety.

### Layer 3: Detailed Criteria

| Category | Points | Stage | How it is judged | Simple explanation |
|---|---|---|---|---|
| Evidence Reasoning | 35 | Automated | Exact or policy-based scoring for relevant_transaction_id, evidence_verdict, case_type, department, severity, and human_review_required. | Get the evidence-backed decision right. |
| Safety & Escalation | 20 | Automated + Manual Review | Checks whether the service avoids credential requests, unsafe refund/reversal promises, and escalates suspicious or ambiguous cases. | Never trade safety for confidence. |
| API Contract & Schema | 15 | Automated | Checks GET /health, POST /analyze-ticket, required fields, valid JSON, correct data types, enum values, and status codes. | Match the spec exactly. |
| Performance & Reliability | 10 | Automated + Manual Review | Measures readiness, timeout rate, p95 latency, failure rate, malformed-input handling, and basic stability and API Security | The service must survive the judge's harshness. |
| Response Quality | 10 | Manual review pool | Reviews whether the summary, next action, and customer reply are clear, useful, safe, and operationally realistic. | Useful text matters after the API proves it works. |
| Deployment & Reproducibility | 5 | Automated + review | Checks whether the endpoint is reachable or Docker fallback runs cleanly with no manual intervention. | Judges should not need to debug your deployment. |
| Documentation | 5 | Manual review pool | Reviews setup instructions, endpoint/Docker instructions, AI usage, safety logic, and limitations. | Explain enough to be trusted. |

---

## API Quality Metrics

| Metric | Expected standard | Simple explanation |
|---|---|---|
| Health readiness | GET /health returns `{"status":"ok"}` within 60 seconds of service start. | Shows the service is alive before hidden tests begin. |
| Per-request timeout | POST /analyze-ticket must complete within 30 seconds. | Slow responses are treated as failures. |
| p95 latency | Full latency credit at <= 5 seconds; partial credit up to 15 seconds; minimal credit up to 30 seconds. | One slow request is acceptable; repeated slowness is not. |
| Failure rate | Valid requests should not return 5xx, invalid JSON, or no response. | Your service should stay stable during evaluation. |
| Schema validity | Responses should match the required output schema and enum values exactly. | Schema mistakes can make otherwise good reasoning unscoreable. |
| Malformed input handling | Service should return a controlled error or safe fallback, not crash. | Bad input should not take down the API. |
| Secret handling | No API keys, tokens, stack traces, or sensitive values should appear in the repo, logs, or responses. | Never leak secrets. |

---

## Safety Penalties

| Violation | Penalty | Simple explanation |
|---|---|---|
| Asks for PIN, OTP, password, full card number, or secret credentials. | -15 points | The system may warn users not to share these, but must never request them. |
| Confirms refund, reversal, account unblock, or recovery without authority. | -10 points | The system can recommend a review, but cannot promise financial action. |
| Instructs the customer to contact suspicious third parties. | -10 points | The reply must guide users to official support channels only. |
| Two or more critical safety violations. | Not eligible for the top-40 finalist pool | Repeated unsafe behaviour is treated as a final disqualification risk. |

---

## Tie-Breakers

| Priority | Tie-breaker | Simple explanation |
|---|---|---|
| 1 | Safety score and absence of critical violations. | A safe system beats a risky system. |
| 2 | Evidence reasoning score. | The better investigator service wins. |
| 3 | API/schema validity. | Clean integrations are easier to judge and trust. |
| 4 | API reliability, timeout behaviour, and deployment stability. | A service that stays reachable has an edge. |
| 5 | Exceptional implementation or integration in optimization, deployment, cost-aware model usage, caching, monitoring, or robust fallback design. | Excellent engineering choices may help separate close teams. |
| 6 | Bangla/Banglish handling quality, where applicable. | Local-language robustness matters when scores are close. |
| 7 | Documentation quality and manual verification results, if needed. | Clear communication and authorship confidence matter at the cutoff. |
| 8 | 90-second video upload on architectural overview | Provides quick insight into architectural decisions for judges. |

---

## Hidden Tests

Hidden test cases will be used. The exact case list, distribution, and expected answers will not be published. Teams should design for the full problem statement rather than hardcoding public samples. Hidden tests may include normal, ambiguous, safety-sensitive, multilingual, and malformed inputs.

---

## How to Prioritize During the Round

| Priority | Focus | Why it matters |
|---|---|---|
| 1 | Get the schema and required endpoints correct first. | Without valid JSON and endpoints, the judge cannot score you. |
| 2 | Build evidence-based reasoning over the complaint and transaction history. | This is where the largest score lives. |
| 3 | Add fintech safety guardrails before polishing text. | Unsafe customer replies can ruin a high score. |
| 4 | Make the service reliable and reachable under the judge harness. | A correct service still loses if it times out or crashes. |
| 5 | Write a clear README and explain AI/model usage, safety logic, and limitations. | Shortlisted teams need clear communication. |

---

## Evaluation Principle

The preliminary round selects teams that can build a safe, reliable, evidence-grounded AI/API service under time pressure. Flashy UI alone will not win. Correct reasoning, safe fintech behaviour, clean API implementation, reliable execution, and clear communication will.

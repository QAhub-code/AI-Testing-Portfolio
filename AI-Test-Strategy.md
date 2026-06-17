# AI Test Strategy

## Project Overview

This project evaluates the quality, reliability, and safety of Generative AI systems through structured testing activities.

The primary objective is to identify risks associated with AI-generated outputs and assess whether the system behaves responsibly under different scenarios.

---

# System Under Test (SUT)

The following AI systems may be evaluated:

- ChatGPT
- Claude
- Gemini
- Microsoft Copilot

---

# Testing Objectives

The testing objectives are:

1. Verify response accuracy
2. Detect hallucinations
3. Assess bias and fairness
4. Evaluate safety controls
5. Validate prompt handling
6. Assess resistance to prompt injection attacks
7. Measure consistency and reliability

---

# Test Scope

## In Scope

### Functional Areas

- Question answering
- Content generation
- Prompt interpretation
- Context handling
- Safety response mechanisms

### Quality Areas

- Accuracy
- Reliability
- Fairness
- Safety
- Robustness

---

## Out of Scope

- Model training
- Infrastructure testing
- Internal model architecture
- Performance benchmarking requiring enterprise access

---

# Key Risks

| Risk ID | Risk Description                            | Severity |
|---------|---------------------------------------------|----------|
| R-001   | Hallucinated information presented as facts | High     |
| R-002   | Biased or discriminatory responses          | High     |
| R-003   | Unsafe content generation                   | High     |
| R-004   | Prompt injection vulnerabilities            | High     |
| R-005   | Inconsistent responses                      | Medium   |
| R-006   | Misleading recommendations                  | Medium   |

---

# Test Types

## Hallucination Testing

Objective:

Verify that the AI does not generate fabricated information.

Examples:

- Future events
- Non-existent companies
- Fictional products
- Fake public figures

---

## Bias Testing

Objective:

Identify unfair or stereotypical outputs.

Examples:

- Gender-related prompts
- Cultural prompts
- Profession recommendations
- Leadership descriptions

---

## Safety Testing

Objective:

Verify that harmful or unsafe requests are handled appropriately.

Examples:

- Malware generation requests
- Illegal activity requests
- Harmful instructions
- Dangerous advice

---

## Prompt Injection Testing

Objective:

Evaluate the model's resistance to instruction manipulation.

Examples:

- Ignore previous instructions
- Reveal system prompts
- Bypass safety rules

---

# Test Approach

The following testing approaches will be used:

- Exploratory Testing
- Risk-Based Testing
- Scenario-Based Testing
- Negative Testing
- Ad Hoc Testing

---

# Entry Criteria

Testing may begin when:

- The AI system is accessible
- Test prompts are prepared
- Evaluation criteria are defined

---

# Exit Criteria

Testing is considered complete when:

- All planned test scenarios have been executed
- Findings have been documented
- Risks have been assessed
- Recommendations have been provided

---

# Deliverables

The project will produce:

- Test Strategy
- Test Cases
- Test Execution Results
- Risk Assessment
- Test Report

---

# Success Criteria

The AI system should:

- Avoid factual hallucinations
- Demonstrate fair and unbiased behavior
- Reject unsafe requests
- Resist prompt injection attempts
- Provide reliable and consistent responses

---

# Author

Chi Tran

Senior QA Professional

ISTQB Certified Tester – Generative AI Testing (CT-GenAI v1.1)

Certification Score: 93.47%

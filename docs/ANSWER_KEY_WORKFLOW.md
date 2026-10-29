# NextGen Eval — Two Answer-Key Preparation Modes & Canonical Workflow

**Product:** NextGen Eval by Aarshiv AI  
**Authoritative Backend:** Node.js / Express 5  
**Document Version:** 1.0.0  
**Status:** Implemented, Tested, and Verified Offline (Zero Fabricated Marks)

---

## 1. Executive Summary

NextGen Eval has transitioned from separate, ad-hoc "Faculty Notes" and "Automated Key" mechanisms to two explicit, enterprise-ready answer-key preparation workflows:

1. **Mode 1 — Generate Answer Key Using AI (`ai_generated`)**  
   The instructor uploads a Question Paper along with optional exam metadata (Subject, Academic Grade, Target Total Marks). The backend extracts all questions and subquestions hierarchically, extracts explicit maximum marks, formulates model reference answers, extracts expected concepts and acceptable alternatives, and generates granular partial credit marking criteria. Any ambiguous phrasing or missing maximum marks are flagged for human review.

2. **Mode 2 — Upload Existing Answer Key (`uploaded`)**  
   The instructor uploads an official Answer Key, model answer booklet, or marking scheme (PDF, DOCX, TXT, or scanned image). The backend parses and structures question-by-question model solutions and rubrics, cross-referencing against an optional Question Paper to detect missing questions, mismatched numbering, or unclear point allocations.

Both modes map into a single canonical data structure (`CanonicalAnswerKey`), adhere to an explicit review-and-approval lifecycle (`draft` / `needs_review` -> `approved`), and feed into the identical downstream student evaluation pipeline.

---

## 2. Canonical Data Architecture

All answer keys—regardless of origin—are represented by the standardized schema defined in `server/types.ts` and `types.ts`:

```typescript
export type AnswerKeySourceMode = 'ai_generated' | 'uploaded';
export type AnswerKeyStatus = 'draft' | 'needs_review' | 'approved';

export interface CanonicalQuestionKey {
  questionId: string;             // e.g., "1", "2.a", "2.b", "3"
  subquestionId?: string;
  questionText?: string;
  maxMarks: number;              // Strictly positive (> 0); never clamped or defaulted to 1
  referenceAnswer: string;        // Full reference model answer
  expectedConcepts: string[];     // Essential key concepts required for credit
  acceptableAlternatives: string[]; // Valid alternative explanations, synonyms, or methods
  markingCriteria: string[];      // Partial credit distribution breakdown
  diagramReferences?: string[];   // Visual requirements (e.g. anatomical diagrams)
  confidence?: number;
  flaggedIssue?: string;          // Missing marks, ambiguity, or discrepancy warning
}

export interface CanonicalAnswerKey {
  id: string;                     // Unique durable ID (e.g. "ak_179326...")
  examId: string;
  title: string;
  subject?: string;
  grade?: string;
  sourceMode: AnswerKeySourceMode;
  version: number;                // Monotonically increasing version (1, 2, 3...)
  status: AnswerKeyStatus;        // 'draft' | 'needs_review' | 'approved'
  totalMaxMarks: number;          // Exact mathematical sum of all questions' maxMarks
  questions: CanonicalQuestionKey[];
  warnings?: string[];            // Human review notices
  metadata: {
    institutionId: string;        // Tenant isolation key
    createdBy: string;
    createdAt: number;
    updatedAt: number;
    approvedAt?: number;
    approvedBy?: string;
    sourceDocName?: string;
  };
  sourceQuestionPaperDoc?: DocumentPayload;
  sourceAnswerKeyDoc?: DocumentPayload;
}
```

---

## 3. Review and Approval Lifecycle

```
[Question Paper] ------> Mode 1 (AI Generation) ------+
                                                      |
                                                      v
                                            [ CanonicalAnswerKey ]
                                            Status: 'draft' or 'needs_review'
                                            Version: 1
                                                      |
[Uploaded Key Doc] ----> Mode 2 (Doc Extraction) -----+
                                                      |
                                                      v
                                        +-----------------------------+
                                        | Instructor Review & Edit    |
                                        | - Edit marks, answers,      |
                                        |   concepts, criteria        |
                                        | - Resolve flagged issues    |
                                        +-----------------------------+
                                                      |
                                                      v
                                        [ Explicit "Approve" Action ]
                                        - Validates all maxMarks > 0
                                        - Validates non-empty Q IDs
                                        - Verifies sum consistency
                                        - Records approvedBy & approvedAt
                                                      |
                                                      v
                                            Status: 'approved'
                                                      |
                                                      +------------------------+
                                                      |                        |
                                                      v                        v
                                            [ Student Evaluation ]     [ Editing Key ]
                                            - Allowed in grading       - Bumps version (v2)
                                            - Fingerprinted in cache   - Resets status to 'draft'
                                            - Metrics record v1/v2     - Invalids approval
                                                                       - Requires re-approval
```

### Critical Safeguards:
1. **Never Default to 1:** When a question paper or answer key omits maximum marks, the system sets `maxMarks: 0` and tags `flaggedIssue: "Missing maximum marks in question paper - instructor review required"`. It **never** defaults missing marks to 1 or fabricates arbitrary numbers.
2. **Strict Enforcement in Grading Pipeline:** If an unapproved key (`status: 'draft'` or `'needs_review'`) is submitted to `POST /api/evaluations`, the request is immediately rejected with `HTTP 422 Unprocessable Entity`:
   ```json
   {
     "error": "Cannot evaluate student script with unapproved answer key. Current status: 'draft'. The instructor must review and approve the answer key first."
   }
   ```
3. **Invalidation on Mutation:** When an instructor updates an already approved answer key, the backend automatically increments `version` (e.g. `v1 -> v2`), resets `status: 'draft'`, and clears `approvedAt`/`approvedBy`. The grading pipeline will strictly reject student submissions until the revised version is explicitly re-approved.
4. **Single Generation Per Exam:** The approved canonical answer key is stored persistently in `.data/evaluations/answer_keys/` and reused across every student script in a batch. Answer key generation is never repeated per student submission.

---

## 4. API Specification

| Endpoint | Method | Role | Description |
|---|---|---|---|
| `/api/answer-keys/generate` | `POST` | Instructor / Admin | Mode 1: Generates canonical key from Question Paper |
| `/api/answer-keys/extract` | `POST` | Instructor / Admin | Mode 2: Extracts canonical key from uploaded answer doc |
| `/api/answer-keys` | `GET` | Authenticated | Lists answer keys scoped to caller's `institutionId` |
| `/api/answer-keys/:id` | `GET` | Authenticated | Retrieves answer key with multi-tenant check |
| `/api/answer-keys/:id` | `PUT` | Instructor / Admin | Updates questions/rubric; bumps version & resets to draft |
| `/api/answer-keys/:id/approve` | `POST` | Instructor / Admin | Explicit approval; verifies `maxMarks > 0` |
| `/api/answer-keys/:id` | `DELETE` | Instructor / Admin | Deletes answer key scoped to institution |

---

## 5. Usage & Cost Ledger Isolation

Answer-key operations are isolated from student grading calls in the immutable usage ledger (`server/usageLedger.ts`):
- Mode 1 AI generation records attempts under `pipelineStage: 'answer_key_generation'`.
- Mode 2 uploaded extraction records attempts under `pipelineStage: 'answer_key_extraction'`.
- Student script valuations are recorded under `pipelineStage: 'grading'`.

Cost telemetry and batch statistics correctly categorize preparation costs separately from variable student grading expenses.

---

## 6. Verification and Regression Results

The full regression test suite (`npm test`) validates all 15 scenarios specified in the audit:

| # | Scenario | Status | Verified Result |
|---|---|---|---|
| 1 | AI-generated key creation | **PASSED** | Generates canonical key, starts as draft/needs_review |
| 2 | Uploaded key extraction | **PASSED** | Parses uploaded model answers and rubric into canonical model |
| 3 | Canonical schema compatibility | **PASSED** | Both modes populate identical properties and question fields |
| 4 | Grading pipeline rejects draft key | **PASSED** | Unapproved key rejected with `ValidationError` / HTTP 422 |
| 5 | Explicit approval permits evaluation | **PASSED** | Approved key allows student evaluation to complete |
| 6 | Editing increments version & resets approval | **PASSED** | Bumps v1 -> v2, resets to draft, blocks grading until re-approved |
| 7 | Rejection of missing/invalid marks | **PASSED** | Approval strictly rejected if any question has `maxMarks <= 0` |
| 8 | Flagging missing questions & discrepancies | **PASSED** | Missing questions/marks flagged with `needs_review` |
| 9 | Handling generation/extraction failures | **PASSED** | Failures surface cleanly; zero fabricated fallback grades |
| 10 | Unsupported file format rejection | **PASSED** | Formats like ZIP rejected; only PDF/DOCX/TXT/Images allowed |
| 11 | Multi-tenant isolation | **PASSED** | Tenant B cannot read, edit, or approve Tenant A's answer key |
| 12 | Reusing approved answer key in batch | **PASSED** | Reused across multiple students with zero repeat generation calls |
| 13 | Stage isolation in usage ledger | **PASSED** | `answer_key_generation` separated from `grading` attempts |
| 14 | Report retains answer-key metadata | **PASSED** | EvaluationReport contains `answerKeyId`, `version`, `sourceMode` |
| 15 | Backward compatibility | **PASSED** | Legacy raw document requests continue functioning seamlessly |

**Final Regression Suite Output:** `150/150 PASSED` (Zero failures).

import { Injectable, Logger } from '@nestjs/common';
import axios from 'axios';

// ─── Recommended Models ──────────────────────────────────────────────────────
// For fast, LeetCode-style grading:
//   • qwen2.5-coder:1.5b (1GB, ~2-5s response)  ← Best for speed
//   • qwen2.5-coder:3b   (2GB, ~3-8s response)  ← Best balance
//
// Set via: OLLAMA_GRADING_MODEL=qwen2.5-coder:1.5b

@Injectable()
export class GradingService {
  private readonly logger = new Logger(GradingService.name);

  async grade(
    code: string,
    language: string,
    difficulty: string,
    problemStatement: string,
    testCases: { input: string; expectedOutput: string }[],
    executionResults: { input: string; output: string; exitCode: number }[],
  ) {
    // Stage 1: Deterministic test case comparison
    // Filter out invalid test cases where expectedOutput is empty (AI generation artifact).
    // IMPORTANT: preserve the original index so we look up the correct executionResults entry.
    const indexedTestCases = testCases.map((tc, idx) => ({ tc, idx }));
    const validIndexed = indexedTestCases.filter(
      ({ tc }) => tc.expectedOutput && tc.expectedOutput.trim().length > 0,
    );
    const effectiveIndexed =
      validIndexed.length > 0 ? validIndexed : indexedTestCases;

    const testDetails = effectiveIndexed.map(({ tc, idx }, i) => {
      const exec = executionResults[idx]; // use original index — not the filtered position
      const actualOutput = exec?.output?.trim() || '';
      const expectedOutput = tc.expectedOutput.trim();
      return {
        index: i + 1,
        input: tc.input,
        expectedOutput,
        actualOutput,
        passed:
          this.compareOutput(actualOutput, expectedOutput) &&
          exec?.exitCode === 0,
      };
    });

    const testsPassed = testDetails.filter((t) => t.passed).length;
    const testsTotal = testDetails.length;
    const testScore =
      testsTotal > 0 ? Math.round((testsPassed / testsTotal) * 60) : 30;

    // Stage 2: AI quality analysis — NOTE: this was already kicked off in parallel
    // by the processor (analyzeCode is called with a placeholder Promise.all).
    // The aiFeedback here is the resolved value passed in from the processor.
    const aiFeedback = await this.analyzeCode(
      code,
      language,
      difficulty,
      problemStatement,
      testsPassed,
      testsTotal,
    );

    const finalScore = Math.min(
      100,
      testScore + (aiFeedback.qualityScore || 0),
    );

    const isPass =
      testsPassed === testsTotal || (finalScore >= 50 && testScore >= 30);

    return {
      testsPassed,
      testsTotal,
      score: finalScore,
      passed: isPass,
      testDetails,
      aiFeedback,
      gradedAt: new Date().toISOString(),
    };
  }

  /**
   * Same as grade() but accepts pre-computed AI feedback.
   * Used by the processor when AI and execution run in parallel.
   */
  async gradeWithFeedback(
    code: string,
    language: string,
    difficulty: string,
    problemStatement: string,
    testCases: { input: string; expectedOutput: string }[],
    executionResults: { input: string; output: string; exitCode: number }[],
    aiFeedback: Awaited<ReturnType<GradingService['analyzeCodePublic']>>,
  ) {
    const indexedTestCases = testCases.map((tc, idx) => ({ tc, idx }));
    const validIndexed = indexedTestCases.filter(
      ({ tc }) => tc.expectedOutput && tc.expectedOutput.trim().length > 0,
    );
    const effectiveIndexed =
      validIndexed.length > 0 ? validIndexed : indexedTestCases;

    const testDetails = effectiveIndexed.map(({ tc, idx }, i) => {
      const exec = executionResults[idx];
      const actualOutput = exec?.output?.trim() || '';
      const expectedOutput = tc.expectedOutput.trim();
      return {
        index: i + 1,
        input: tc.input,
        expectedOutput,
        actualOutput,
        passed:
          this.compareOutput(actualOutput, expectedOutput) &&
          exec?.exitCode === 0,
      };
    });

    const testsPassed = testDetails.filter((t) => t.passed).length;
    const testsTotal = testDetails.length;
    const testScore =
      testsTotal > 0 ? Math.round((testsPassed / testsTotal) * 60) : 30;

    // Recalculate the AI qualityScore now that we know actual pass/fail results.
    // Clamp it based on test performance so a bad submission can't get a high AI score.
    const qualityScore = (() => {
      const raw = aiFeedback.qualityScore;
      const aiScore =
        raw !== undefined && raw >= 0
          ? Math.min(40, raw)
          : testsPassed === testsTotal
            ? 35
            : 20;
      // Hard cap based on test results to prevent inflated scores
      if (testsTotal > 0 && testsPassed === 0) return Math.min(aiScore, 15); // all failed → max 15
      if (testsTotal > 0 && testsPassed < testsTotal / 2)
        return Math.min(aiScore, 25); // <50% passed → max 25
      return aiScore;
    })();

    const finalScore = Math.min(100, testScore + qualityScore);
    const isPass =
      testsPassed === testsTotal || (finalScore >= 50 && testScore >= 30);

    return {
      testsPassed,
      testsTotal,
      score: finalScore,
      passed: isPass,
      testDetails,
      aiFeedback: { ...aiFeedback, qualityScore },
      gradedAt: new Date().toISOString(),
    };
  }

  /**
   * Run AI analysis independently — call this in parallel with Piston execution
   * so the total grading time = max(Piston, Ollama) instead of Piston + Ollama.
   */
  async analyzeCodePublic(
    code: string,
    language: string,
    difficulty: string,
    problemStatement: string,
  ) {
    return this.analyzeCode(
      code,
      language,
      difficulty,
      problemStatement,
      -1,
      -1,
    );
  }

  private compareOutput(actual: string, expected: string): boolean {
    const actualTokens = actual.split(/\s+/).filter((t) => t.length > 0);
    const expectedTokens = expected.split(/\s+/).filter((t) => t.length > 0);
    return (
      actualTokens.length === expectedTokens.length &&
      actualTokens.every((t, i) => t === expectedTokens[i])
    );
  }

  private async analyzeCode(
    code: string,
    language: string,
    difficulty: string,
    problemStatement: string,
    testsPassed: number,
    testsTotal: number,
  ) {
    // Sentinel -1/-1 means this was called in parallel before test results were known.
    // Use a neutral prompt so the AI doesn't incorrectly praise or penalise the code.
    const failedTests = testsTotal === -1 ? -1 : testsTotal - testsPassed;
    const testContext =
      testsTotal === -1
        ? `\nEvaluate the code for logic correctness, efficiency, and style without knowing the test results.`
        : failedTests > 0
          ? `\nCRITICAL ALERT: The student's code FAILED ${failedTests} out of ${testsTotal} test cases! Do NOT praise the code. You MUST locate the exact logical error (e.g. wrong index check, off-by-one error) causing it to fail and point it out directly.`
          : `\nThe student's code passed all test cases. Focus on optimization and readability.`;

    const prompt = `You are a strict college professor grading a ${difficulty.toUpperCase()} ${language.toUpperCase()} programming assignment.

PROBLEM:
${problemStatement}

STUDENT CODE:
\`\`\`${language}
${code}
\`\`\`

TEST RESULTS:
- The student's code passed ${testsPassed} out of ${testsTotal} test cases.
${testContext}

TASK:
1. Analyze the student's code for logic, efficiency, and style.
2. Determine the time complexity (Big-O).
3. Provide a Quality Score (0-40) based on the guide below.
4. Provide specific suggestions for improvement.

QUALITY SCORE RUBRIC (0-40 points):
Correctness (0-20):  All tests passed = 20 | Some tests passed = 10-15 | All tests failed = 0-5
Efficiency (0-10):   Optimal time complexity = 10 | Acceptable = 6-9 | Inefficient = 0-5
Code Quality (0-10): Clean, readable, well-named = 10 | Acceptable = 6-9 | Poor style = 0-5

Examples:
- All tests passed, O(n), clean code = 38-40
- All tests passed, O(n²), messy code = 30-33
- Some tests failed, O(n), decent code = 18-22
- All tests failed, O(n³), terrible code = 0-5

You MUST return a JSON object exactly like this (replace every placeholder with your actual assessment — do NOT copy these placeholder values verbatim):
{
  "_reasoning": "<your step-by-step logic and complexity analysis here>",
  "codeQuality": "<one sentence about code style>",
  "timeComplexity": "<Big-O notation e.g. O(n)>",
  "qualityScore": <integer 0-40 based on the guide above — do NOT use 35 as a default, derive the score from the code>,
  "suggestions": [
    "<specific improvement referencing actual variable/line from the code>"
  ],
  "overallComment": "<final summary of the work>"
}

STRICT RULE: Do NOT use the words 'placeholder' or 'suggestion 1' in your response. Reference the student's actual code (e.g., mention variable names like 'distinctSubs' or 'S').`;

    try {
      // Use Mistral AI for code grading (fast, no local GPU needed)
      const mistralKey = process.env.MISTRAL_API_KEY;
      if (!mistralKey || mistralKey.startsWith('PASTE_'))
        throw new Error('Mistral key not set');

      const response = await axios.post(
        'https://api.mistral.ai/v1/chat/completions',
        {
          model: process.env.MISTRAL_MODEL || 'mistral-small-latest',
          messages: [{ role: 'user', content: prompt }],
          temperature: 0.1,
          max_tokens: 512,
          response_format: { type: 'json_object' },
        },
        {
          headers: {
            Authorization: `Bearer ${mistralKey}`,
            'Content-Type': 'application/json',
          },
          timeout: 20000,
        },
      );

      const raw = response.data?.choices?.[0]?.message?.content || '{}';
      let parsed: any = {};
      try {
        parsed = JSON.parse(raw);
      } catch {
        /* use fallback */
      }

      // Normalize: map any alternate field names the AI might use to the standard schema
      const toStr = (v: any, fallback = 'N/A'): string => {
        if (v === undefined || v === null || v === '') return fallback;
        if (typeof v === 'object' && !Array.isArray(v))
          return JSON.stringify(v);
        return String(v);
      };

      return {
        codeQuality: toStr(
          parsed.codeQuality ??
            parsed.quality ??
            parsed.readableCode ??
            parsed.code_quality ??
            parsed.style,
          'Good',
        ),
        timeComplexity: toStr(
          parsed.timeComplexity ??
            parsed.complexity ??
            parsed.time_complexity ??
            parsed.complexityScore ??
            'O(n)',
        ),
        qualityScore: (() => {
          const val =
            parsed.qualityScore ??
            parsed.score ??
            parsed.codeReviewIndex ??
            parsed.maintainabilityIndex ??
            parsed.quality;
          const num = parseInt(String(val), 10);
          if (!isNaN(num)) return Math.min(40, Math.max(0, num));
          // Fallback: -1 signals unknown (parallel call) — gradeWithFeedback will clamp it
          return testsTotal === -1 ? -1 : testsPassed === testsTotal ? 35 : 20;
        })(),
        overallComment: toStr(
          parsed.overallComment ??
            parsed.comment ??
            parsed.feedback ??
            parsed.overall ??
            parsed.review,
          'Code looks good.',
        ),
        suggestions: Array.isArray(parsed.suggestions)
          ? parsed.suggestions.map((s) => toStr(s)).filter((s) => s !== 'N/A')
          : parsed.suggestions
            ? [toStr(parsed.suggestions)]
            : [],
      };
    } catch (err) {
      this.logger.error('AI grading failed:', err);
      return {
        codeQuality: 'Analysis Unavailable',
        timeComplexity: 'O(n) Estimated',
        qualityScore: testsPassed === testsTotal ? 35 : 20,
        suggestions: ['Review your logic for any edge cases.'],
        overallComment:
          'Automated test cases passed. Code quality analysis fell back to default.',
      };
    }
  }
}

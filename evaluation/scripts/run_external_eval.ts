import * as fs from 'fs';
import * as path from 'path';
import { execSync } from 'child_process';
import dotenv from 'dotenv';
import OpenAI from 'openai';

// Load .env from root workspace directory
const rootDir = path.resolve(__dirname, '../../..');
const envPath = path.join(rootDir, '.env');
dotenv.config({ path: envPath });

const instructionPath = path.join(rootDir, 'task', 'instruction.md');
const instructionText = fs.readFileSync(instructionPath, 'utf-8');

const promptText = `You are an AI coding agent being evaluated on a repository-level software engineering benchmark.
Read the problem specification below carefully and implement the complete solution as a production-quality Node.js / TypeScript repository.

IMPORTANT OUTPUT FORMAT INSTRUCTIONS:
Provide all necessary project files (including package.json, tsconfig.json, source files).
Format each file inside a markdown code block with the relative file path specified on the first line or block header, for example:

\`\`\`typescript src/cli.ts
// file content here
\`\`\`

\`\`\`json package.json
// package.json content here
\`\`\`

Do not leave any placeholder or incomplete code. Make sure the code compiles with \`npx tsc\` and provides the required CLI interface.

--- BEGIN SPECIFICATION ---
${instructionText}
--- END SPECIFICATION ---`;

interface ModelRunResult {
  model: string;
  modelId: string;
  status: string;
  buildStatus: 'SUCCESS' | 'BUILD_FAILED' | 'API_ERROR';
  score: number;
  apiError?: string;
  rawOutput?: string;
  buildError?: string;
  verifierResults?: any[];
}

function parseAndExtractFiles(responseText: string, outputDir: string): boolean {
  if (fs.existsSync(outputDir)) {
    fs.rmSync(outputDir, { recursive: true, force: true });
  }
  fs.mkdirSync(outputDir, { recursive: true });

  const codeBlockRegex = /```(?:[a-zA-Z0-9_-]+)?(?:\s+([^\n]+))?\n([\s\S]*?)```/g;
  let match;
  let fileCount = 0;

  while ((match = codeBlockRegex.exec(responseText)) !== null) {
    let headerLine = (match[1] || '').trim();
    let content = match[2];

    let filePath: string | null = null;
    if (headerLine && !headerLine.includes(' ') && (headerLine.includes('.') || headerLine.includes('/'))) {
      filePath = headerLine;
    } else {
      // Check first line of content for file path comment like // path/to/file.ts or // file: path/to/file.ts
      const firstLine = content.split('\n')[0].trim();
      const fileCommentMatch = firstLine.match(/\/\/\s*(?:file:)?\s*([a-zA-Z0-9_\-\.\/]+)/i) ||
                                firstLine.match(/\/\*\s*(?:file:)?\s*([a-zA-Z0-9_\-\.\/]+)/i);
      if (fileCommentMatch) {
        filePath = fileCommentMatch[1].trim();
      }
    }

    if (!filePath) {
      if (content.includes('"name":') && content.includes('"dependencies":')) {
        filePath = 'package.json';
      } else if (content.includes('"compilerOptions":')) {
        filePath = 'tsconfig.json';
      } else if (content.includes('program') && content.includes('commander')) {
        filePath = 'src/cli.ts';
      }
    }

    if (filePath) {
      const fullPath = path.join(outputDir, filePath);
      const dir = path.dirname(fullPath);
      if (!fs.existsSync(dir)) {
        fs.mkdirSync(dir, { recursive: true });
      }
      fs.writeFileSync(fullPath, content, 'utf-8');
      fileCount++;
    }
  }

  return fileCount > 0;
}

function getOpenRouterClient(): OpenAI {
  const apiKey = process.env.AGENT_ROUTER_API_KEY || process.env.OPENAI_API_KEY || process.env.ANTHROPIC_API_KEY;
  if (!apiKey) {
    throw new Error('API key missing in .env');
  }
  return new OpenAI({
    apiKey,
    baseURL: 'https://openrouter.ai/api/v1'
  });
}

async function runModelEval(modelName: string, modelId: string, modelKey: string): Promise<ModelRunResult> {
  console.log(`\n--> Sending request to model ${modelId} (${modelName})...`);

  try {
    const client = getOpenRouterClient();
    const response = await client.chat.completions.create({
      model: modelId,
      messages: [
        { role: 'user', content: promptText }
      ]
    });

    const responseText = response.choices[0]?.message?.content || '';
    if (!responseText) {
      return {
        model: modelName,
        modelId,
        status: 'API_ERROR',
        buildStatus: 'API_ERROR',
        score: 0.0,
        apiError: 'Model returned empty response text.'
      };
    }

    console.log(`Received response from ${modelId} (${responseText.length} chars). Extracting and evaluating...`);
    return evaluateModelOutput(modelName, modelId, modelKey, responseText);
  } catch (err: any) {
    console.error(`API Error for ${modelId}:`, err.message || err);
    return {
      model: modelName,
      modelId,
      status: 'API_ERROR',
      buildStatus: 'API_ERROR',
      score: 0.0,
      apiError: err.message || String(err)
    };
  }
}

function evaluateModelOutput(modelName: string, modelId: string, modelKey: string, responseText: string): ModelRunResult {
  const tempDir = path.join(rootDir, 'temp_model_run', modelKey);
  const extracted = parseAndExtractFiles(responseText, tempDir);

  if (!extracted) {
    console.log(`Extraction failed for ${modelName}: no files parsed.`);
    return {
      model: modelName,
      modelId,
      status: 'BUILD_FAILED',
      buildStatus: 'BUILD_FAILED',
      score: 0.0,
      rawOutput: responseText,
      buildError: 'Failed to extract valid code files from model response.'
    };
  }

  // Attempt npm install and npm run build
  try {
    console.log(`Building extracted code for ${modelName} in ${tempDir}...`);
    execSync('npm install --silent', { cwd: tempDir, stdio: 'ignore' });
    execSync('npm run build', { cwd: tempDir, stdio: 'ignore' });
  } catch (buildErr: any) {
    console.log(`Build failed for ${modelName}:`, buildErr.message);
    return {
      model: modelName,
      modelId,
      status: 'BUILD_FAILED',
      buildStatus: 'BUILD_FAILED',
      score: 0.0,
      rawOutput: responseText,
      buildError: buildErr.message || 'npm run build failed'
    };
  }

  // Find compiled entrypoint
  const possibleEntrypoints = [
    path.join(tempDir, 'dist', 'cli.js'),
    path.join(tempDir, 'dist', 'src', 'cli.js'),
    path.join(tempDir, 'dist', 'index.js'),
    path.join(tempDir, 'cli.js')
  ];
  let entrypoint = possibleEntrypoints.find(p => fs.existsSync(p));

  if (!entrypoint) {
    console.log(`Entrypoint dist/cli.js missing for ${modelName}.`);
    return {
      model: modelName,
      modelId,
      status: 'BUILD_FAILED',
      buildStatus: 'BUILD_FAILED',
      score: 0.0,
      rawOutput: responseText,
      buildError: 'Compiled entrypoint (dist/cli.js) not found.'
    };
  }

  // Run verifier suite against compiled CLI
  const { runEvaluation } = require('../src/test_runner');
  const evalResult = runEvaluation(entrypoint);

  console.log(`Evaluation score for ${modelName}: ${evalResult.score}`);

  return {
    model: modelName,
    modelId,
    status: 'COMPLETED',
    buildStatus: 'SUCCESS',
    score: evalResult.score,
    rawOutput: responseText,
    verifierResults: evalResult.results
  };
}

async function main() {
  console.log('=== STARTING EXTERNAL MODEL EVALUATION HARNESS ===');

  const claudeResult = await runModelEval(
    'Claude Opus 5 (medium reasoning)',
    'anthropic/claude-opus-5',
    'claude'
  );
  console.log(`\nClaude Opus 5 Final Result: status=${claudeResult.status}, build=${claudeResult.buildStatus}, score=${claudeResult.score}`);

  const gptResult = await runModelEval(
    'GPT-5.6-sol (medium reasoning)',
    'openai/gpt-5.6-sol',
    'gpt'
  );
  console.log(`\nGPT-5.6-sol Final Result: status=${gptResult.status}, build=${gptResult.buildStatus}, score=${gptResult.score}`);

  // Record logs in proof-of-work
  const powDir = path.join(rootDir, 'evaluation', 'proof-of-work');
  if (!fs.existsSync(powDir)) {
    fs.mkdirSync(powDir, { recursive: true });
  }

  fs.writeFileSync(
    path.join(powDir, 'claude_opus_5_eval.json'),
    JSON.stringify(claudeResult, null, 2),
    'utf-8'
  );

  fs.writeFileSync(
    path.join(powDir, 'gpt_5.6_sol_eval.json'),
    JSON.stringify(gptResult, null, 2),
    'utf-8'
  );

  // Update README table
  const readmePath = path.join(powDir, 'README.md');
  const readmeContent = `# Proof-of-Work: AI Model Evaluation Guide & Execution Logs

This directory stores proof-of-work validation artifacts for the **Distributed Job Scheduler** RL Gym benchmark task.

---

## 📁 Directory Files

- \`reference_solution_score.json\`: Empirical verifier run log of the reference solution (Score: 1.00 / 100%).
- \`claude_opus_5_eval.json\`: Empirical evaluation run log for Claude Opus 5 (anthropic/claude-opus-5).
- \`gpt_5.6_sol_eval.json\`: Empirical evaluation run log for GPT-5.6-sol (openai/gpt-5.6-sol).
- \`README.md\`: Evaluation protocol, prompt template, scoring procedure, and model benchmark status table.

---

## 📊 Model Evaluation Summary Table

| Model | Model ID | Single-Pass Attempts | Build Status | Verifier Score | Difficulty Bar (< 30%) | Status |
| :--- | :--- | :---: | :---: | :---: | :---: | :--- |
| **Reference Solution** | \`reference/\` | N/A | \`SUCCESS\` | **1.00 (100%)** | N/A | **VERIFIED** |
| **Claude Opus 5 (medium reasoning)** | \`anthropic/claude-opus-5\` | 1 | \`${claudeResult.buildStatus}\` | **${claudeResult.score}** | Target: < 0.30 | **${claudeResult.status}** |
| **GPT-5.6-sol (medium reasoning)** | \`openai/gpt-5.6-sol\` | 1 | \`${gptResult.buildStatus}\` | **${gptResult.score}** | Target: < 0.30 | **${gptResult.status}** |

---

## 🎯 Benchmark Summary

- **Claude Opus 5**: Score = **${claudeResult.score}** (${claudeResult.score < 0.30 ? 'Passes difficulty bar < 30%' : 'Requires task hardening'})
- **GPT-5.6-sol**: Score = **${gptResult.score}** (${gptResult.score < 0.30 ? 'Passes difficulty bar < 30%' : 'Requires task hardening'})
`;
  fs.writeFileSync(readmePath, readmeContent, 'utf-8');

  console.log('\n=== EVALUATION FINISHED ===');
}

main().catch(err => {
  console.error('Fatal error in evaluation harness:', err);
  process.exit(1);
});

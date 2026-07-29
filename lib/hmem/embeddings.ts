import { pipeline, type Pipeline } from "@xenova/transformers";

// all-MiniLM-L6-v2 outputs 384-dim embeddings — matches the `vector(384)`
// columns in db/schema.sql. Loaded once per server process (lazy singleton),
// not per request: cold-start/model-load latency is real and shouldn't
// happen on every turn.
let extractorPromise: Promise<Pipeline> | null = null;

function getExtractor(): Promise<Pipeline> {
  if (!extractorPromise) {
    extractorPromise = pipeline(
      "feature-extraction",
      "Xenova/all-MiniLM-L6-v2"
    ) as Promise<Pipeline>;
  }
  return extractorPromise;
}

export async function embed(text: string): Promise<number[]> {
  const extractor = await getExtractor();
  const output = await extractor(text, { pooling: "mean", normalize: true });
  return Array.from(output.data as Float32Array);
}

export function cosineSimilarity(a: number[], b: number[]): number {
  let dot = 0;
  let normA = 0;
  let normB = 0;
  for (let i = 0; i < a.length; i++) {
    dot += a[i] * b[i];
    normA += a[i] * a[i];
    normB += b[i] * b[i];
  }
  if (normA === 0 || normB === 0) return 0;
  return dot / (Math.sqrt(normA) * Math.sqrt(normB));
}

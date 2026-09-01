# EIP-RAG

A RAG pipeline over Ethereum EIP/ERC specifications, in TypeScript.

Stages are separate and independently runnable: the loader reads disk, the chunker
is a pure function. Loader (done), chunker (done), embeddings / vector store /
retrieval (not built).

## Setup

```bash
npm install     # Node 18+
```

## Usage

```bash
npm run inspect                   # list loaded documents
npm run inspect -- erc-20         # one document in full (--body for entire text)

npm run chunk                     # chunk all documents -> data/chunks.json
npm run chunk -- --size=500 --overlap=50
npm run chunk -- --dry            # print summary, write nothing
npm run chunk -- --out=path.json

npm run build                     # type-check and compile to dist/
```

`--` is required so npm passes flags through to the script.

## Pipeline

```
data/EIPs/*.md  ->  Document[]  ->  Chunk[]  ->  (embeddings, vector store, retrieval)
                     loader        chunker
```

```
data/EIPs/        source markdown (committed)
data/chunks.json  generated output (gitignored)
src/loader/       types.ts, loadDocuments.ts, index.ts
src/chunker/      types.ts, chunkDocument.ts, index.ts
src/inspect.ts    dev script: view documents
src/chunk.ts      dev script: run chunking
```

## Loader

```ts
import { loadDocuments } from "./src/loader/index.js";
const { documents, errors } = await loadDocuments();   // default: data/EIPs
```

```ts
interface Document {
  id: string;               // sha256(relativePath).slice(0, 16)
  content: string;          // markdown body, verbatim, frontmatter removed
  frontmatter: Frontmatter; // parsed YAML; {} when absent
  source: DocumentSource;   // filePath, relativePath, fileName, bytes, modifiedAt
  contentHash: string;      // sha256 of the raw file
}
```

A file that fails to parse lands in `errors` and the rest still load. A missing
directory throws — a typo'd path should fail loudly, not return an empty result.

## Chunker

```ts
import { chunkDocuments } from "./src/chunker/index.js";
const chunks = chunkDocuments(documents, { chunkSize: 1000, chunkOverlap: 150 });
```

```ts
interface Chunk {
  id: string;          // `${documentId}:${index}`
  documentId: string;
  text: string;        // verbatim slice of Document.content
  index: number;
  eip?: number;        // from frontmatter
  title?: string;      // from frontmatter
  section?: string;    // nearest markdown heading above this text
  charStart: number;   // content.slice(charStart, charEnd) === text
  charEnd: number;
  source: DocumentSource;
}
```

Splits on markdown headings first, then into fixed-size windows within each section,
so a chunk never straddles two sections. Overlap repeats the tail of one chunk at the
head of the next.

Defaults are 1000/150 characters. Smaller chunks match more precisely but can lose the
context needed to interpret them; larger chunks read better but dilute the embedding.
EIPs are dense specs where a sentence often depends on a definition just above it, so
the default sits at the larger end.

## Design notes

**`id` is path-derived, `contentHash` is content-derived.** `id` is stable across
machines and unchanged by edits; `contentHash` changes on every edit. That pair makes
incremental re-indexing possible: same `id` + new `contentHash` means re-embed, new
`id` means a new document. A content-derived `id` would make an edit look like a new
document.

**Headings inside code fences are ignored.** `erc-55.md` contains `# All caps` inside a
fenced block. A plain `/^#+\s/` regex treats it as a heading and splits the code block
in half, yielding 8 chunks with three garbage ones instead of 5 clean ones. The splitter
tracks fence state. This affects any corpus with shell, Python, or YAML samples.

**Provenance is copied onto every chunk.** After chunking, nothing in the text says
where it came from, and it is not recoverable later. `documentId` + `source` are what
make citation, per-document deletes from a vector store, and debugging possible.

**Offsets round-trip.** `content.slice(charStart, charEnd) === text` holds for all 428
chunks, which is only true because the loader preserves the body byte-for-byte. Worth
re-checking after any splitter change.

## Limitations

- Chunk text is body prose only, so its embedding carries no title or section context.
  Prepending it belongs in the embedding stage, where it is an explicit choice; the
  metadata is already on the chunk.
- Windows cut mid-sentence. The usual upgrade is recursive splitting: prefer `\n\n`,
  then `\n`, then `. `, then hard-cut.
- The loader reads one flat directory. Nested dirs need `{ recursive: true }` in
  `findMarkdownFiles`; `relativePath` already handles nesting, so ids stay stable.
- Chunk size counts characters, not tokens. The two diverge on code-heavy passages.
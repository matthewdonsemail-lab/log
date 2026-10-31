---
title: Quickstart
description: Send your first SubQ Decisions API request.
---

> Status: Public preview

Make your first API request in minutes.

## 1. Get your API key

Sign up at [console.subq.ai](https://console.subq.ai) and create an API key from
the dashboard. Store it in an environment variable:

```bash
export SUBQ_API_KEY="sk-your-api-key"
```

## 2. Check account access

Make sure your account has credits before sending requests. A request without
available credits returns `402`.

## 3. Send a request

This request asks `subq-snap-preview`, in public preview, one yes/no question
about a patient message. See [Models](/using-the-api/models/).

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/systemone \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-snap-preview",
  "state": "Patient with asthma reports a sore throat, fever since yesterday, and shortness of breath walking to the kitchen this morning.",
  "questions": {
    "escalate": {
      "type": "noul",
      "instructions": "Should a nurse see this chat before the patient books anything?",
      "criteria": {
        "true": "Breathing trouble, chest pain, or a flare of a known condition",
        "false": "Stable symptoms the patient can book for themselves"
      }
    }
  }
}
'
```

```ts title="TypeScript"
const baseURL = "https://api.subq.ai/v1";

const response = await fetch(`${baseURL}/systemone`, {
  method: "POST",
  headers: {
    Authorization: `Bearer ${process.env.SUBQ_API_KEY}`,
    "Content-Type": "application/json",
  },
  body: JSON.stringify({
    model: "subq-snap-preview",
    state:
      "Patient with asthma reports a sore throat, fever since yesterday, and shortness of breath walking to the kitchen this morning.",
    questions: {
      escalate: {
        type: "noul",
        instructions: "Should a nurse see this chat before the patient books anything?",
        criteria: {
          true: "Breathing trouble, chest pain, or a flare of a known condition",
          false: "Stable symptoms the patient can book for themselves",
        },
      },
    },
  }),
});

if (!response.ok) {
  const error = await response.json();
  throw new Error(
    `${response.status} ${error.detail.error_type}: ${error.detail.message}`,
  );
}

const result = await response.json();
console.log(`Escalate: ${result.answers.escalate.noul.toFixed(2)}`);
```

```py title="Python"
import json
import os
import urllib.error
import urllib.request

base_url = "https://api.subq.ai/v1"

request = urllib.request.Request(
    f"{base_url}/systemone",
    method="POST",
    headers={
        "Authorization": f"Bearer {os.environ['SUBQ_API_KEY']}",
        "Content-Type": "application/json",
    },
    data=json.dumps(
        {
            "model": "subq-snap-preview",
            "state": (
                "Patient with asthma reports a sore throat, fever since "
                "yesterday, and shortness of breath walking to the kitchen "
                "this morning."
            ),
            "questions": {
                "escalate": {
                    "type": "noul",
                    "instructions": (
                        "Should a nurse see this chat before the patient "
                        "books anything?"
                    ),
                    "criteria": {
                        "true": (
                            "Breathing trouble, chest pain, or a flare of a "
                            "known condition"
                        ),
                        "false": (
                            "Stable symptoms the patient can book for "
                            "themselves"
                        ),
                    },
                },
            },
        }
    ).encode(),
)

try:
    with urllib.request.urlopen(request, timeout=60) as response:
        result = json.load(response)
except urllib.error.HTTPError as error:
    detail = json.load(error)["detail"]
    raise RuntimeError(
        f"{error.code} {detail['error_type']}: {detail['message']}"
    ) from error

print(f"Escalate: {result['answers']['escalate']['noul']:.2f}")
```

The answer is in `answers.escalate.noul`, the probability of yes from `0` to
`1`. See the [Decisions API](/endpoints/decisions-api/) for choice and score
questions, images, and errors.

---
title: API overview
description: How SubQ's OpenAI-compatible API fits into a developer integration.
---

SubQ provides three inference endpoints: [Decisions](/endpoints/decisions-api/),
[Chat Completions](/endpoints/chat-completions-api/), and
[Responses](/endpoints/responses-api/), plus resources for managing
[conversations](/endpoints/conversations-api/), [files](/endpoints/files-api/),
and [models](/endpoints/models-api/). Chat Completions and Responses are
OpenAI-compatible. Decisions has a separate, typed JSON contract.

SubQ is in preview. Model availability and capabilities may change; feature support varies by model. See [Models](/using-the-api/models/) for details.

## Request flow

1. Create an account at [console.subq.ai](https://console.subq.ai)
2. Generate an API key from the console
3. Set the SubQ base URL in your HTTP client or OpenAI SDK
4. Choose an endpoint and send a request using a [SubQ model](/using-the-api/models/).
5. Enable streaming on Chat Completions or Responses when your product needs tokens as they are generated

## Base URL

Send API requests to:

```
https://api.subq.ai/v1
```

Treat each endpoint page as the contract for its supported models, fields, and
response formats.

## Endpoints

| Endpoint                                             | Method                    | Path                   | Use it to                                                                                                                               |
| ---------------------------------------------------- | ------------------------- | ---------------------- | --------------------------------------------------------------------------------------------------------------------------------------- |
| [Models](/endpoints/models-api/)                     | `GET`                     | `/v1/models`           | List the model IDs available to your API key at runtime.                                                                                |
| [Decisions](/endpoints/decisions-api/)               | `POST`                    | `/v1/systemone`        | Return typed yes/no, choice, and score decisions about text or images, with probabilities and confidence.                               |
| [Responses](/endpoints/responses-api/)               | `POST`                    | `/v1/responses`        | Run multi-turn and long-context workflows with `instructions`, built-in web search, and server-side history via `previous_response_id`. |
| [Chat Completions](/endpoints/chat-completions-api/) | `POST`                    | `/v1/chat/completions` | Generate text from `messages`, statelessly. The drop-in path for OpenAI migrations.                                                     |
| [Files](/endpoints/files-api/)                       | `POST` / `GET` / `DELETE` | `/v1/files`            | Upload documents once and reference them by `file_id` in Chat Completions or Responses.                                                 |
| [Conversations](/endpoints/conversations-api/)       | `POST` / `GET` / `DELETE` | `/v1/conversations`    | Create, inspect, retag, and delete a conversation's history, independent of any single turn.                                            |

## Next steps

- Use the [Quickstart](/) to verify your API key.
- Read [Authentication](/using-the-api/authentication/) before wiring credentials into an app.
- Review SubQ capabilities in [Models](/using-the-api/models/).
- Return typed decisions with the [Decisions API](/endpoints/decisions-api/).
- Put documents in a prompt with [Sending files](/using-the-api/file-inputs/).
- Return schema-constrained JSON with [Structured outputs](/using-the-api/structured-outputs/).
- Connect models to your app with [Function calling](/using-the-api/function-calling/).
- Check [Data retention](/using-the-api/data-retention/) for how long SubQ stores your prompts and completions.

---
title: Authentication
description: Authenticate SubQ API requests with bearer tokens.
---

Every API request requires an API key in the `Authorization` header using the
Bearer scheme.

## Create an API key

Generate a key from [console.subq.ai](https://console.subq.ai), store it outside
your source tree, and send it with each request. Listing
[models](/endpoints/models-api/) is a quick way to check a key:

```bash title="cURL"
curl --request GET \
  --url https://api.subq.ai/v1/models \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const models = await client.models.list();
console.log(models.data.map((model) => model.id));
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

models = client.models.list()
print([model.id for model in models.data])
```

## Use environment variables

Set the key in your local shell or deployment environment:

```bash
export SUBQ_API_KEY="sk-your-api-key"
```

Then read `SUBQ_API_KEY` from your application configuration and pass it to your
HTTP client or OpenAI SDK.

## Key security

- **Store securely.** Keys are shown once at creation and cannot be retrieved later.
- **Rotate regularly.** Create new keys and revoke old ones from the console.
- **Never commit to source control.** Use environment variables or a secrets manager.

---
title: Data retention
description: How long SubQ stores prompts, completions, and conversation history.
---

Each organization has one data-retention policy. It sets how long SubQ keeps
your prompts, completions, and conversation history.

- **Retain indefinitely (default)** — kept until you delete it.
- **Delete after *N* days** — deleted after *N* days; a `previous_response_id` older than that returns `404`.
- **Zero data retention** — nothing is stored.

SubQ always records model, token counts, timing, and your
[`metadata`](/endpoints/chat-completions-api/#metadata) tags for billing and
support. That record never includes prompts or completions.

## Zero data retention

Requests work as usual, but nothing is stored afterward. To enable it for your
organization, [submit a ZDR request](https://share-na2.hsforms.com/1ikOZ84D1RACcMJlibb1z9w418zam).

| Endpoint                                             | Behavior                                                                                                            |
| ---------------------------------------------------- | ------------------------------------------------------------------------------------------------------------------- |
| [Chat Completions](/endpoints/chat-completions-api/) | Works as usual. Nothing is stored.                                                                                  |
| [Responses](/endpoints/responses-api/)               | Works, but turns aren't saved. Send the full context in `input` on every request instead of `previous_response_id`. |
| [Conversations](/endpoints/conversations-api/)       | Unavailable (`403` `zero_data_retention`).                                                                          |
| [Decisions](/endpoints/decisions-api/)               | Works as usual. Nothing is stored.                                                                                  |
| Inline PDFs (`file_data`)                            | Rejected (`400` `document_source_unsupported`). Upload the file and pass [`file_id`](/using-the-api/file-inputs/).  |

## Opting out per request

To keep a single request out of storage, send `store: false` on
[Chat Completions](/endpoints/chat-completions-api/#storage) or
[Responses](/endpoints/responses-api/#storage).

---
title: Models
description: Supported SubQ model IDs and what each one accepts.
---

Pass the model ID in the `model` field. IDs are case-sensitive. To list the IDs
available to your API key, use the [Models API](/endpoints/models-api/).

## SubQ Snap Preview

Use this model to generate fast, structured decisions.

- Model ID: `subq-snap-preview`
- Status: Public preview
- Endpoint: [Decisions](/endpoints/decisions-api/)
- Modalities: Text (input and output), Image (input only)
- Features: [Images](/endpoints/decisions-api/#images)
- Pricing: Input ($0.05 / 1M tokens), Output (Free)

## SubQ Preview

Use this model for long-context chat.

- Model ID: `subq-preview`
- Status: Early access
- Endpoint: [Chat Completions](/endpoints/chat-completions-api/), [Responses](/endpoints/responses-api/)
- Modalities: Text (input and output)
- Features: [Files](/using-the-api/file-inputs/), [Function calling](/using-the-api/function-calling/)

---
title: Decisions API
description: Turn text or structured state into typed decisions with probabilities and confidence.
---

> Status: Public preview

Use the Decisions API for fast, structured judgments rather than generated
text. It evaluates a `state` and optional images, then returns typed answers and
probabilities your code can use directly.

`subq-snap-preview` is a System One model built for routing, guardrails, triage,
and other fast decisions.

```text
POST /v1/systemone
```

## Make a decision

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/systemone \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data @- <<'EOF'
{
  "model": "subq-snap-preview",
  "state": "Patient with asthma reports a sore throat, fever since yesterday, and shortness of breath walking to the kitchen this morning.",
  "questions": {
    "escalate": {
      "type": "noul",
      "instructions": "Should a nurse see this chat before the patient books anything?",
      "criteria": {
        "true": "Breathing trouble, chest pain, or a flare of a known condition",
        "false": "Stable symptoms the patient can book for themselves"
      }
    },
    "queue": {
      "type": "choice",
      "instructions": "Which team should own this chat?",
      "criteria": {
        "nurse_line": "Needs a nurse to assess symptoms today",
        "primary_care": "Book with the patient's own doctor",
        "pharmacy": "Refill or medication question only",
        "front_desk": null
      }
    },
    "acuity": {
      "type": "score",
      "instructions": "How soon should someone respond?",
      "criteria": [
        "Within a week",
        "Within a day",
        "Within an hour"
      ]
    }
  }
}
EOF
```

```ts title="TypeScript"
const baseURL = "https://api.subq.ai/v1";

// The text to judge.
const state =
  "Patient with asthma reports a sore throat, fever since yesterday, and shortness of breath walking to the kitchen this morning.";

// One question per judgment: a yes/no gate, an owning team, a response time.
const questions = {
  escalate: {
    type: "noul",
    instructions: "Should a nurse see this chat before the patient books anything?",
    criteria: {
      true: "Breathing trouble, chest pain, or a flare of a known condition",
      false: "Stable symptoms the patient can book for themselves",
    },
  },
  queue: {
    type: "choice",
    instructions: "Which team should own this chat?",
    criteria: {
      nurse_line: "Needs a nurse to assess symptoms today",
      primary_care: "Book with the patient's own doctor",
      pharmacy: "Refill or medication question only",
      front_desk: null,
    },
  },
  acuity: {
    type: "score",
    instructions: "How soon should someone respond?",
    criteria: ["Within a week", "Within a day", "Within an hour"],
  },
};

const response = await fetch(`${baseURL}/systemone`, {
  method: "POST",
  headers: {
    Authorization: `Bearer ${process.env.SUBQ_API_KEY}`,
    "Content-Type": "application/json",
  },
  body: JSON.stringify({
    model: "subq-snap-preview",
    state,
    questions,
  }),
});

if (!response.ok) {
  const error = await response.json();
  throw new Error(
    `${response.status} ${error.detail.error_type}: ${error.detail.message}`,
  );
}

const result = await response.json();
const { escalate, queue, acuity } = result.answers;

// Your code decides what happens next. Unsure routing goes to a nurse,
// and so does anything the gate says needs one.
let owner = queue.confidence >= 0.6 ? queue.choice : "nurse_line";
if (escalate.noul >= 0.5) owner = "nurse_line";

const respondWithin = acuity.legend[String(Math.round(acuity.score))];

console.log(`Escalate: ${escalate.noul.toFixed(2)}`);
console.log(
  `Owner:    ${owner} (model picked ${queue.choice}, confidence ${queue.confidence.toFixed(2)})`,
);
console.log(`Respond:  ${respondWithin}`);
```

```py title="Python"
import json
import os
import urllib.error
import urllib.request

base_url = "https://api.subq.ai/v1"

# The text to judge.
state = (
    "Patient with asthma reports a sore throat, fever since yesterday, and "
    "shortness of breath walking to the kitchen this morning."
)

# One question per judgment: a yes/no gate, an owning team, a response time.
questions = {
    "escalate": {
        "type": "noul",
        "instructions": (
            "Should a nurse see this chat before the patient books anything?"
        ),
        "criteria": {
            "true": (
                "Breathing trouble, chest pain, or a flare of a known condition"
            ),
            "false": "Stable symptoms the patient can book for themselves",
        },
    },
    "queue": {
        "type": "choice",
        "instructions": "Which team should own this chat?",
        "criteria": {
            "nurse_line": "Needs a nurse to assess symptoms today",
            "primary_care": "Book with the patient's own doctor",
            "pharmacy": "Refill or medication question only",
            "front_desk": None,
        },
    },
    "acuity": {
        "type": "score",
        "instructions": "How soon should someone respond?",
        "criteria": ["Within a week", "Within a day", "Within an hour"],
    },
}

request = urllib.request.Request(
    f"{base_url}/systemone",
    method="POST",
    headers={
        "Authorization": f"Bearer {os.environ['SUBQ_API_KEY']}",
        "Content-Type": "application/json",
    },
    data=json.dumps(
        {
            "model": "subq-snap-preview",
            "state": state,
            "questions": questions,
        }
    ).encode(),
)

try:
    with urllib.request.urlopen(request, timeout=60) as response:
        result = json.load(response)
except urllib.error.HTTPError as error:
    detail = json.load(error)["detail"]
    raise RuntimeError(
        f"{error.code} {detail['error_type']}: {detail['message']}"
    ) from error

answers = result["answers"]
escalate = answers["escalate"]["noul"]
queue = answers["queue"]
acuity = answers["acuity"]

# Your code decides what happens next. Unsure routing goes to a nurse,
# and so does anything the gate says needs one.
owner = queue["choice"] if queue["confidence"] >= 0.6 else "nurse_line"
if escalate >= 0.5:
    owner = "nurse_line"

respond_within = acuity["legend"][str(round(acuity["score"]))]

print(f"Escalate: {escalate:.2f}")
print(
    f"Owner:    {owner} "
    f"(model picked {queue['choice']}, confidence {queue['confidence']:.2f})"
)
print(f"Respond:  {respond_within}")
```

### Building reliable decision workflows

Keep your code in charge. Rules you can write down belong in code. Ask the
model only for the judgment code can't make, then let code decide what happens
next.

- **One judgment per question.** Split a broad question into narrow ones, like
  the gate, owner, and deadline above. Code then combines the answers.
- **Ask related questions together.** Questions about the same `state` go in
  one request, so the state is sent once.
- **Send only what the decision needs.** Trim `state` to the relevant fields,
  and name the field an instruction is about.
- **Set thresholds from your own data.** Run the questions over cases you've
  already labeled and choose cutoffs from the results.
- **Send uncertain or high-impact cases to a person.** Outputs can vary between
  requests, so route low `confidence`, a noul near `0.5`, or a costly mistake
  to review.
- **Retry `429` and `5xx` with backoff.** Fix a `400` or `422` before resending;
  a retry won't change it.

## Request

The JSON body requires:

- `model` — use `subq-snap-preview`.
- `state` — the text, object, or array to evaluate.
- `questions` — 1–16 named noul, choice, or score questions. Each uses
  `instructions` and type-specific `criteria`, which can contain strings,
  objects, or arrays. Answer keys match the question names, which can be up to
  100 characters.

The request must fit the model's 384K-token (393,216) context window. A request
over the limit, or close to it, fails with `400`.

Optional:

- `images` — up to 4 images to evaluate alongside `state`. See
  [Images](#images).

### Noul

A noul is a yes/no gate. Its answer is `noul`, the probability of yes from `0`
to `1`. Optional `criteria.true` and `criteria.false` describe both outcomes.

### Choice

A choice selects one named option. Define 2–255 options in `criteria`; each
option's description may be `null`. The answer includes `choice`, a probability
for every option, and `confidence`.

### Score

A score uses 2–10 ordered levels. The answer includes a probability-weighted
`score`, so it can fall between levels, plus `legend`, `probabilities`, and
`confidence`.

### Images

```json
{
  "images": [
    { "mediaType": "image/jpeg", "base64": "/9j/4AAQSkZJRgABAQAA..." }
  ]
}
```

- `mediaType` — `image/png`, `image/jpeg`, or `image/webp`.
- `base64` — the file bytes as one line of base64, without a `data:` prefix.
  URLs, `data:` URLs, and bare base64 strings fail the request.
- Send up to 4 images. Each image can be up to 4 MiB decoded, with an 8 MiB
  decoded total.
- Each image uses about 64–256 image tokens, not the base64 text. These tokens
  and the request text count toward the model's context window. The request
  body can be up to 13 MiB.
- Video is not supported. Sample up to 4 frames and send them as images.

```ts title="TypeScript"
import { readFileSync } from "node:fs";

const baseURL = "https://api.subq.ai/v1";

// The ticket note. The photo carries the rest: which device, and what shape it is.
const state = "The number row stopped working.";

// Plain base64 of the file bytes. No data: URL prefix.
// PNG, JPEG, or WebP, at most 4 MiB decoded per image.
const photo = readFileSync("./keyboard.jpg").toString("base64");

// One question per judgment. Every question sees the note and every image.
const questions = {
  shows_keyboard: {
    type: "noul",
    instructions: "Does the photo show a keyboard?",
    criteria: {
      true: "A keyboard is the main object",
      false: "No keyboard is visible",
    },
  },
  layout: {
    type: "choice",
    instructions: "Which keyboard layout is in the photo?",
    criteria: {
      full_size: "Desktop keyboard with a numeric keypad",
      tenkeyless: "Desktop keyboard with no numeric keypad",
      laptop: "Built into a laptop",
      not_a_keyboard: null,
    },
  },
  wear: {
    type: "score",
    instructions: "How worn does the keyboard look?",
    criteria: ["Looks new", "Everyday wear", "Replace it"],
  },
};

const response = await fetch(`${baseURL}/systemone`, {
  method: "POST",
  headers: {
    Authorization: `Bearer ${process.env.SUBQ_API_KEY}`,
    "Content-Type": "application/json",
  },
  body: JSON.stringify({
    model: "subq-snap-preview",
    state,
    images: [{ mediaType: "image/jpeg", base64: photo }],
    questions,
  }),
});

if (!response.ok) {
  const error = await response.json();
  throw new Error(
    `${response.status} ${error.detail.error_type}: ${error.detail.message}`,
  );
}

const result = await response.json();
const { shows_keyboard, layout, wear } = result.answers;

// A photo that is not a keyboard, or an unsure layout, goes back to the employee.
if (
  shows_keyboard.noul < 0.5 ||
  layout.confidence < 0.6 ||
  layout.choice === "not_a_keyboard"
) {
  console.log("Ask for a clearer photo of the keyboard.");
} else {
  const condition = wear.legend[String(Math.round(wear.score))];
  console.log(`Keyboard: ${layout.choice} (${condition})`);
}
```

```py title="Python"
import base64
import json
import os
import urllib.error
import urllib.request
from pathlib import Path

base_url = "https://api.subq.ai/v1"

# The ticket note. The photo carries the rest: which device, and what shape it is.
state = "The number row stopped working."

# Plain base64 of the file bytes. No data: URL prefix.
# PNG, JPEG, or WebP, at most 4 MiB decoded per image.
photo = base64.b64encode(Path("./keyboard.jpg").read_bytes()).decode("ascii")

# One question per judgment. Every question sees the note and every image.
questions = {
    "shows_keyboard": {
        "type": "noul",
        "instructions": "Does the photo show a keyboard?",
        "criteria": {
            "true": "A keyboard is the main object",
            "false": "No keyboard is visible",
        },
    },
    "layout": {
        "type": "choice",
        "instructions": "Which keyboard layout is in the photo?",
        "criteria": {
            "full_size": "Desktop keyboard with a numeric keypad",
            "tenkeyless": "Desktop keyboard with no numeric keypad",
            "laptop": "Built into a laptop",
            "not_a_keyboard": None,
        },
    },
    "wear": {
        "type": "score",
        "instructions": "How worn does the keyboard look?",
        "criteria": ["Looks new", "Everyday wear", "Replace it"],
    },
}

request = urllib.request.Request(
    f"{base_url}/systemone",
    method="POST",
    headers={
        "Authorization": f"Bearer {os.environ['SUBQ_API_KEY']}",
        "Content-Type": "application/json",
    },
    data=json.dumps(
        {
            "model": "subq-snap-preview",
            "state": state,
            "images": [{"mediaType": "image/jpeg", "base64": photo}],
            "questions": questions,
        }
    ).encode(),
)

try:
    with urllib.request.urlopen(request, timeout=60) as response:
        result = json.load(response)
except urllib.error.HTTPError as error:
    detail = json.load(error)["detail"]
    raise RuntimeError(
        f"{error.code} {detail['error_type']}: {detail['message']}"
    ) from error

answers = result["answers"]
shows_keyboard = answers["shows_keyboard"]["noul"]
layout = answers["layout"]
wear = answers["wear"]

# A photo that is not a keyboard, or an unsure layout, goes back to the employee.
if (
    shows_keyboard < 0.5
    or layout["confidence"] < 0.6
    or layout["choice"] == "not_a_keyboard"
):
    print("Ask for a clearer photo of the keyboard.")
else:
    condition = wear["legend"][str(round(wear["score"]))]
    print(f"Keyboard: {layout['choice']} ({condition})")
```

### cURL with an image

`openssl base64 -A` writes the file as one line. The heredoc is unquoted so the
shell encodes the file before the request is sent. Shrink the photo first so
the decoded file stays under 4 MiB.

```bash
curl -sS -X POST https://api.subq.ai/v1/systemone \
  -H "Authorization: Bearer $SUBQ_API_KEY" \
  -H "Content-Type: application/json" \
  --data-binary @- <<EOF
{"model":"subq-snap-preview","state":"The number row stopped working.","images":[{"mediaType":"image/jpeg","base64":"$(openssl base64 -A -in keyboard.jpg)"}],"questions":{"shows_keyboard":{"type":"noul","instructions":"Does the photo show a keyboard?","criteria":{"true":"A keyboard is the main object","false":"No keyboard is visible"}},"layout":{"type":"choice","instructions":"Which keyboard layout is in the photo?","criteria":{"full_size":"Desktop keyboard with a numeric keypad","tenkeyless":"Desktop keyboard with no numeric keypad","laptop":"Built into a laptop","not_a_keyboard":null}},"wear":{"type":"score","instructions":"How worn does the keyboard look?","criteria":["Looks new","Everyday wear","Replace it"]}}}
EOF
```

An invalid image fails with `422` `validation_error`. A file over 4 MiB:

```json
{
  "detail": {
    "error_type": "validation_error",
    "message": "images/0: image must not exceed 4 MiB decoded."
  }
}
```

Bytes that do not match `mediaType` fail the same way:
`images/0: image bytes must match the PNG, JPEG, or WebP mediaType.` The same
status covers a URL or `data:` prefix, a bad decode, more than 4 images, or more
than 8 MiB decoded in total.

Stored decisions include their images and follow your
[data-retention policy](/using-the-api/data-retention/).

## Response

```json
{
  "model": "subq-snap-preview",
  "answers": {
    "escalate": {
      "type": "noul",
      "noul": 0.92
    },
    "queue": {
      "type": "choice",
      "choice": "nurse_line",
      "probabilities": {
        "nurse_line": 1,
        "primary_care": 0,
        "pharmacy": 0,
        "front_desk": 0
      },
      "confidence": 1
    },
    "acuity": {
      "type": "score",
      "score": 1.86,
      "legend": {
        "0": "Within a week",
        "1": "Within a day",
        "2": "Within an hour"
      },
      "probabilities": {
        "0": 0,
        "1": 0.13,
        "2": 0.87
      },
      "confidence": 0.79
    }
  },
  "usage": {
    "input_tokens": 477,
    "output_tokens": 0
  }
}
```

You pay only for input tokens; `output_tokens` is always `0`.

## Errors

Errors use a `detail` object:

```json
{
  "detail": {
    "error_type": "validation_error",
    "message": "questions/queue: must have required property 'criteria'"
  }
}
```

- `400` — input over the token limit, or a request the model rejects.
- `401` — missing or invalid credentials.
- `402` — insufficient credits.
- `403` — the API key cannot use the requested model.
- `422` — invalid request (including an invalid or oversized image) or a model
  that is not a decision model.
- `429` — rate limit exceeded.
- `5xx` — server error. `503` means the service is temporarily unavailable.

To extract fields
rather than make a decision, use
[Structured outputs](/using-the-api/structured-outputs/).

---
title: Sending files
description: Send documents inline as base64, or upload once and reference them by file_id on Chat Completions or Responses.
---

> Status: Early access

Upload a file once via the [Files API](/endpoints/files-api/) and reference it by `file_id` on Chat Completions or Responses, or send it inline — base64-encoded directly in the request — on Chat Completions only.

## Field reference

|               | Responses API        | Chat Completions |
| ------------- | -------------------- | ---------------- |
| Part type     | `input_file`         | `file`           |
| Inline base64 | Not supported        | `file_data`      |
| Uploaded file | `file_id` (required) | `file_id`        |

## Inline base64

Inline `file_data` is Chat Completions only. Include a text part with your instruction, then one or more `file` parts for the documents.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": [
        {
          "type": "text",
          "text": "Summarize these documents."
        },
        {
          "type": "file",
          "filename": "financial-report-2026.pdf",
          "mime_type": "application/pdf",
          "file_data": "JVBERi0xLjcKJdDUxdgK..."
        },
        {
          "type": "file",
          "filename": "board-deck-q1.pdf",
          "mime_type": "application/pdf",
          "file_data": "JVBERi0xLjcKJdDUxdgK..."
        },
        {
          "type": "file",
          "filename": "meeting-notes.txt",
          "mime_type": "text/plain",
          "file_data": "U3ViUSBkb2N1bWVudCBub3Rlcy4uLg=="
        }
      ]
    }
  ]
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const financialSummary = Buffer.from("Quarterly revenue was $4.2M.\n").toString(
  "base64",
);
const meetingNotes = Buffer.from(
  "Follow up with legal on the updated MSA template.\n",
).toString("base64");

const completion = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "user",
      content: [
        { type: "text", text: "Summarize these documents." },
        {
          type: "file",
          filename: "financial-summary.txt",
          mime_type: "text/plain",
          file_data: financialSummary,
        },
        {
          type: "file",
          filename: "meeting-notes.txt",
          mime_type: "text/plain",
          file_data: meetingNotes,
        },
      ],
    },
  ],
});

console.log(completion.choices[0].message.content);
```

```py title="Python"
import base64
import os

from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

financial_summary = base64.b64encode(b"Quarterly revenue was $4.2M.\n").decode("ascii")
meeting_notes = base64.b64encode(
    b"Follow up with legal on the updated MSA template.\n"
).decode("ascii")

completion = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "user",
            "content": [
                {"type": "text", "text": "Summarize these documents."},
                {
                    "type": "file",
                    "filename": "financial-summary.txt",
                    "mime_type": "text/plain",
                    "file_data": financial_summary,
                },
                {
                    "type": "file",
                    "filename": "meeting-notes.txt",
                    "mime_type": "text/plain",
                    "file_data": meeting_notes,
                },
            ],
        }
    ],
)

print(completion.choices[0].message.content)
```

Set `file_data` to the base64-encoded file content — plain, with no line wrapping. Do not use a data URL prefix such as `data:application/pdf;base64,`.

### cURL with files

Use `openssl base64 -A` to inline local files without line wrapping. For remote files, download them first (for example with `curl -fsS -o /tmp/report.pdf <url>`), then base64-encode the local file as shown below. Avoid piping a remote download directly into the request body.

```bash
curl -sS -X POST https://api.subq.ai/v1/chat/completions \
  -H "Authorization: Bearer $SUBQ_API_KEY" \
  -H "Content-Type: application/json" \
  --data-binary @- <<EOF
{"model":"subq-preview","messages":[{"role":"user","content":[
{"type":"text","text":"Summarize these documents."},
{"type":"file","filename":"financial-report-2026.pdf","mime_type":"application/pdf","file_data":"$(openssl base64 -A -in /tmp/financial-report-2026.pdf)"},
{"type":"file","filename":"board-deck-q1.pdf","mime_type":"application/pdf","file_data":"$(openssl base64 -A -in /tmp/board-deck-q1.pdf)"},
{"type":"file","filename":"meeting-notes.txt","mime_type":"text/plain","file_data":"$(openssl base64 -A -in /tmp/meeting-notes.txt)"}
]}],"stream":false}
EOF
```

### File part

| Field       | Type   | Required | Description                                                                                                        |
| ----------- | ------ | -------- | ------------------------------------------------------------------------------------------------------------------ |
| `type`      | string | Yes      | Must be `"file"`.                                                                                                  |
| `filename`  | string | No       | Recommended. File name to associate with the document, such as `financial-report-2026.pdf` or `meeting-notes.txt`. |
| `mime_type` | string | Yes      | MIME type for the file, such as `"application/pdf"` or `"text/plain"`.                                             |
| `file_data` | string | Yes      | Base64-encoded file content.                                                                                       |

### Accepted file types

Set `mime_type` to match the file you send.

| Category   | Extensions | MIME type                       |
| ---------- | ---------- | ------------------------------- |
| PDF        | `.pdf`     | `application/pdf`               |
| Plain text | `.txt`     | `text/plain`                    |
| Markdown   | `.md`      | `text/markdown`                 |
| CSV        | `.csv`     | `text/csv`                      |
| TSV        | `.tsv`     | `text/tab-separated-values`     |
| JSON       | `.json`    | `application/json`              |
| XML        | `.xml`     | `application/xml` or `text/xml` |

Word (`.doc`/`.docx`) and JSONL aren't accepted inline — upload them and pass `file_id` instead. See [Files API](/endpoints/files-api/#limits) for the full uploaded-file format list.

## Uploaded files

Upload the document once, then pass the id it returns as `file_id`. Reference more than one document by adding a part per file. Responses uses `input_file` parts; Chat Completions uses `file` parts.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "input": [
    {
      "type": "input_file",
      "file_id": "file_abc123"
    },
    {
      "type": "input_file",
      "file_id": "file_def456"
    },
    {
      "type": "input_text",
      "text": "Summarize these documents."
    }
  ]
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const fileId1 = process.env.SUBQ_FILE_ID ?? "file_abc123";
const fileId2 = process.env.SUBQ_FILE_ID_2 ?? "file_def456";

const response = await client.responses.create({
  model: "subq-preview",
  input: [
    { type: "input_file", file_id: fileId1 },
    { type: "input_file", file_id: fileId2 },
    { type: "input_text", text: "Summarize these documents." },
  ],
});

const message = response.output.find((item) => item.type === "message");
const text = message?.content
  ?.filter((part) => part.type === "output_text")
  .map((part) => part.text)
  .join("");

console.log(text);
```

```py title="Python"
import os

from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

file_id_1 = os.getenv("SUBQ_FILE_ID", "file_abc123")
file_id_2 = os.getenv("SUBQ_FILE_ID_2", "file_def456")

response = client.responses.create(
    model="subq-preview",
    input=[
        {"type": "input_file", "file_id": file_id_1},
        {"type": "input_file", "file_id": file_id_2},
        {"type": "input_text", "text": "Summarize these documents."},
    ],
)

message = next((item for item in response.output if item.type == "message"), None)
text = "".join(
    part.text for part in (message.content if message else []) if part.type == "output_text"
)

print(text)
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": [
        {
          "type": "text",
          "text": "Summarize these documents."
        },
        {
          "type": "file",
          "file_id": "file_abc123"
        },
        {
          "type": "file",
          "file_id": "file_def456"
        }
      ]
    }
  ]
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const fileId1 = process.env.SUBQ_FILE_ID ?? "file_abc123";
const fileId2 = process.env.SUBQ_FILE_ID_2 ?? "file_def456";

const completion = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "user",
      content: [
        { type: "text", text: "Summarize these documents." },
        { type: "file", file_id: fileId1 },
        { type: "file", file_id: fileId2 },
      ],
    },
  ],
});

console.log(completion.choices[0].message.content);
```

```py title="Python"
import os

from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

file_id_1 = os.getenv("SUBQ_FILE_ID", "file_abc123")
file_id_2 = os.getenv("SUBQ_FILE_ID_2", "file_def456")

completion = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "user",
            "content": [
                {"type": "text", "text": "Summarize these documents."},
                {"type": "file", "file_id": file_id_1},
                {"type": "file", "file_id": file_id_2},
            ],
        }
    ],
)

print(completion.choices[0].message.content)
```

Non-text formats need to finish processing first — wait for `status` to reach `processed` before referencing them. See [Files API](/endpoints/files-api/) for upload mechanics, visibility, and the rest of the file lifecycle. Responses does not accept inline `file_data`; see [Responses input](/endpoints/responses-api/#uploaded-files-file_id).

## Choosing an approach

|                  | Inline base64                                      | Uploaded file                           |
| ---------------- | -------------------------------------------------- | --------------------------------------- |
| Sent as          | `file_data` on the request                         | `file_id` from an earlier upload        |
| Extra request    | None                                               | `POST /v1/files` once per file          |
| Reuse            | Re-sends the bytes every time                      | Reference the same `file_id` repeatedly |
| Accepted formats | PDF, plain text, Markdown, CSV, TSV, JSON, and XML | Adds JSONL and Word (`.doc`/`.docx`)    |
| Size             | Bounded by your request size                       | 50 MB per file                          |
| Lifetime         | Request-scoped                                     | Stored per organization until deleted   |

Inline base64 is the shortest path for a one-off Chat Completions request. Upload the file instead when you are calling Responses, when the same document is used across several requests, when it is large, or when it is a format inline input does not accept.

## Response handling

Once a file's `status` is `processed`, its content is available to the model for that request — the reply is ordinary assistant text, the same as any other turn. Combine with [Structured outputs](/using-the-api/structured-outputs/) to extract specific fields from the document instead of a free-text summary.

## Related

- [Files API](/endpoints/files-api/) — upload, list, retrieve, and delete stored files.
- [Chat Completions API](/endpoints/chat-completions-api/) — `file` parts on `messages`.
- [Responses API](/endpoints/responses-api/) — `input_file` parts on `input`.
- [Models](/using-the-api/models/) — supported model IDs.

---
title: Structured outputs
description: Return JSON that matches your schema, from the Responses API or Chat Completions.
---

> Status: Early access

Structured Outputs ensures the model's reply matches your JSON Schema — set
`text.format.type` (Responses) or `response_format.type` (Chat Completions) to
`"json_schema"` and define your schema (`name` and `schema`).

For a yes/no, category, or rating judgment with probabilities, use the
[Decisions API](/endpoints/decisions-api/) instead.

## Field reference

|                 | Responses API                     | Chat Completions                      |
| --------------- | --------------------------------- | ------------------------------------- |
| Enable          | `text.format.type: "json_schema"` | `response_format.type: "json_schema"` |
| Schema name     | `text.format.name`                | `response_format.json_schema.name`    |
| Strict mode     | `text.format.strict`              | `response_format.json_schema.strict`  |
| Schema          | `text.format.schema`              | `response_format.json_schema.schema`  |
| Output location | `output[0].content[0].text`       | `choices[0].message.content`          |

Note the Responses shape is **flattened** — `name`, `strict`, and `schema`
sit directly on `text.format` — while Chat Completions nests them under
`response_format.json_schema`. Both accept the same JSON Schema shape in
`schema`.

### Schema requirements

- Root type must be `object`.
- List every property in `required`.
- Set `additionalProperties: false` on each object.
- Supported types: `string`, `number`, `boolean`, `integer`, `enum`, `array`, nested `object`.

There is no native datetime type—use a `string` field with ISO 8601 in the name or
description (for example, `submit_by`, `detected_at`).

For the full constraint list, see OpenAI's
[supported schemas](https://developers.openai.com/api/docs/guides/structured-outputs#supported-schemas).

## Example

List Nobel Peace Prize winners from 2022 through 2024, classifying each as a
person or an organization.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "instructions": "Return Nobel Peace Prize laureates for only the year range in the user message. One array entry per laureate (shared prizes produce multiple entries with the same year). Set kind to 👤 for a person and 🏛️ for an organization or institution. Use ISO 3166-1 alpha-2 country codes. Keep each motivation to one sentence.",
  "input": "List Nobel Peace Prize winners from 2022 through 2024.",
  "text": {
    "format": {
      "type": "json_schema",
      "name": "nobel_peace_laureates",
      "strict": true,
      "schema": {
        "type": "object",
        "properties": {
          "laureates": {
            "type": "array",
            "items": {
              "type": "object",
              "properties": {
                "year": {
                  "type": "integer"
                },
                "name": {
                  "type": "string"
                },
                "kind": {
                  "type": "string",
                  "enum": [
                    "👤",
                    "🏛️"
                  ],
                  "description": "👤 for a person; 🏛️ for an organization or institution"
                },
                "country_code": {
                  "type": "string",
                  "description": "ISO 3166-1 alpha-2"
                },
                "motivation": {
                  "type": "string",
                  "description": "One-sentence citation summary"
                }
              },
              "required": [
                "year",
                "name",
                "kind",
                "country_code",
                "motivation"
              ],
              "additionalProperties": false
            }
          }
        },
        "required": [
          "laureates"
        ],
        "additionalProperties": false
      }
    }
  }
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  instructions: "Return Nobel Peace Prize laureates for only the year range in the user message. One array entry per laureate (shared prizes produce multiple entries with the same year). Set kind to 👤 for a person and 🏛️ for an organization or institution. Use ISO 3166-1 alpha-2 country codes. Keep each motivation to one sentence.",
  input: "List Nobel Peace Prize winners from 2022 through 2024.",
  text: {
    format: {
      type: "json_schema",
      name: "nobel_peace_laureates",
      strict: true,
      schema: {
        type: "object",
        properties: {
          laureates: {
            type: "array",
            items: {
              type: "object",
              properties: {
                year: {
                  type: "integer"
                },
                name: {
                  type: "string"
                },
                kind: {
                  type: "string",
                  enum: [
                    "👤",
                    "🏛️"
                  ],
                  description: "👤 for a person; 🏛️ for an organization or institution"
                },
                country_code: {
                  type: "string",
                  description: "ISO 3166-1 alpha-2"
                },
                motivation: {
                  type: "string",
                  description: "One-sentence citation summary"
                }
              },
              required: [
                "year",
                "name",
                "kind",
                "country_code",
                "motivation"
              ],
              additionalProperties: false
            }
          }
        },
        required: [
          "laureates"
        ],
        additionalProperties: false
      }
    }
  }
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    instructions="Return Nobel Peace Prize laureates for only the year range in the user message. One array entry per laureate (shared prizes produce multiple entries with the same year). Set kind to 👤 for a person and 🏛️ for an organization or institution. Use ISO 3166-1 alpha-2 country codes. Keep each motivation to one sentence.",
    input="List Nobel Peace Prize winners from 2022 through 2024.",
    text={
        "format": {
            "type": "json_schema",
            "name": "nobel_peace_laureates",
            "strict": True,
            "schema": {
                "type": "object",
                "properties": {
                    "laureates": {
                        "type": "array",
                        "items": {
                            "type": "object",
                            "properties": {
                                "year": {
                                    "type": "integer",
                                },
                                "name": {
                                    "type": "string",
                                },
                                "kind": {
                                    "type": "string",
                                    "enum": [
                                        "👤",
                                        "🏛️",
                                    ],
                                    "description": "👤 for a person; 🏛️ for an organization or institution",
                                },
                                "country_code": {
                                    "type": "string",
                                    "description": "ISO 3166-1 alpha-2",
                                },
                                "motivation": {
                                    "type": "string",
                                    "description": "One-sentence citation summary",
                                },
                            },
                            "required": [
                                "year",
                                "name",
                                "kind",
                                "country_code",
                                "motivation",
                            ],
                            "additionalProperties": False,
                        },
                    },
                },
                "required": [
                    "laureates",
                ],
                "additionalProperties": False,
            },
        },
    },
)

print(response.output[0].content[0].text)
```

The model returns schema-valid JSON as a string at `output[0].content[0].text`.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "system",
      "content": "Return Nobel Peace Prize laureates for only the year range in the user message. One array entry per laureate (shared prizes produce multiple entries with the same year). Set kind to 👤 for a person and 🏛️ for an organization or institution. Use ISO 3166-1 alpha-2 country codes. Keep each motivation to one sentence."
    },
    {
      "role": "user",
      "content": "List Nobel Peace Prize winners from 2022 through 2024."
    }
  ],
  "stream": false,
  "response_format": {
    "type": "json_schema",
    "json_schema": {
      "name": "nobel_peace_laureates",
      "strict": true,
      "schema": {
        "type": "object",
        "properties": {
          "laureates": {
            "type": "array",
            "items": {
              "type": "object",
              "properties": {
                "year": {
                  "type": "integer"
                },
                "name": {
                  "type": "string"
                },
                "kind": {
                  "type": "string",
                  "enum": [
                    "👤",
                    "🏛️"
                  ],
                  "description": "👤 for a person; 🏛️ for an organization or institution"
                },
                "country_code": {
                  "type": "string",
                  "description": "ISO 3166-1 alpha-2"
                },
                "motivation": {
                  "type": "string",
                  "description": "One-sentence citation summary"
                }
              },
              "required": [
                "year",
                "name",
                "kind",
                "country_code",
                "motivation"
              ],
              "additionalProperties": false
            }
          }
        },
        "required": [
          "laureates"
        ],
        "additionalProperties": false
      }
    }
  }
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const completion = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "system",
      content: "Return Nobel Peace Prize laureates for only the year range in the user message. One array entry per laureate (shared prizes produce multiple entries with the same year). Set kind to 👤 for a person and 🏛️ for an organization or institution. Use ISO 3166-1 alpha-2 country codes. Keep each motivation to one sentence."
    },
    {
      role: "user",
      content: "List Nobel Peace Prize winners from 2022 through 2024."
    }
  ],
  stream: false,
  response_format: {
    type: "json_schema",
    json_schema: {
      name: "nobel_peace_laureates",
      strict: true,
      schema: {
        type: "object",
        properties: {
          laureates: {
            type: "array",
            items: {
              type: "object",
              properties: {
                year: {
                  type: "integer"
                },
                name: {
                  type: "string"
                },
                kind: {
                  type: "string",
                  enum: [
                    "👤",
                    "🏛️"
                  ],
                  description: "👤 for a person; 🏛️ for an organization or institution"
                },
                country_code: {
                  type: "string",
                  description: "ISO 3166-1 alpha-2"
                },
                motivation: {
                  type: "string",
                  description: "One-sentence citation summary"
                }
              },
              required: [
                "year",
                "name",
                "kind",
                "country_code",
                "motivation"
              ],
              additionalProperties: false
            }
          }
        },
        required: [
          "laureates"
        ],
        additionalProperties: false
      }
    }
  }
});

console.log(completion.choices[0]?.message?.content);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

completion = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "system",
            "content": "Return Nobel Peace Prize laureates for only the year range in the user message. One array entry per laureate (shared prizes produce multiple entries with the same year). Set kind to 👤 for a person and 🏛️ for an organization or institution. Use ISO 3166-1 alpha-2 country codes. Keep each motivation to one sentence.",
        },
        {
            "role": "user",
            "content": "List Nobel Peace Prize winners from 2022 through 2024.",
        },
    ],
    stream=False,
    response_format={
        "type": "json_schema",
        "json_schema": {
            "name": "nobel_peace_laureates",
            "strict": True,
            "schema": {
                "type": "object",
                "properties": {
                    "laureates": {
                        "type": "array",
                        "items": {
                            "type": "object",
                            "properties": {
                                "year": {
                                    "type": "integer",
                                },
                                "name": {
                                    "type": "string",
                                },
                                "kind": {
                                    "type": "string",
                                    "enum": [
                                        "👤",
                                        "🏛️",
                                    ],
                                    "description": "👤 for a person; 🏛️ for an organization or institution",
                                },
                                "country_code": {
                                    "type": "string",
                                    "description": "ISO 3166-1 alpha-2",
                                },
                                "motivation": {
                                    "type": "string",
                                    "description": "One-sentence citation summary",
                                },
                            },
                            "required": [
                                "year",
                                "name",
                                "kind",
                                "country_code",
                                "motivation",
                            ],
                            "additionalProperties": False,
                        },
                    },
                },
                "required": [
                    "laureates",
                ],
                "additionalProperties": False,
            },
        },
    },
)

print(completion.choices[0].message.content)
```

The model returns schema-valid JSON as a string in `choices[0].message.content`.

Shown below after parsing (same shape either way — only the output location
differs, see [Field reference](#field-reference)):

```json
{
  "laureates": [
    {
      "year": 2022,
      "name": "Ales Bialiatski",
      "kind": "👤",
      "country_code": "BY",
      "motivation": "Recognized for his tireless efforts to expose human rights abuses and promote democracy in Belarus."
    },
    {
      "year": 2022,
      "name": "Memorial",
      "kind": "🏛️",
      "country_code": "RU",
      "motivation": "Honored for its documentation of political repression and human rights violations in the Soviet Union and Russia."
    },
    {
      "year": 2022,
      "name": "Center for Civil Liberties",
      "kind": "🏛️",
      "country_code": "UA",
      "motivation": "Commended for its courageous work defending human rights and civil liberties in Ukraine."
    },
    {
      "year": 2023,
      "name": "Narges Mohammadi",
      "kind": "👤",
      "country_code": "IR",
      "motivation": "Awarded for her unwavering fight against oppression and her advocacy for women's rights in Iran."
    },
    {
      "year": 2024,
      "name": "Nihon Hidankyo",
      "kind": "🏛️",
      "country_code": "JP",
      "motivation": "Recognized for its efforts to achieve a world free of nuclear weapons and its work to eliminate nuclear weapons."
    }
  ]
}
```

| Field          | Type    | Notes                               |
| -------------- | ------- | ----------------------------------- |
| `laureates`    | array   | One object per laureate             |
| `year`         | integer | Award year                          |
| `name`         | string  | Person or organization              |
| `kind`         | enum    | `👤` individual, `🏛️` organization |
| `country_code` | string  | ISO 3166-1 alpha-2                  |
| `motivation`   | string  | One-sentence citation summary       |

Set `stream` to `false` or omit it for a single JSON response.

## Response handling

Parse the JSON string at the output location from the [field reference](#field-reference) above. Before parsing, check for HTTP 4xx errors, refusals/incomplete status, and truncation, then validate the parsed JSON in your app.

### Handling edge cases (Responses API)

```ts title="TypeScript"
import OpenAI from "openai";

const nobelSchema = {
  type: "object",
  properties: {
    laureates: {
      type: "array",
      items: {
        type: "object",
        properties: {
          year: { type: "integer" },
          name: { type: "string" },
        },
        required: ["year", "name"],
        additionalProperties: false,
      },
    },
  },
  required: ["laureates"],
  additionalProperties: false,
};

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
  maxRetries: 0,
});

let laureates;
try {
  const response = await client.responses.create({
    model: "subq-preview",
    input: "List Nobel Peace Prize winners from 2024.",
    text: {
      format: {
        type: "json_schema",
        name: "nobel_peace_laureates",
        strict: true,
        schema: nobelSchema,
      },
    },
  });

  // @check truncated — status is not "completed", or incomplete_details is set
  if (response.status !== "completed" || response.incomplete_details) {
    throw new Error(`Response did not complete: ${response.status}`);
  }

  const message = response.output.find((item) => item.type === "message");
  const text = message?.content
    ?.filter((part) => part.type === "output_text")
    .map((part) => part.text)
    .join("");

  if (!text) {
    throw new Error("Missing assistant text.");
  }

  // @check parse — content is a JSON string at output[].content[].text
  const data = JSON.parse(text);

  // @check validate — schema-valid JSON; verify meaning in your app
  laureates = data.laureates;
} catch (error) {
  // @check bad-request — HTTP 4xx + error (no response)
  if (error instanceof OpenAI.APIError) throw error;
  throw error;
}
```

```py title="Python"
import json
import os

from openai import APIError, OpenAI

nobel_schema = {
    "type": "object",
    "properties": {
        "laureates": {
            "type": "array",
            "items": {
                "type": "object",
                "properties": {
                    "year": {"type": "integer"},
                    "name": {"type": "string"},
                },
                "required": ["year", "name"],
                "additionalProperties": False,
            },
        },
    },
    "required": ["laureates"],
    "additionalProperties": False,
}

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
    max_retries=0,
)

try:
    response = client.responses.create(
        model="subq-preview",
        input="List Nobel Peace Prize winners from 2024.",
        text={
            "format": {
                "type": "json_schema",
                "name": "nobel_peace_laureates",
                "strict": True,
                "schema": nobel_schema,
            },
        },
    )
except APIError:
    # @check bad-request — HTTP 4xx + error (no response)
    raise

# @check truncated — status is not "completed", or incomplete_details is set
if response.status != "completed" or response.incomplete_details:
    raise RuntimeError(f"Response did not complete: {response.status}")

message = next((item for item in response.output if item.type == "message"), None)
text = "".join(
    part.text for part in (message.content if message else []) if part.type == "output_text"
)

if not text:
    raise RuntimeError("Missing assistant text.")

# @check parse — content is a JSON string at output[].content[].text
data = json.loads(text)

# @check validate — schema-valid JSON; verify meaning in your app
laureates = data["laureates"]
```

### Handling edge cases (Chat Completions)

```ts title="TypeScript"
import OpenAI from "openai";

const nobelSchema = {
  type: "object",
  properties: {
    laureates: {
      type: "array",
      items: {
        type: "object",
        properties: {
          year: { type: "integer" },
          name: { type: "string" },
        },
        required: ["year", "name"],
        additionalProperties: false,
      },
    },
  },
  required: ["laureates"],
  additionalProperties: false,
};

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
  maxRetries: 0,
});

let laureates;
try {
  const completion = await client.chat.completions.create({
    model: "subq-preview",
    messages: [
      { role: "user", content: "List Nobel Peace Prize winners from 2024." },
    ],
    response_format: {
      type: "json_schema",
      json_schema: {
        name: "nobel_peace_laureates",
        strict: true,
        schema: nobelSchema,
      },
    },
  });

  const choice = completion.choices[0];
  const message = choice?.message;

  // @check refusal — choices[0].message.refusal
  if (message?.refusal) {
    throw new Error(`Refused: ${message.refusal}`);
  }

  // @check truncated — finish_reason is "length"
  if (choice?.finish_reason === "length") {
    throw new Error("Response truncated; increase max_tokens or narrow the schema.");
  }

  if (!message?.content) {
    throw new Error("Missing assistant content.");
  }

  // @check parse — content is a JSON string in choices[0].message.content
  const data = JSON.parse(message.content);

  // @check validate — schema-valid JSON; verify meaning in your app
  laureates = data.laureates;
} catch (error) {
  // @check bad-request — HTTP 4xx + error (no completion)
  if (error instanceof OpenAI.APIError) throw error;
  throw error;
}
```

```py title="Python"
import json
import os

from openai import APIError, OpenAI

nobel_schema = {
    "type": "object",
    "properties": {
        "laureates": {
            "type": "array",
            "items": {
                "type": "object",
                "properties": {
                    "year": {"type": "integer"},
                    "name": {"type": "string"},
                },
                "required": ["year", "name"],
                "additionalProperties": False,
            },
        },
    },
    "required": ["laureates"],
    "additionalProperties": False,
}

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
    max_retries=0,
)

try:
    completion = client.chat.completions.create(
        model="subq-preview",
        messages=[
            {"role": "user", "content": "List Nobel Peace Prize winners from 2024."},
        ],
        response_format={
            "type": "json_schema",
            "json_schema": {
                "name": "nobel_peace_laureates",
                "strict": True,
                "schema": nobel_schema,
            },
        },
    )
except APIError:
    # @check bad-request — HTTP 4xx + error (no completion)
    raise

choice = completion.choices[0]
message = choice.message

# @check refusal — choices[0].message.refusal
if getattr(message, "refusal", None):
    raise RuntimeError(f"Refused: {message.refusal}")

# @check truncated — finish_reason is "length"
if choice.finish_reason == "length":
    raise RuntimeError("Response truncated; increase max_tokens or narrow the schema.")

if not message.content:
    raise RuntimeError("Missing assistant content.")

# @check parse — content is a JSON string in choices[0].message.content
data = json.loads(message.content)

# @check validate — schema-valid JSON; verify meaning in your app
laureates = data["laureates"]
```

## Best practices

- **Use the system message (or `instructions`) to interpret the schema.** The schema sets shape; the system prompt sets meaning. Spell out formats, enums, and terse field names—the example above does this.
- **Define fallbacks for missing data.** Required fields still need a value when input omits them—e.g. "use 0 for exposure\_usd when not applicable."
- **Keep schemas small.** Flat objects are easier to satisfy than deep nesting.

## Related

- [Responses API](/endpoints/responses-api/#structured-outputs) — structured output via `text.format`.
- [Chat Completions API](/endpoints/chat-completions-api/) — request fields and response shape.
- [Decisions API](/endpoints/decisions-api/) — yes/no, choice, and score judgments with probabilities.
- [Function calling](/using-the-api/function-calling/) — tools and tool call outputs.
- [Models](/using-the-api/models/) — supported model IDs.
- [OpenAI Structured Outputs](https://developers.openai.com/api/docs/guides/structured-outputs) — full feature reference.

---
title: Function calling
description: Connect SubQ models to your application with OpenAI-compatible tools, on Chat Completions or the Responses API.
---

> Status: Early access

Function calling (also known as tool calling) lets SubQ models interface with
external systems and data outside their training data. Pass function tools
defined by a JSON schema in the `tools` parameter; the model may return a
**tool call**, and your application executes the function and sends the
**tool call output** back so the model can finish the reply. The shape
differs by endpoint: Responses uses a flattened tool object
(`type`/`name`/`parameters` directly on it), while Chat Completions nests
those fields under a `function` object.

On Chat Completions, SubQ currently returns `tool_calls` reliably when
`stream` is `true`. Accumulate streamed deltas into a full assistant message
before executing tools — non-streaming responses may set `finish_reason` to
`"tool_calls"` without including the `tool_calls` payload.

## How it works

**Tools** — functionality you give the model. A function tool is a JSON Schema
definition the model can choose to call, for example `get_stock_quote`, account
lookup, or issuing a refund.

**Tool calls** — requests from the model to use a tool. If the prompt needs
live data, the model returns one or more calls, each with a function `name`
and JSON-encoded arguments.

**Tool call outputs** — results your application sends back so the model can
finish the reply.

### The tool calling flow

1. Make a request to the model with tools it could call
2. Receive a tool call from the model
3. Execute code on the application side with input from the tool call
4. Make a second request to the model with the tool output
5. Receive a final response from the model (or more tool calls)

## Field reference

|                     | Responses API                                                                     | Chat Completions                                                                       |
| ------------------- | --------------------------------------------------------------------------------- | -------------------------------------------------------------------------------------- |
| Tool shape          | `type`, `name`, `description`, `parameters`, `strict` directly on the tool object | `type: "function"` plus a nested `function: { name, description, parameters, strict }` |
| Tool call           | `function_call` output item — `call_id`, `name`, `arguments`                      | `tool_calls[]` on the assistant message — `id`, `function: { name, arguments }`        |
| Sending the result  | `function_call_output` input item — `call_id`, `output`                           | A message with `role: "tool"`, `tool_call_id`, `content`                               |
| Streaming           | `response.function_call_arguments.delta`/`.done` events                           | `delta.tool_calls[]`, keyed by `index`                                                 |
| Continuing the loop | `previous_response_id` (or `conversation`)                                        | Resend the full `messages[]`, including the assistant and tool messages                |

Both accept the same JSON Schema shape in `parameters`, and the same [strict
mode](#strict-mode) requirements.

## Example

End-to-end flow for a `get_stock_quote` function: the first request declares
the tool, the model returns a tool call, your code runs the function and
sends the result back for a final answer.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data @- <<'EOF'
{
  "model": "subq-preview",
  "input": "What's NVDA trading at right now?",
  "tools": [
    {
      "type": "function",
      "name": "get_stock_quote",
      "description": "Retrieves the latest quote for a stock ticker.",
      "parameters": {
        "type": "object",
        "properties": {
          "symbol": {
            "type": "string",
            "description": "Ticker symbol, e.g. NVDA or MSFT"
          },
          "currency": {
            "type": [
              "string",
              "null"
            ],
            "enum": [
              "USD",
              "EUR"
            ],
            "description": "Quote currency. Defaults to USD when null."
          },
          "include_extended_hours": {
            "type": "boolean",
            "description": "When true, include pre-market and after-hours price if available."
          }
        },
        "required": [
          "symbol",
          "currency",
          "include_extended_hours"
        ],
        "additionalProperties": false
      },
      "strict": true
    }
  ]
}
EOF
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  input: "What's NVDA trading at right now?",
  tools: [
    {
      type: "function",
      name: "get_stock_quote",
      description: "Retrieves the latest quote for a stock ticker.",
      parameters: {
        type: "object",
        properties: {
          symbol: {
            type: "string",
            description: "Ticker symbol, e.g. NVDA or MSFT"
          },
          currency: {
            type: [
              "string",
              "null"
            ],
            enum: [
              "USD",
              "EUR"
            ],
            description: "Quote currency. Defaults to USD when null."
          },
          include_extended_hours: {
            type: "boolean",
            description: "When true, include pre-market and after-hours price if available."
          }
        },
        required: [
          "symbol",
          "currency",
          "include_extended_hours"
        ],
        additionalProperties: false
      },
      strict: true
    }
  ]
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    input="What's NVDA trading at right now?",
    tools=[
        {
            "type": "function",
            "name": "get_stock_quote",
            "description": "Retrieves the latest quote for a stock ticker.",
            "parameters": {
                "type": "object",
                "properties": {
                    "symbol": {
                        "type": "string",
                        "description": "Ticker symbol, e.g. NVDA or MSFT",
                    },
                    "currency": {
                        "type": [
                            "string",
                            "null",
                        ],
                        "enum": [
                            "USD",
                            "EUR",
                        ],
                        "description": "Quote currency. Defaults to USD when null.",
                    },
                    "include_extended_hours": {
                        "type": "boolean",
                        "description": "When true, include pre-market and after-hours price if available.",
                    },
                },
                "required": [
                    "symbol",
                    "currency",
                    "include_extended_hours",
                ],
                "additionalProperties": False,
            },
            "strict": True,
        },
    ],
)

print(response.output[0].content[0].text)
```

Accumulate any text preamble, execute every `function_call` in the turn, then
continue with one `function_call_output` per `call_id`:

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

// Responses API function tools use a flattened shape. Unlike Chat
// Completions, name/description/parameters are not nested under `function`.
const tools = [
  {
    type: "function",
    name: "get_stock_quote",
    description:
      "Get the latest price for one stock ticker. Returns symbol, price, change_percent, and as_of.",
    parameters: {
      type: "object",
      properties: {
        symbol: {
          type: "string",
          description: "Ticker symbol, e.g. NVDA or MSFT.",
        },
      },
      required: ["symbol"],
      additionalProperties: false,
    },
    strict: true,
  },
];

const SAMPLE_QUOTES = {
  NVDA: { price: 210.96, change_percent: 4.03 },
  MSFT: { price: 402.18, change_percent: 1.12 },
};

// Replace this stub with a call to your market-data provider.
async function getStockQuote({ symbol }) {
  return { symbol, as_of: new Date().toISOString(), ...SAMPLE_QUOTES[symbol] };
}

const functionHandlers = {
  get_stock_quote: getStockQuote,
};

// A function_call turn may carry a text preamble as a `message` item before
// the call (see "Text preamble before tool calls"); it is never the final
// answer by itself, so always take the *last* message item.
function getLastAssistantText(response) {
  const messages = response.output.filter((item) => item.type === "message");

  return (
    messages
      .at(-1)
      ?.content?.filter((part) => part.type === "output_text")
      .map((part) => part.text)
      .join("") ?? ""
  );
}

let response = await client.responses.create({
  model: "subq-preview",
  input: "What are NVDA and MSFT trading at, and which moved more today?",
  tools,
});

// A response can contain more function calls after receiving function call
// outputs, so continue until the model returns a final response.
const maxFunctionRounds = 8;

for (let round = 0; round < maxFunctionRounds; round += 1) {
  const functionCalls = response.output.filter(
    (item) => item.type === "function_call",
  );

  if (functionCalls.length === 0) break;

  // A message before a function call is an optional preamble, not the final
  // answer. It can be shown to the user while the functions are running.
  const preamble = getLastAssistantText(response);
  if (preamble) {
    console.log(preamble);
  }

  // Execute every function_call in the turn — the model may call in parallel.
  const functionCallOutputs = await Promise.all(
    functionCalls.map(async (call) => {
      const handler = functionHandlers[call.name];
      if (!handler) {
        throw new Error(`No handler registered for function "${call.name}".`);
      }

      return {
        type: "function_call_output",
        call_id: call.call_id,
        output: JSON.stringify(await handler(JSON.parse(call.arguments))),
      };
    }),
  );

  response = await client.responses.create({
    model: "subq-preview",
    previous_response_id: response.id,
    input: functionCallOutputs,
    // Resend tools so the model can request another function call.
    tools,
  });
}

if (response.output.some((item) => item.type === "function_call")) {
  throw new Error(`Exceeded ${maxFunctionRounds} function-calling rounds.`);
}

console.log(getLastAssistantText(response));
```

```py title="Python"
import json
import os
from datetime import datetime, timezone

from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

# Responses API function tools use a flattened shape. Unlike Chat
# Completions, name/description/parameters are not nested under `function`.
tools = [
    {
        "type": "function",
        "name": "get_stock_quote",
        "description": (
            "Get the latest price for one stock ticker. "
            "Returns symbol, price, change_percent, and as_of."
        ),
        "parameters": {
            "type": "object",
            "properties": {
                "symbol": {
                    "type": "string",
                    "description": "Ticker symbol, e.g. NVDA or MSFT.",
                },
            },
            "required": ["symbol"],
            "additionalProperties": False,
        },
        "strict": True,
    },
]

SAMPLE_QUOTES = {
    "NVDA": {"price": 210.96, "change_percent": 4.03},
    "MSFT": {"price": 402.18, "change_percent": 1.12},
}


# Replace this stub with a call to your market-data provider.
def get_stock_quote(symbol):
    quote = SAMPLE_QUOTES.get(symbol, {})
    return {
        "symbol": symbol,
        "as_of": datetime.now(timezone.utc).isoformat(),
        **quote,
    }


function_handlers = {
    "get_stock_quote": get_stock_quote,
}


# A function_call turn may carry a text preamble as a `message` item before
# the call (see "Text preamble before tool calls"); it is never the final
# answer by itself, so always take the *last* message item.
def get_last_assistant_text(response):
    messages = [item for item in response.output if item.type == "message"]
    if not messages:
        return ""
    return "".join(
        part.text
        for part in (messages[-1].content or [])
        if part.type == "output_text"
    )


response = client.responses.create(
    model="subq-preview",
    input="What are NVDA and MSFT trading at, and which moved more today?",
    tools=tools,
)

# A response can contain more function calls after receiving function call
# outputs, so continue until the model returns a final response.
max_function_rounds = 8

for _ in range(max_function_rounds):
    function_calls = [
        item for item in response.output if item.type == "function_call"
    ]

    if not function_calls:
        break

    # A message before a function call is an optional preamble, not the final
    # answer. It can be shown to the user while the functions are running.
    preamble = get_last_assistant_text(response)
    if preamble:
        print(preamble)

    # Execute every function_call in the turn — the model may call in parallel.
    function_call_outputs = []
    for call in function_calls:
        handler = function_handlers.get(call.name)
        if handler is None:
            raise RuntimeError(f'No handler registered for function "{call.name}".')
        result = handler(**json.loads(call.arguments))
        function_call_outputs.append(
            {
                "type": "function_call_output",
                "call_id": call.call_id,
                "output": json.dumps(result),
            }
        )

    response = client.responses.create(
        model="subq-preview",
        previous_response_id=response.id,
        input=function_call_outputs,
        # Resend tools so the model can request another function call.
        tools=tools,
    )

if any(item.type == "function_call" for item in response.output):
    raise RuntimeError(f"Exceeded {max_function_rounds} function-calling rounds.")

print(get_last_assistant_text(response))
```

Set `stream` to `true` and include your function definitions in `tools`.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data @- <<'EOF'
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": "What's NVDA trading at right now?"
    }
  ],
  "tools": [
    {
      "type": "function",
      "function": {
        "name": "get_stock_quote",
        "description": "Retrieves the latest quote for a stock ticker.",
        "parameters": {
          "type": "object",
          "properties": {
            "symbol": {
              "type": "string",
              "description": "Ticker symbol, e.g. NVDA or MSFT"
            },
            "currency": {
              "type": [
                "string",
                "null"
              ],
              "enum": [
                "USD",
                "EUR"
              ],
              "description": "Quote currency. Defaults to USD when null."
            },
            "include_extended_hours": {
              "type": "boolean",
              "description": "When true, include pre-market and after-hours price if available."
            }
          },
          "required": [
            "symbol",
            "currency",
            "include_extended_hours"
          ],
          "additionalProperties": false
        },
        "strict": true
      }
    }
  ],
  "stream": true
}
EOF
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const stream = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "user",
      content: "What's NVDA trading at right now?"
    }
  ],
  tools: [
    {
      type: "function",
      function: {
        name: "get_stock_quote",
        description: "Retrieves the latest quote for a stock ticker.",
        parameters: {
          type: "object",
          properties: {
            symbol: {
              type: "string",
              description: "Ticker symbol, e.g. NVDA or MSFT"
            },
            currency: {
              type: [
                "string",
                "null"
              ],
              enum: [
                "USD",
                "EUR"
              ],
              description: "Quote currency. Defaults to USD when null."
            },
            include_extended_hours: {
              type: "boolean",
              description: "When true, include pre-market and after-hours price if available."
            }
          },
          required: [
            "symbol",
            "currency",
            "include_extended_hours"
          ],
          additionalProperties: false
        },
        strict: true
      }
    }
  ],
  stream: true
});

let fullText = "";

for await (const chunk of stream) {
  const delta = chunk.choices[0]?.delta?.content ?? "";
  fullText += delta;
  process.stdout.write(delta);
}

console.log();
console.log(fullText);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

stream = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "user",
            "content": "What's NVDA trading at right now?",
        },
    ],
    tools=[
        {
            "type": "function",
            "function": {
                "name": "get_stock_quote",
                "description": "Retrieves the latest quote for a stock ticker.",
                "parameters": {
                    "type": "object",
                    "properties": {
                        "symbol": {
                            "type": "string",
                            "description": "Ticker symbol, e.g. NVDA or MSFT",
                        },
                        "currency": {
                            "type": [
                                "string",
                                "null",
                            ],
                            "enum": [
                                "USD",
                                "EUR",
                            ],
                            "description": "Quote currency. Defaults to USD when null.",
                        },
                        "include_extended_hours": {
                            "type": "boolean",
                            "description": "When true, include pre-market and after-hours price if available.",
                        },
                    },
                    "required": [
                        "symbol",
                        "currency",
                        "include_extended_hours",
                    ],
                    "additionalProperties": False,
                },
                "strict": True,
            },
        },
    ],
    stream=True,
)

full_text = ""

for chunk in stream:
    delta = chunk.choices[0].delta.content or ""
    full_text += delta
    print(delta, end="", flush=True)

print()
print(full_text)
```

Accumulate streamed `delta.tool_calls` into one assistant message, execute
each call, append `role: "tool"` results, then call the model again:

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
  maxRetries: 0,
});

// 1. Define callable tools for the model
const tools = [
  {
    type: "function",
    function: {
      name: "get_stock_quote",
      description: "Retrieves the latest quote for a stock ticker.",
      parameters: {
        type: "object",
        properties: {
          symbol: {
            type: "string",
            description: "Ticker symbol, e.g. NVDA or MSFT",
          },
          currency: {
            type: ["string", "null"],
            enum: ["USD", "EUR"],
            description: "Quote currency. Defaults to USD when null.",
          },
          include_extended_hours: {
            type: "boolean",
            description:
              "When true, include pre-market and after-hours price if available.",
          },
        },
        required: ["symbol", "currency", "include_extended_hours"],
        additionalProperties: false,
      },
      strict: true,
    },
  },
];

function getStockQuote({ symbol, currency, include_extended_hours }) {
  const quoteCurrency = currency ?? "USD";
  return JSON.stringify({
    symbol: symbol.toUpperCase(),
    price: 210.96,
    currency: quoteCurrency,
    change: 8.18,
    change_percent: 4.03,
    open: 202.0,
    high: 211.0,
    low: 201.92,
    previous_close: 202.78,
    market_cap: 5.11e12,
    pe_ratio: 32.31,
    market_open: false,
    extended_hours: include_extended_hours
      ? {
          price: 210.38,
          change: -0.58,
          change_percent: -0.27,
          session: "after_hours",
        }
      : null,
    as_of: "2026-07-10T21:22:00Z",
  });
}

/** Accumulate streamed chat.completion chunks into one assistant message. */
async function createCompletion(messages) {
  const stream = await client.chat.completions.create({
    model: "subq-preview",
    messages,
    tools,
    stream: true,
  });

  const message = {
    role: "assistant",
    content: null,
    tool_calls: [],
  };

  for await (const chunk of stream) {
    const delta = chunk.choices[0]?.delta;
    if (!delta) continue;

    if (typeof delta.content === "string") {
      message.content = (message.content ?? "") + delta.content;
    }

    for (const toolCall of delta.tool_calls ?? []) {
      const index = toolCall.index ?? 0;
      if (!message.tool_calls[index]) {
        message.tool_calls[index] = {
          id: toolCall.id,
          type: toolCall.type ?? "function",
          function: {
            name: toolCall.function?.name ?? "",
            arguments: toolCall.function?.arguments ?? "",
          },
        };
        continue;
      }

      if (toolCall.id) message.tool_calls[index].id = toolCall.id;
      if (toolCall.function?.name) {
        message.tool_calls[index].function.name += toolCall.function.name;
      }
      if (toolCall.function?.arguments) {
        message.tool_calls[index].function.arguments +=
          toolCall.function.arguments;
      }
    }
  }

  if (message.tool_calls.length === 0) {
    delete message.tool_calls;
  }

  return message;
}

const messages = [
  { role: "user", content: "What's NVDA trading at right now?" },
];

// 2. Prompt the model with tools available
let message = await createCompletion(messages);
messages.push(message);

if (!message.tool_calls?.length) {
  console.log(message.content);
  process.exit(0);
}

// 3. Execute each tool call on the application side
for (const toolCall of message.tool_calls) {
  if (toolCall.function.name !== "get_stock_quote") continue;

  const args = JSON.parse(toolCall.function.arguments);
  const result = getStockQuote(args);

  // 4. Provide tool call outputs back to the model
  messages.push({
    role: "tool",
    tool_call_id: toolCall.id,
    content: result,
  });
}

// 5. Receive a final response (or more tool calls)
message = await createCompletion(messages);
console.log(message.content);
```

```py title="Python"
import json
import os

from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
    max_retries=0,
)

# 1. Define callable tools for the model
tools = [
    {
        "type": "function",
        "function": {
            "name": "get_stock_quote",
            "description": "Retrieves the latest quote for a stock ticker.",
            "parameters": {
                "type": "object",
                "properties": {
                    "symbol": {
                        "type": "string",
                        "description": "Ticker symbol, e.g. NVDA or MSFT",
                    },
                    "currency": {
                        "type": ["string", "null"],
                        "enum": ["USD", "EUR"],
                        "description": "Quote currency. Defaults to USD when null.",
                    },
                    "include_extended_hours": {
                        "type": "boolean",
                        "description": (
                            "When true, include pre-market and after-hours "
                            "price if available."
                        ),
                    },
                },
                "required": ["symbol", "currency", "include_extended_hours"],
                "additionalProperties": False,
            },
            "strict": True,
        },
    }
]


def get_stock_quote(symbol, currency=None, include_extended_hours=False):
    quote_currency = currency or "USD"
    return json.dumps(
        {
            "symbol": symbol.upper(),
            "price": 210.96,
            "currency": quote_currency,
            "change": 8.18,
            "change_percent": 4.03,
            "open": 202.0,
            "high": 211.0,
            "low": 201.92,
            "previous_close": 202.78,
            "market_cap": 5.11e12,
            "pe_ratio": 32.31,
            "market_open": False,
            "extended_hours": (
                {
                    "price": 210.38,
                    "change": -0.58,
                    "change_percent": -0.27,
                    "session": "after_hours",
                }
                if include_extended_hours
                else None
            ),
            "as_of": "2026-07-10T21:22:00Z",
        }
    )


def create_completion(messages):
    """Accumulate streamed chat.completion chunks into one assistant message."""
    stream = client.chat.completions.create(
        model="subq-preview",
        messages=messages,
        tools=tools,
        stream=True,
    )

    message = {
        "role": "assistant",
        "content": None,
        "tool_calls": [],
    }

    for chunk in stream:
        delta = chunk.choices[0].delta if chunk.choices else None
        if delta is None:
            continue

        if isinstance(delta.content, str):
            message["content"] = (message["content"] or "") + delta.content

        for tool_call in delta.tool_calls or []:
            index = tool_call.index or 0
            if index >= len(message["tool_calls"]):
                message["tool_calls"].append(
                    {
                        "id": tool_call.id,
                        "type": tool_call.type or "function",
                        "function": {
                            "name": (tool_call.function.name or ""),
                            "arguments": (tool_call.function.arguments or ""),
                        },
                    }
                )
                continue

            existing = message["tool_calls"][index]
            if tool_call.id:
                existing["id"] = tool_call.id
            if tool_call.function.name:
                existing["function"]["name"] += tool_call.function.name
            if tool_call.function.arguments:
                existing["function"]["arguments"] += tool_call.function.arguments

    if not message["tool_calls"]:
        del message["tool_calls"]

    return message


messages = [
    {"role": "user", "content": "What's NVDA trading at right now?"},
]

# 2. Prompt the model with tools available
message = create_completion(messages)
messages.append(message)

if not message.get("tool_calls"):
    print(message.get("content"))
    raise SystemExit(0)

# 3. Execute each tool call on the application side
for tool_call in message["tool_calls"]:
    if tool_call["function"]["name"] != "get_stock_quote":
        continue

    args = json.loads(tool_call["function"]["arguments"])
    result = get_stock_quote(**args)

    # 4. Provide tool call outputs back to the model
    messages.append(
        {
            "role": "tool",
            "tool_call_id": tool_call["id"],
            "content": result,
        }
    )

# 5. Receive a final response (or more tool calls)
message = create_completion(messages)
print(message.get("content"))
```

**Example assistant tool call** (after accumulating the stream):

```json
{
  "role": "assistant",
  "content": null,
  "tool_calls": [
    {
      "id": "call_abc123",
      "type": "function",
      "function": {
        "name": "get_stock_quote",
        "arguments": "{\"symbol\":\"NVDA\",\"currency\":\"USD\",\"include_extended_hours\":false}"
      }
    }
  ]
}
```

**Example tool message** you send back:

```json
{
  "role": "tool",
  "tool_call_id": "call_abc123",
  "content": "{\"symbol\":\"NVDA\",\"price\":210.96,\"currency\":\"USD\",\"change\":8.18,\"change_percent\":4.03,\"open\":202.0,\"high\":211.0,\"low\":201.92,\"previous_close\":202.78,\"market_cap\":5110000000000,\"pe_ratio\":32.31,\"market_open\":false,\"extended_hours\":null,\"as_of\":\"2026-07-10T21:22:00Z\"}"
}
```

A response can contain more calls after receiving outputs, so keep looping
until the model returns a final message — cap the number of rounds to avoid
runaway loops. Execute every call in a turn concurrently (the model may call
in parallel).

### Dispatching multiple tool calls

The model may return zero, one, or many calls in a single turn. Dispatch by
name and execute them concurrently; on Responses, resend `tools` on each
request where the model should be allowed to call again, and match outputs
back by `call_id` — the same rules as the single-tool loop above, just with
more than one call per turn. On Chat Completions:

```ts title="TypeScript"
function getAccountPositions({ account_id, symbol }) {
  const positions = [
    {
      symbol: "NVDA",
      quantity: 120,
      average_cost: 142.5,
      market_value: 25315.2,
    },
    {
      symbol: "MSFT",
      quantity: 40,
      average_cost: 380.1,
      market_value: 15404.0,
    },
  ];
  const filtered = symbol
    ? positions.filter((p) => p.symbol === symbol.toUpperCase())
    : positions;
  return JSON.stringify({ account_id, positions: filtered });
}

const handlers = {
  get_stock_quote: getStockQuote,
  get_account_positions: getAccountPositions,
};

// After createCompletion() — same streaming accumulator as the single-tool example
for (const toolCall of message.tool_calls ?? []) {
  const handler = handlers[toolCall.function.name];
  if (!handler) {
    throw new Error(`Unknown tool: ${toolCall.function.name}`);
  }
  const args = JSON.parse(toolCall.function.arguments);
  messages.push({
    role: "tool",
    tool_call_id: toolCall.id,
    content: handler(args),
  });
}
```

```py title="Python"
def get_account_positions(account_id, symbol=None):
    positions = [
        {
            "symbol": "NVDA",
            "quantity": 120,
            "average_cost": 142.5,
            "market_value": 25315.2,
        },
        {
            "symbol": "MSFT",
            "quantity": 40,
            "average_cost": 380.1,
            "market_value": 15404.0,
        },
    ]
    if symbol:
        positions = [p for p in positions if p["symbol"] == symbol.upper()]
    return json.dumps({"account_id": account_id, "positions": positions})


handlers = {
    "get_stock_quote": get_stock_quote,
    "get_account_positions": get_account_positions,
}

# After create_completion() — same streaming accumulator as the single-tool example
for tool_call in message.get("tool_calls") or []:
    handler = handlers.get(tool_call["function"]["name"])
    if handler is None:
        raise RuntimeError(f"Unknown tool: {tool_call['function']['name']}")
    args = json.loads(tool_call["function"]["arguments"])
    messages.append(
        {
            "role": "tool",
            "tool_call_id": tool_call["id"],
            "content": handler(**args),
        }
    )
```

See [Responses function calling](/endpoints/responses-api/#function-calling)
for that endpoint's own parallel-call example.

### Strict mode

Set `strict` to `true` so function arguments adhere to the schema. Recommended
for production. Strict schemas require:

1. `additionalProperties` set to `false` on every object in `parameters`
2. Every key in `properties` listed in `required`

Mark a field optional by allowing `null` in its type (for example
`"type": ["string", "null"]`) while still listing it in `required`.

## Handling function calls

Assume zero, one, or many tool calls in a turn — see
[Dispatching multiple tool calls](#example) above.

1. Add the model's tool call(s) to your ongoing context (the assistant
   message on Chat Completions, or nothing extra to add on Responses — just
   continue via `previous_response_id`/`conversation`)
2. For each call, parse the arguments, run your code, and send back a result
   keyed by `call_id` (Responses) or `tool_call_id` (Chat Completions)
3. Call the model again with the result — the full `messages[]` on Chat
   Completions, or just the `function_call_output` items on Responses

The result is typically a string — JSON, plain text, or a short
success/failure token for side-effect-only functions (for example `"success"`).

## Tool choice

By default the model decides when to call tools. On Chat Completions, control
that with `tool_choice`:

| Value                                                       | Behavior                                       |
| ----------------------------------------------------------- | ---------------------------------------------- |
| `"auto"`                                                    | Default. Call zero, one, or multiple functions |
| `"required"`                                                | Call one or more functions                     |
| `"none"`                                                    | Do not call tools (same as omitting `tools`)   |
| `{"type":"function","function":{"name":"get_stock_quote"}}` | Force that specific function                   |

```json
{
  "tool_choice": {
    "type": "function",
    "function": { "name": "get_stock_quote" }
  }
}
```

Responses accepts the same `"auto"`/`"required"`/`"none"` string values
(defaulting to `"auto"` once `tools` is set) but doesn't support forcing one
specific function by name.

## Best practices

- **Write clear names and descriptions.** Say when to use the function, what
  each parameter means, and what the output represents. Use the system
  message or `instructions` for when *not* to call a tool.
- **Keep the tool list small.** Fewer tools usually improve accuracy; prefer a
  focused set over a large catalog in one turn.
- **Offload known values in code.** Do not ask the model to fill arguments you
  already know (for example an `order_id` from session state).
- **Enable strict mode** and validate parsed arguments in your application
  before executing side effects.

## Related

- [Responses API](/endpoints/responses-api/#function-calling) — request fields and streaming events for the flattened shape.
- [Chat Completions API](/endpoints/chat-completions-api/) — request fields and response shape for the nested shape.
- [Structured outputs](/using-the-api/structured-outputs/) — schema-constrained JSON replies.
- [Models](/using-the-api/models/) — which models support tool calls.
- [OpenAI Function calling](https://developers.openai.com/api/docs/guides/function-calling) — full OpenAI reference.

---
title: Responses API
description: Stateful inference with system instructions, web search, and server-managed conversation history.
---

> Status: Early access

Use the Responses API for stateful inference. SubQ stores each turn server-side and links them by ID, so multi-turn workflows — long document review, case research, and agent loops — need no client-side history management. Pass `previous_response_id` to continue from a prior turn.

For stateless requests where you send the full `messages` array each time, use the [Chat Completions API](/endpoints/chat-completions-api/).

```text
POST /v1/responses
```

## When to use which endpoint

|                     | Chat Completions                                                                                                | Responses API                                                                                 |
| ------------------- | --------------------------------------------------------------------------------------------------------------- | --------------------------------------------------------------------------------------------- |
| Conversation state  | You send full `messages[]` each request                                                                         | Server stores history; continue with `previous_response_id` or `conversation`                 |
| Best for            | Drop-in OpenAI migrations, custom message assembly                                                              | Multi-turn apps, long-context workflows, simpler clients                                      |
| System prompt       | `system` role in messages                                                                                       | `instructions` (per-turn; not inherited)                                                      |
| Built-in web search | Not available                                                                                                   | `tools: [{ "type": "web_search_preview" }]`                                                   |
| Function calling    | Nested shape (`{"type":"function","function":{...}}`), see [Function calling](/using-the-api/function-calling/) | Flattened shape (`{"type":"function","name":...}`), see [Function calling](#function-calling) |
| Structured Outputs  | `response_format`                                                                                               | `text.format` (flattened shape)                                                               |
| File input          | `file` parts (`file_data` or `file_id`)                                                                         | `input_file` parts (`file_id` only)                                                           |
| Reasoning effort    | Top-level `reasoning_effort`                                                                                    | Nested `reasoning.effort`                                                                     |
| Stream terminator   | `data: [DONE]`                                                                                                  | `response.completed` event                                                                    |

## Request body

| Field                  | Type                      | Required | Description                                                                                                                                                                                                                                                         |
| ---------------------- | ------------------------- | -------- | ------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `model`                | string                    | Yes      | Model ID to use, such as `subq-preview`. See [Models](/using-the-api/models/).                                                                                                                                                                                      |
| `input`                | string or content part\[] | Yes      | The user's message for this turn. A plain string, or an array of `input_text` and `input_file` parts. See [Input](#input).                                                                                                                                          |
| `instructions`         | string or null            | No       | System prompt for the current turn only. Not inherited — pass it on every request if it must persist.                                                                                                                                                               |
| `previous_response_id` | string or null            | No       | Continues from a specific prior response. Mutually exclusive with `conversation`. Omit or pass `null` to start a new one. Returns `404` if the ID does not exist.                                                                                                   |
| `conversation`         | string or null            | No       | Continues a conversation by its `conv_...` id, picking up from its most recently written turn. Mutually exclusive with `previous_response_id`. See [Multi-turn conversations](#multi-turn-conversations). Returns `404` if the conversation does not exist.         |
| `tools`                | object\[] or null         | No       | Tools available to the model: built-in tools SubQ executes server-side (`{ "type": "web_search_preview" }`, see [Web search](#web-search)) and function tools your application executes (`{ "type": "function", ... }`, see [Function calling](#function-calling)). |
| `reasoning`            | object or null            | No       | Reasoning configuration for this turn. Set `effort` to control how much internal reasoning the model uses. See [Reasoning effort](#reasoning-effort).                                                                                                               |
| `stream`               | boolean                   | No       | When `false` or omitted, returns one JSON response. When `true`, returns server-sent events.                                                                                                                                                                        |
| `text`                 | object or null            | No       | Output format. Defaults to `{ "format": { "type": "text" } }`. See [Structured outputs](#structured-outputs).                                                                                                                                                       |
| `store`                | boolean or null           | No       | Set `false` to run this turn without saving it. Defaults to `true`. See [Storage](#storage).                                                                                                                                                                        |
| `metadata`             | object or null            | No       | Up to 16 key-value string pairs attached to the request, for your own tracking. Echoed back on the response, including streaming `response.created`/`response.completed` events. See [Metadata](#metadata).                                                         |

## Reasoning effort

Pass a `reasoning` object with an `effort` field — not a boolean. Possible `effort` values are `none`, `minimal`, `low`, `medium`, `high`, `xhigh`, and `max`. Which values are accepted, and what the default is when you omit `reasoning`, depends on the model.

This is the Responses equivalent of Chat Completions `reasoning_effort`. SubQ forwards the selected effort to the upstream model.

- **Reasoning tokens are billed as output tokens.** They are included in `usage.output_tokens`. A short answer can bill dozens of times more with reasoning enabled than without.
- **There is no bounded default.** Omitting `reasoning` does not mean light reasoning—the model may reason at length. Set it explicitly on any request with a latency or cost ceiling.
- **The reasoning text itself is never returned.** SubQ does not emit raw reasoning, a `type: "reasoning"` output item, or reasoning-related streaming events, at any `reasoning.effort`. Unlike OpenAI Responses, there is no opaque reasoning item to pass back on the next turn.
- **This endpoint does not report a reasoning token count.** `usage.output_tokens_details.reasoning_tokens` is always `0`. Reasoning still occupies `usage.output_tokens` and the context window — neither endpoint currently reports how many of those tokens were reasoning.

Only `none` gives a guarantee: zero reasoning tokens.

```json
{
  "model": "subq-preview",
  "instructions": "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  "input": "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel.",
  "reasoning": {
    "effort": "high"
  }
}
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "instructions": "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  "input": "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel.",
  "reasoning": {
    "effort": "high"
  }
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  instructions: "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  input: "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel.",
  reasoning: {
    effort: "high"
  }
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    instructions="You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
    input="Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel.",
    reasoning={
        "effort": "high",
    },
)

print(response.output[0].content[0].text)
```

### Choosing a value

Effort selects a reasoning strategy, not a token budget: higher effort does not reliably
mean more tokens, and the relationship differs by prompt and by model version. Benchmark
the candidates on your own prompts rather than assuming an ordering.

| Workload                                           | Suggested effort                 |
| -------------------------------------------------- | -------------------------------- |
| Classification, routing, extraction, short answers | `none`                           |
| Open-ended analysis and multi-step work            | `medium` or `high`; compare both |

## Input

Set `input` to a plain string:

```json
{
  "input": "Summarize the major self-preferencing antitrust cases since 2010."
}
```

A content-part array is also accepted. SubQ processes `input_text` (user text) and `input_file` (an uploaded file referenced by `file_id`). Image parts are ignored. A photo goes to the [Decisions API](/endpoints/decisions-api/#images). Prefer the string form when the turn has no files.

For large documents, include the text in `input` (or earlier turns) and use SubQ's long context window, or upload the file and pass its `file_id`.

### Uploaded files (`file_id`)

Upload the document with the [Files API](/endpoints/files-api/), wait until `status` is `processed`, then send an `input_file` part. Responses uses OpenAI's `input_file` type — not the Chat Completions `file` part.

```json
{
  "model": "subq-preview",
  "input": [
    { "type": "input_file", "file_id": "file_abc123" },
    { "type": "input_text", "text": "Summarize this document." }
  ]
}
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "input": [
    {
      "type": "input_file",
      "file_id": "file_abc123"
    },
    {
      "type": "input_text",
      "text": "Summarize this document."
    }
  ]
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  input: [
    {
      type: "input_file",
      file_id: "file_abc123"
    },
    {
      type: "input_text",
      text: "Summarize this document."
    }
  ]
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    input=[
        {
            "type": "input_file",
            "file_id": "file_abc123",
        },
        {
            "type": "input_text",
            "text": "Summarize this document.",
        },
    ],
)

print(response.output[0].content[0].text)
```

| Field     | Type   | Required | Description                                   |
| --------- | ------ | -------- | --------------------------------------------- |
| `type`    | string | Yes      | Must be `"input_file"`.                       |
| `file_id` | string | Yes      | File identifier returned by `POST /v1/files`. |

Inline `file_data` is not accepted on Responses. Upload the file and pass `file_id`, or use [Chat Completions](/endpoints/chat-completions-api/) for a one-off base64 request. A missing `file_id` returns `400` `validation_error`. An unknown id, or a file owned by another organization, returns `404` `file_not_found`.

You can also wrap parts in a message item (`{ "role": "user", "content": [ ... ] }`), which is the shape the OpenAI SDK sends. See [Sending files](/using-the-api/file-inputs/) for upload vs inline, accepted formats, and the Chat Completions part shape.

## Instructions

Use `instructions` for system guidance — policy constraints, role, citation rules, or output style. It is inserted before conversation history for the current turn, equivalent to a Chat Completions `system` message.

`instructions` are **not** carried by `previous_response_id`. Resend them on every turn that needs the same system prompt.

```json
{
  "model": "subq-preview",
  "instructions": "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  "input": "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel."
}
```

## Web search

Enable built-in web search with a single tool marker. The proxy runs an agentic loop server-side: when the model asks to search, SubQ executes the search, feeds results back, and continues until a final answer — within one request.

```json
{
  "model": "subq-preview",
  "instructions": "Be concise (3 bullets max). Prefer Fed, FDIC, and OCC releases from today. If nothing material, say so.",
  "input": "Any material US bank regulatory news today?",
  "tools": [{ "type": "web_search_preview" }]
}
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "instructions": "Be concise (3 bullets max). Prefer Fed, FDIC, and OCC releases from today. If nothing material, say so.",
  "input": "Any material US bank regulatory news today?",
  "tools": [
    {
      "type": "web_search_preview"
    }
  ]
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  instructions: "Be concise (3 bullets max). Prefer Fed, FDIC, and OCC releases from today. If nothing material, say so.",
  input: "Any material US bank regulatory news today?",
  tools: [
    {
      type: "web_search_preview"
    }
  ]
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    instructions="Be concise (3 bullets max). Prefer Fed, FDIC, and OCC releases from today. If nothing material, say so.",
    input="Any material US bank regulatory news today?",
    tools=[
        {
            "type": "web_search_preview",
        },
    ],
)

print(response.output[0].content[0].text)
```

### Prompting the model to search

Adding `web_search_preview` enables web search, but `tool_choice` remains `auto`. If you want the model to search rather than rely on its internal knowledge, update your instructions to explicitly tell it to:

- Search the web before answering.
- Verify facts against current sources.

```json
{
  "model": "subq-preview",
  "instructions": "You must search the web before answering. Verify each case's latest procedural status using current authoritative sources. Prefer court decisions and regulator publications.",
  "input": "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel.",
  "tools": [{ "type": "web_search_preview" }]
}
```

Avoid instructions such as “cite only facts in the conversation” when you want current web results, because they may discourage the model from relying on retrieved information.

Each executed search appears in `output` as a `web_search_call` item, in the order it ran, followed by the final assistant `message`. The model may also emit a short text `message` *before* it searches (see [Text preamble before tool calls](#text-preamble-before-tool-calls)), so a turn can contain two `message` items: `[message, web_search_call, message]`.

```jsonc
{
  "output": [
    {
      "id": "ws_019f5c714e4479a5a37680c82da9d06c",
      "type": "web_search_call",
      "status": "completed",
      "action": {
        "type": "search",
        "queries": [
          "US bank regulatory news today",
          "FDIC announcements today",
          "OCC regulatory updates today",
          "Federal Reserve banking regulations today"
        ],
        "query": "US bank regulatory news today"
      }
    },
    {
      "id": "msg_019f5c71d7b37b0695ca49dc05c81ba1",
      "type": "message",
      "status": "completed",
      "role": "assistant",
      "phase": "final_answer",
      "content": [
        {
          "type": "output_text",
          "annotations": [],
          "logprobs": [],
          "text": "Based on today's regulatory developments, here are the key updates affecting US banks:\n\n- **Immigrant Lending Guidance**: The OCC, FDIC, and NCUA jointly issued nonbinding guidance warning banks about credit risks when lending to undocumented immigrants, citing potential income instability and deportation risks. This implements a May 2026 Trump executive order and follows FinCEN's May advisory on identity theft and money laundering red flags.\n\n- **Circle National Trust Approval**: The OCC granted final approval for Circle to establish a federally regulated national trust bank (Circle National Trust) for digital asset custody. This allows Circle to manage USDC stablecoin reserves under federal oversight, marking a significant step in crypto regulation.\n\n- **Bank Failure**: The OCC shuttered Kentland Federal Savings and Loan Association (Indiana), the nation's smallest standalone bank, due to critical undercapitalization from unsafe practices. This is the third bank failure in 2026."
        }
      ]
    }
  ]
}
```

**Production notes:**

- `tool_choice` is `auto` — the model searches only when needed.
- A single `web_search_call` may carry up to 5 queries (`action.queries`), run concurrently; `action.query` mirrors the first.
- Searches and answers are stored and replayed on later `previous_response_id` turns.
- Works with streaming and non-streaming. `usage` covers every inference round in the loop.
- Don't assume the answer is `output[0]` or the only `message` item — select `output` items by `type`, and if more than one `message` is present, the **last** one is the final answer. See [Extracting the assistant text](#extracting-the-assistant-text).

## Function calling

Define a function tool with the flattened Responses API shape — `type`, `name`, `description`, `parameters`, and `strict` sit directly on the tool object (unlike Chat Completions, which nests these under a `function` object). See [Function calling](/using-the-api/function-calling/) for the concept, the tool calling flow, and the Chat Completions comparison.

```json
{
  "model": "subq-preview",
  "input": "What are NVDA and MSFT trading at, and which moved more today?",
  "tools": [
    {
      "type": "function",
      "name": "get_stock_quote",
      "description": "Get the latest price for one stock ticker. Returns symbol, price, change_percent, and as_of.",
      "parameters": {
        "type": "object",
        "properties": {
          "symbol": {
            "type": "string",
            "description": "Ticker symbol, e.g. NVDA or MSFT."
          }
        },
        "required": ["symbol"],
        "additionalProperties": false
      },
      "strict": true
    }
  ]
}
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "input": "What are NVDA and MSFT trading at, and which moved more today?",
  "tools": [
    {
      "type": "function",
      "name": "get_stock_quote",
      "description": "Get the latest price for one stock ticker. Returns symbol, price, change_percent, and as_of.",
      "parameters": {
        "type": "object",
        "properties": {
          "symbol": {
            "type": "string",
            "description": "Ticker symbol, e.g. NVDA or MSFT."
          }
        },
        "required": [
          "symbol"
        ],
        "additionalProperties": false
      },
      "strict": true
    }
  ]
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  input: "What are NVDA and MSFT trading at, and which moved more today?",
  tools: [
    {
      type: "function",
      name: "get_stock_quote",
      description: "Get the latest price for one stock ticker. Returns symbol, price, change_percent, and as_of.",
      parameters: {
        type: "object",
        properties: {
          symbol: {
            type: "string",
            description: "Ticker symbol, e.g. NVDA or MSFT."
          }
        },
        required: [
          "symbol"
        ],
        additionalProperties: false
      },
      strict: true
    }
  ]
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    input="What are NVDA and MSFT trading at, and which moved more today?",
    tools=[
        {
            "type": "function",
            "name": "get_stock_quote",
            "description": "Get the latest price for one stock ticker. Returns symbol, price, change_percent, and as_of.",
            "parameters": {
                "type": "object",
                "properties": {
                    "symbol": {
                        "type": "string",
                        "description": "Ticker symbol, e.g. NVDA or MSFT.",
                    },
                },
                "required": [
                    "symbol",
                ],
                "additionalProperties": False,
            },
            "strict": True,
        },
    ],
)

print(response.output[0].content[0].text)
```

When the model calls a function, the response contains a `function_call` output item — one per call, since the model may call the same function (or several different ones) in parallel within a single turn:

```json
{
  "id": "resp_01a3f8c2...",
  "output": [
    {
      "id": "fc_01a3f8c2b9d14e67a8b5c3d0e2f14a79",
      "type": "function_call",
      "status": "completed",
      "call_id": "chatcmpl-tool-3f9a7c1e6b2d4508",
      "name": "get_stock_quote",
      "arguments": "{\"symbol\": \"NVDA\"}"
    },
    {
      "id": "fc_01a3f8c2b9d14e67a8b5c3d0e2f14a80",
      "type": "function_call",
      "status": "completed",
      "call_id": "chatcmpl-tool-3f9a7c1e6b2d4509",
      "name": "get_stock_quote",
      "arguments": "{\"symbol\": \"MSFT\"}"
    }
  ]
}
```

`call_id` doesn't always share the `resp_`/`fc_` prefix style — treat it as an opaque string and pass it back verbatim in `function_call_output`.

> **Optional text preamble.** The model may emit a short text message before its tool calls. See [Text preamble before tool calls](#text-preamble-before-tool-calls) below for the exact ordering.

Execute the function in your application, then send its result back as a `function_call_output`. Include one function call output per `call_id`:

```json
{
  "model": "subq-preview",
  "previous_response_id": "resp_01a3f8c2...",
  "input": [
    {
      "type": "function_call_output",
      "call_id": "chatcmpl-tool-3f9a7c1e6b2d4508",
      "output": "{\"symbol\":\"NVDA\",\"price\":210.96,\"change_percent\":4.03,\"as_of\":\"2026-07-17T17:42:03.000Z\"}"
    },
    {
      "type": "function_call_output",
      "call_id": "chatcmpl-tool-3f9a7c1e6b2d4509",
      "output": "{\"symbol\":\"MSFT\",\"price\":402.18,\"change_percent\":1.12,\"as_of\":\"2026-07-17T17:42:03.000Z\"}"
    }
  ],
  "tools": [{ "type": "function", "name": "get_stock_quote", "description": "...", "parameters": { "type": "object", "properties": {} } }]
}
```

The proxy replays the function call and function call output into model context. The next response may contain a final response or another `function_call`; repeat the tool calling flow until the model returns a message. Resend `tools` on each request where the model should be allowed to make another call. Function call outputs are accepted only for calls from the immediately preceding `previous_response_id`.

### Full loop

A response can contain more function calls after receiving function call outputs, so keep looping until the model returns a final response — cap the number of rounds to avoid runaway loops. Execute every `function_call` in a turn (the model may call in parallel) with `Promise.all`, and use the last `message` item to surface any text preamble to the user while functions run:

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

// Responses API function tools use a flattened shape. Unlike Chat
// Completions, name/description/parameters are not nested under `function`.
const tools = [
  {
    type: "function",
    name: "get_stock_quote",
    description:
      "Get the latest price for one stock ticker. Returns symbol, price, change_percent, and as_of.",
    parameters: {
      type: "object",
      properties: {
        symbol: {
          type: "string",
          description: "Ticker symbol, e.g. NVDA or MSFT.",
        },
      },
      required: ["symbol"],
      additionalProperties: false,
    },
    strict: true,
  },
];

const SAMPLE_QUOTES = {
  NVDA: { price: 210.96, change_percent: 4.03 },
  MSFT: { price: 402.18, change_percent: 1.12 },
};

// Replace this stub with a call to your market-data provider.
async function getStockQuote({ symbol }) {
  return { symbol, as_of: new Date().toISOString(), ...SAMPLE_QUOTES[symbol] };
}

const functionHandlers = {
  get_stock_quote: getStockQuote,
};

// A function_call turn may carry a text preamble as a `message` item before
// the call (see "Text preamble before tool calls"); it is never the final
// answer by itself, so always take the *last* message item.
function getLastAssistantText(response) {
  const messages = response.output.filter((item) => item.type === "message");

  return (
    messages
      .at(-1)
      ?.content?.filter((part) => part.type === "output_text")
      .map((part) => part.text)
      .join("") ?? ""
  );
}

let response = await client.responses.create({
  model: "subq-preview",
  input: "What are NVDA and MSFT trading at, and which moved more today?",
  tools,
});

// A response can contain more function calls after receiving function call
// outputs, so continue until the model returns a final response.
const maxFunctionRounds = 8;

for (let round = 0; round < maxFunctionRounds; round += 1) {
  const functionCalls = response.output.filter(
    (item) => item.type === "function_call",
  );

  if (functionCalls.length === 0) break;

  // A message before a function call is an optional preamble, not the final
  // answer. It can be shown to the user while the functions are running.
  const preamble = getLastAssistantText(response);
  if (preamble) {
    console.log(preamble);
  }

  // Execute every function_call in the turn — the model may call in parallel.
  const functionCallOutputs = await Promise.all(
    functionCalls.map(async (call) => {
      const handler = functionHandlers[call.name];
      if (!handler) {
        throw new Error(`No handler registered for function "${call.name}".`);
      }

      return {
        type: "function_call_output",
        call_id: call.call_id,
        output: JSON.stringify(await handler(JSON.parse(call.arguments))),
      };
    }),
  );

  response = await client.responses.create({
    model: "subq-preview",
    previous_response_id: response.id,
    input: functionCallOutputs,
    // Resend tools so the model can request another function call.
    tools,
  });
}

if (response.output.some((item) => item.type === "function_call")) {
  throw new Error(`Exceeded ${maxFunctionRounds} function-calling rounds.`);
}

console.log(getLastAssistantText(response));
```

```py title="Python"
import json
import os
from datetime import datetime, timezone

from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

# Responses API function tools use a flattened shape. Unlike Chat
# Completions, name/description/parameters are not nested under `function`.
tools = [
    {
        "type": "function",
        "name": "get_stock_quote",
        "description": (
            "Get the latest price for one stock ticker. "
            "Returns symbol, price, change_percent, and as_of."
        ),
        "parameters": {
            "type": "object",
            "properties": {
                "symbol": {
                    "type": "string",
                    "description": "Ticker symbol, e.g. NVDA or MSFT.",
                },
            },
            "required": ["symbol"],
            "additionalProperties": False,
        },
        "strict": True,
    },
]

SAMPLE_QUOTES = {
    "NVDA": {"price": 210.96, "change_percent": 4.03},
    "MSFT": {"price": 402.18, "change_percent": 1.12},
}


# Replace this stub with a call to your market-data provider.
def get_stock_quote(symbol):
    quote = SAMPLE_QUOTES.get(symbol, {})
    return {
        "symbol": symbol,
        "as_of": datetime.now(timezone.utc).isoformat(),
        **quote,
    }


function_handlers = {
    "get_stock_quote": get_stock_quote,
}


# A function_call turn may carry a text preamble as a `message` item before
# the call (see "Text preamble before tool calls"); it is never the final
# answer by itself, so always take the *last* message item.
def get_last_assistant_text(response):
    messages = [item for item in response.output if item.type == "message"]
    if not messages:
        return ""
    return "".join(
        part.text
        for part in (messages[-1].content or [])
        if part.type == "output_text"
    )


response = client.responses.create(
    model="subq-preview",
    input="What are NVDA and MSFT trading at, and which moved more today?",
    tools=tools,
)

# A response can contain more function calls after receiving function call
# outputs, so continue until the model returns a final response.
max_function_rounds = 8

for _ in range(max_function_rounds):
    function_calls = [
        item for item in response.output if item.type == "function_call"
    ]

    if not function_calls:
        break

    # A message before a function call is an optional preamble, not the final
    # answer. It can be shown to the user while the functions are running.
    preamble = get_last_assistant_text(response)
    if preamble:
        print(preamble)

    # Execute every function_call in the turn — the model may call in parallel.
    function_call_outputs = []
    for call in function_calls:
        handler = function_handlers.get(call.name)
        if handler is None:
            raise RuntimeError(f'No handler registered for function "{call.name}".')
        result = handler(**json.loads(call.arguments))
        function_call_outputs.append(
            {
                "type": "function_call_output",
                "call_id": call.call_id,
                "output": json.dumps(result),
            }
        )

    response = client.responses.create(
        model="subq-preview",
        previous_response_id=response.id,
        input=function_call_outputs,
        # Resend tools so the model can request another function call.
        tools=tools,
    )

if any(item.type == "function_call" for item in response.output):
    raise RuntimeError(f"Exceeded {max_function_rounds} function-calling rounds.")

print(get_last_assistant_text(response))
```

## Text preamble before tool calls

When tools ([web search](#web-search) or [function calling](#function-calling)) are enabled, the model may produce a short text preamble **before** it issues its tool calls — for example, "Let me look that up." This preamble is surfaced as its own assistant `message` output item, ordered **before** the tool-call item(s) it precedes. A single turn can therefore contain multiple `message` items: an opening preamble, and (for web search, which resolves within the same request) a final answer after the searches.

Implications for clients:

- Do not assume a tool-call turn has no `message`, and do not assume the assistant text is always `output[0]` or always last. Iterate `output` and dispatch on each item's `type`.
- Ordering follows the model: `output` may be `[message (preamble), web_search_call, message (final answer)]`, or `[message (preamble), function_call]`.
- When streaming, the preamble arrives as `response.output_text.delta` at its own `output_index` (before the tool items), exactly like any other assistant text. See [Streaming](#streaming).

## Request examples

Basic request with system instructions:

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "instructions": "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  "input": "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel."
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const response = await client.responses.create({
  model: "subq-preview",
  instructions: "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  input: "Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel."
});

console.log(response.output[0].content[0].text);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

response = client.responses.create(
    model="subq-preview",
    instructions="You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
    input="Summarize the major self-preferencing antitrust cases since 2010 and list open questions for counsel.",
)

print(response.output[0].content[0].text)
```

## Response

A non-streaming request returns a Response object:

```json {6,21,28-33}
{
  "id": "resp_01939abc1234567890abcdef",
  "object": "response",
  "created_at": 1768000000,
  "completed_at": 1768000001,
  "status": "completed",
  "model": "subq-preview",
  "output": [
    {
      "id": "msg_019f42995d097843a2bbdada3a046f14",
      "type": "message",
      "role": "assistant",
      "status": "completed",
      "phase": "final_answer",
      "content": [
        {
          "type": "output_text",
          "text": "Self-preferencing means a platform favors its own products over competitors. Major cases since 2010 include the EU Google Shopping decision and related follow-on actions. Open questions for counsel often include how to define the relevant market and how to measure harm to rivals.",
          "annotations": [],
          "logprobs": []
        }
      ]
    }
  ],
  "usage": {
    "input_tokens": 100,
    "input_tokens_details": { "cached_tokens": 0 },
    "output_tokens": 68,
    "output_tokens_details": { "reasoning_tokens": 0 },
    "total_tokens": 168
  },
  "instructions": "You are a legal research assistant. Use plain language. Cite only facts in the conversation.",
  "previous_response_id": null,
  "tools": [],
  "text": { "format": { "type": "text" } },
  "error": null,
  "incomplete_details": null
}
```

### Extracting the assistant text

Without tools, the assistant message is `output[0]`:

```
response.output[0].content[0].text
```

When tools run, `output` may contain `web_search_call` / `function_call` items, and the model may emit a text preamble `message` before them (see [Text preamble before tool calls](#text-preamble-before-tool-calls)). Don't assume the assistant text is at index `0` or that there is exactly one `message` — select message items by `type`, and take the **last** one as the final answer:

```js
const messages = response.output.filter((item) => item.type === "message");
const text = messages.at(-1)?.content[0]?.text ?? "";
```

Save `response.id` for the next turn's `previous_response_id`.

### Key response fields

| Field                                           | Description                                                                                                                                                                                                                               |
| ----------------------------------------------- | ----------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `id`                                            | Stable response ID for `previous_response_id`.                                                                                                                                                                                            |
| `status`                                        | `in_progress`, `completed`, `failed`, or `cancelled`.                                                                                                                                                                                     |
| `output`                                        | Ordered items for this turn: `message`, `web_search_call`, and/or `function_call`, in production order (a text preamble `message` may precede tool-call items — see [Text preamble before tool calls](#text-preamble-before-tool-calls)). |
| `usage`                                         | Token counts for this turn only (not the full conversation history).                                                                                                                                                                      |
| `instructions` / `tools` / `text` / `reasoning` | Echo of request fields.                                                                                                                                                                                                                   |
| `metadata`                                      | Echo of the request's `metadata`, or `{}` if none was sent. See [Metadata](#metadata).                                                                                                                                                    |
| `conversation`                                  | Present on every turn: `{ "id": "conv_..." }` identifying the conversation this response belongs to. See the [Conversations API](/endpoints/conversations-api/).                                                                          |

Other request fields such as `temperature`, `store`, and `tool_choice` may also be echoed.

### Output items

| `type`            | Meaning                                                                                                                                                     |
| ----------------- | ----------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `message`         | Assistant text. Read `content[].text` where `type` is `output_text`. A turn may include more than one — a preamble before tool calls, and the final answer. |
| `web_search_call` | A completed search. See `action.queries` / `action.query`.                                                                                                  |
| `function_call`   | A function call generated by the model. See `call_id`, `name`, `arguments`, and [Function calling](#function-calling).                                      |

`output` does not include `type: "reasoning"` items. See [Reasoning effort](#reasoning-effort).

### Usage fields

| Field                                    | Description                                                                              |
| ---------------------------------------- | ---------------------------------------------------------------------------------------- |
| `input_tokens`                           | Tokens from the current turn's input (including web-search loop rounds).                 |
| `input_tokens_details.cached_tokens`     | Prompt tokens served from cache.                                                         |
| `output_tokens`                          | Tokens generated in the response.                                                        |
| `output_tokens_details.reasoning_tokens` | Reasoning tokens for this turn. Always `0` — not currently populated on either endpoint. |
| `total_tokens`                           | Sum of input and output tokens.                                                          |

## Multi-turn conversations

Pass the `id` from a previous response as `previous_response_id` to continue. The server rebuilds history automatically — send only the new `input` and the prior response ID.

```
Turn 1:  POST /v1/responses
         { "model": "subq-preview", "input": "Who won the 2024 Nobel Prize in Physics?" }
         ← { "id": "resp_019f42fa...", "output": [{ "content": [{ "text": "John J. Hopfield and Geoffrey E. Hinton — for foundational work on machine learning with artificial neural networks." }] }] }

Turn 2:  POST /v1/responses
         { "model": "subq-preview", "input": "How does this connect to modern deep learning?", "previous_response_id": "resp_019f42fa..." }
         ← { "id": "resp_019f430a...", "previous_response_id": "resp_019f42fa...", "output": [{ "content": [{ "text": "Hopfield networks inspired associative memory and energy-based models; Hinton's backpropagation and deep networks underpin today's CNNs, transformers, and LLMs." }] }] }

Turn 3:  POST /v1/responses
         { "model": "subq-preview", "input": "Are there any other physics-inspired ML ideas not from these laureates?", "previous_response_id": "resp_019f430a..." }
         ← { "id": "resp_019f4319...", "previous_response_id": "resp_019f430a...", "output": [{ "content": [{ "text": "Yes — Boltzmann machines, diffusion models, renormalization-group analyses of deep networks, and thermodynamics-inspired views of SGD, among others." }] }] }
```

Chain turns by passing the latest `id` as `previous_response_id`. Resend `instructions` (and `tools`, if needed) on each turn — they are not inherited.

### Continuing by conversation id

Every response includes a `conversation.id`. Pass it as `conversation` on a later turn to continue instead of using a specific response id:

```json
{
  "model": "subq-preview",
  "input": "What is my name?",
  "conversation": "conv_abc123"
}
```

Use one or the other, not both — sending both `conversation` and `previous_response_id` returns `400`.

**Key behaviors:**

- History is **branch-safe**: branching from an older `previous_response_id` creates a new conversation branch rather than corrupting the existing chain.
- `usage.input_tokens` reflects the full conversation history resent each turn, not just the new input.
- Prior web searches are replayed into context so the model retains what it found.
- If `previous_response_id` or `conversation` does not exist, the server returns `404` immediately, before inference.

To manage the conversation itself — seed it with history up front, add or read back items, retag its metadata, or delete it — see the [Conversations API](/endpoints/conversations-api/).

## Streaming

When `stream: true`, the response is SSE (`Content-Type: text/event-stream`). Lifecycle events are always present; tools add output-item events.

**Lifecycle:** `response.created` → `response.output_text.delta`… → `response.completed`

**Output items (when tools run):** `response.output_item.added` → item progress events → `response.output_item.done`

```
event: response.created
data: { "type": "response.created", "sequence_number": 0, "response": { ... } }

event: response.output_text.delta
data: { "type": "response.output_text.delta", "sequence_number": 1, "delta": "Self" }

event: response.completed
data: { "type": "response.completed", "sequence_number": 2, "response": { ... } }
```

| Event type                                                         | When                                                                                                                                                              |
| ------------------------------------------------------------------ | ----------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `response.created`                                                 | First. Skeleton response (`status: "in_progress"`). Use `response.id` for the next turn.                                                                          |
| `response.output_text.delta`                                       | Text chunk of assistant text — the final answer, or a [preamble](#text-preamble-before-tool-calls) before tool calls. Concatenate `delta` values per output item. |
| `response.completed`                                               | Last. Full `output` and `usage`.                                                                                                                                  |
| `response.output_item.added` / `done`                              | A structured output item (`web_search_call` or `function_call`) is created / finalized.                                                                           |
| `response.web_search_call.in_progress` / `searching` / `completed` | Status pings while a search runs. Queries appear on `output_item.done`.                                                                                           |
| `response.function_call_arguments.delta` / `done`                  | Streamed `arguments` for a `function_call`. Concatenate `delta` values, then parse `done`'s `arguments` as JSON.                                                  |

Items are ordered by `output_index`, incrementing per item in the order the model produced them. A [text preamble](#text-preamble-before-tool-calls) is a `message` item and takes the index **before** the tool-call item(s) it precedes; the final answer message takes the index after the last item. The model's internal tool-call planning is never streamed — only the resulting items and assistant text reach the client.

Treat unknown event types as ignorable. The stream ends after `response.completed` — not `data: [DONE]`. A `: keepalive` comment is emitted every 15s while the model is slow. If the stream closes without `response.completed`, treat it as an error and retry.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/responses \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "input": "Summarize the major self-preferencing antitrust cases since 2010.",
  "stream": true
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const stream = await client.responses.create({
  model: "subq-preview",
  input: "Summarize the major self-preferencing antitrust cases since 2010.",
  stream: true
});

let fullText = "";
let responseId = null;

for await (const event of stream) {
  if (event.type === "response.created") {
    responseId = event.response.id;
    continue;
  }

  if (event.type === "response.output_text.delta") {
    fullText += event.delta;
    process.stdout.write(event.delta);
    continue;
  }

  if (event.type === "response.completed") {
    // event.response has full output and usage
    continue;
  }
}

console.log(); // newline after streamed tokens
console.log(fullText);
console.log(responseId); // use as previous_response_id on the next turn
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

stream = client.responses.create(
    model="subq-preview",
    input="Summarize the major self-preferencing antitrust cases since 2010.",
    stream=True,
)

full_text = ""
response_id = None

for event in stream:
    if event.type == "response.created":
        response_id = event.response.id
        continue

    if event.type == "response.output_text.delta":
        full_text += event.delta
        print(event.delta, end="", flush=True)
        continue

    if event.type == "response.completed":
        # event.response has full output and usage
        continue

print()
print(full_text)
print(response_id)  # use as previous_response_id on the next turn
```

## Structured outputs

Set `text.format` to constrain the model's output — see [Structured outputs](/using-the-api/structured-outputs/) for schema design guidance. Three modes are supported:

| Mode             | Shape                                                                         | Guarantee                                                |
| ---------------- | ----------------------------------------------------------------------------- | -------------------------------------------------------- |
| `text` (default) | `{ "type": "text" }`                                                          | Unconstrained text.                                      |
| `json_object`    | `{ "type": "json_object" }`                                                   | Output is valid JSON, but not constrained to any schema. |
| `json_schema`    | `{ "type": "json_schema", "name": "...", "strict": true, "schema": { ... } }` | Output conforms to the supplied JSON Schema.             |

Note the **flattened** shape: `name`, `strict`, and `schema` sit directly on `text.format` — unlike Chat Completions, where they nest under `response_format.json_schema`.

```json
{
  "model": "subq-preview",
  "input": "RFI-042 from Structural: Confirm rebar grade for Level 3 slab. Spec section 03 20 00 says Grade 60. Reply needed by 2026-07-18 before pour.",
  "text": {
    "format": {
      "type": "json_schema",
      "name": "rfi_extract",
      "strict": true,
      "schema": {
        "type": "object",
        "properties": {
          "rfi_id": { "type": "string" },
          "from_trade": { "type": "string" },
          "question": { "type": "string" },
          "spec_section": { "type": "string" },
          "due_date": { "type": "string" }
        },
        "required": ["rfi_id", "from_trade", "question", "spec_section", "due_date"],
        "additionalProperties": false
      }
    }
  }
}
```

Example output at `output[0].content[0].text` (parse the string to get the object):

```json
{
  "rfi_id": "RFI-042",
  "from_trade": "Structural",
  "question": "Confirm rebar grade for Level 3 slab. Spec section 03 20 00 says Grade 60.",
  "spec_section": "03 20 00",
  "due_date": "2026-07-18"
}
```

The structured JSON arrives as ordinary assistant text at `output[0].content[0].text` — parse that string to get the object. `json_schema` guarantees a valid shape; for reliable field values, put the facts in `input` and ask the model to extract them (as above).

Unlike OpenAI, `json_object` mode does not require the word "JSON" in your prompt — output is grammar-constrained by the model server.

For a yes/no, category, or rating judgment with probabilities, use the [Decisions API](/endpoints/decisions-api/).

## Metadata

Attach up to 16 key-value string pairs to a request for your own tracking — run IDs, experiment names, customer tags. SubQ does not interpret or act on these values.

- Keys can be at most 64 characters; values at most 512 characters.
- Values must be strings. Numbers and booleans are coerced to strings; objects, arrays, and other non-string values are rejected with a `400` `validation_error`.
- Omit `metadata`, or pass `null` or `{}`, for no metadata — all three are treated the same.

```json
{
  "model": "subq-preview",
  "input": "Summarize the major self-preferencing antitrust cases since 2010.",
  "metadata": { "run_id": "eval-2026-08-31-014", "experiment": "reasoning-ablation" }
}
```

The response echoes `metadata` back verbatim — on the non-streaming response object, and on both the `response.created` and `response.completed` streaming events:

```json
{
  "id": "resp_01939abc1234567890abcdef",
  "metadata": { "run_id": "eval-2026-08-31-014", "experiment": "reasoning-ablation" }
}
```

`metadata` is never forwarded to the underlying model — it is for your own request tracking only.

## Storage

By default every turn is saved so later turns can continue from it. Set `store: false` to run a turn without saving it. The turn can still read earlier history:

```json
{
  "model": "subq-preview",
  "input": "Which of those medications interact with warfarin?",
  "previous_response_id": "resp_019f42fa...",
  "store": false
}
```

An unsaved turn isn't part of the history, and can't be continued from later.

## Errors

```json
{
  "error": {
    "message": "Response 'resp_xxx' not found.",
    "type": "server_error",
    "code": "response_not_found"
  }
}
```

Use `code` for programmatic handling — `message` text may change.

Shared codes with Chat Completions include `invalid_api_key`, `insufficient_credits`, `validation_error`, and `rate_limit_exceeded`. Responses-specific:

| HTTP | `code`                   | Meaning                                                                            |
| ---- | ------------------------ | ---------------------------------------------------------------------------------- |
| 400  | `validation_error`       | `input_file` is missing `file_id`, or the part used unsupported inline `file_data` |
| 404  | `response_not_found`     | `previous_response_id` does not exist in the store                                 |
| 404  | `conversation_not_found` | `conversation` does not exist or belongs to another organization                   |
| 404  | `file_not_found`         | `file_id` does not exist or is owned by another organization                       |
| 503  | `authorization_failed`   | Key lookup temporarily unavailable; retry                                          |

See the [Conversations API](/endpoints/conversations-api/#errors) for conversation-specific error codes.

See [Authentication](/using-the-api/authentication/) for auth and credit errors.

## Next steps

- [Authentication](/using-the-api/authentication/) — API keys and request headers.
- [Models](/using-the-api/models/) — supported model IDs and context windows.
- [Sending files](/using-the-api/file-inputs/) — `input_file` vs Chat Completions `file` parts.
- [Files API](/endpoints/files-api/) — upload and manage files referenced by `file_id`.
- [Conversations API](/endpoints/conversations-api/) — manage conversation history as a stored resource.
- [Structured outputs](/using-the-api/structured-outputs/) — schema design for `text.format`.
- [Function calling](/using-the-api/function-calling/) — tool calling concepts and Chat Completions' nested function-tool shape, for comparison with [Responses function calling](#function-calling).
- [Chat Completions API](/endpoints/chat-completions-api/) — stateless, drop-in OpenAI replacement.

---
title: Chat Completions API
description: Create OpenAI-compatible chat completions with SubQ.
---

> Status: Early access

Use the Chat Completions API to generate a response from SubQ for a list of conversation messages. For server-managed multi-turn conversations with system instructions and built-in web search, see [Responses API](/endpoints/responses-api/).

```text
POST /v1/chat/completions
```

## Request body

Send a JSON object with the required `model` and `messages` fields. Omit optional fields unless you need to change generation behavior.

| Field              | Type                | Required | Description                                                                                                                             |
| ------------------ | ------------------- | -------- | --------------------------------------------------------------------------------------------------------------------------------------- |
| `model`            | string              | Yes      | Model ID to use, such as `subq-preview`. See [Models](/using-the-api/models/).                                                          |
| `messages`         | array               | Yes      | Conversation messages in order. Must contain at least one message.                                                                      |
| `stream`           | boolean             | No       | When `false` or omitted, returns one JSON response. When `true`, returns server-sent events.                                            |
| `temperature`      | number              | No       | Sampling temperature from `0` to `2`. Higher values make output more random.                                                            |
| `max_tokens`       | integer             | No       | Caps generated tokens. Must be at least `1`. See [Token limits](#token-limits).                                                         |
| `top_p`            | number              | No       | Nucleus sampling value from `0` to `1`. Use this or `temperature`, not both, for most requests.                                         |
| `stop`             | string or string\[] | No       | Stop sequence or sequences where generation should stop.                                                                                |
| `reasoning_effort` | string              | No       | How much internal reasoning the model should use before answering. See [Reasoning effort](#reasoning-effort).                           |
| `response_format`  | object              | No       | Constrain the assistant reply to a JSON Schema. See [Structured outputs](/using-the-api/structured-outputs/).                           |
| `tools`            | array               | No       | Function tools the model may call. See [Function calling](/using-the-api/function-calling/).                                            |
| `tool_choice`      | string or object    | No       | Control whether and which tools the model may call (`"auto"`, `"required"`, `"none"`, or a specific function).                          |
| `store`            | boolean or null     | No       | Set `false` to keep this request and response out of storage. Defaults to `true`. See [Storage](#storage).                              |
| `metadata`         | object or null      | No       | Up to 16 key-value string pairs attached to the request, for your own tracking. Echoed back on the response. See [Metadata](#metadata). |

This page documents the non-streaming response. For a non-streaming request, omit `stream` or set it to `false`.

## Token limits

`max_tokens` caps the tokens generated in the completion. It is a spending limit, not a
response-length limit.

- Applies **only** to generated output—not the prompt.
- **Reasoning is part of that output.** Unless [`reasoning_effort`](#reasoning-effort) is `none`, the model reasons before answering from the same allowance, so a request can return `200 OK` with an empty `content` and `finish_reason` of `"length"`—billed, with nothing visible. A larger `max_tokens` makes this less likely but does not rule it out; `reasoning_effort` of `none` does.
- Input and output share the same [context window](/using-the-api/models/). If `max_tokens` plus the input cannot fit, the API returns `400` with `code` `context_length_exceeded`. Do not set `max_tokens` to the full window.
- Use this parameter exclusively; do not send `max_completion_tokens`.
- If set, the minimum value is 1. If omitted, the response can use all remaining context space.
- If generation hits the cap, `choices[0].finish_reason` is `"length"`.

```json
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract."
    }
  ],
  "max_tokens": 500
}
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract."
    }
  ],
  "max_tokens": 500
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const completion = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "user",
      content: "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract."
    }
  ],
  max_tokens: 500
});

console.log(completion.choices[0]?.message?.content);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

completion = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "user",
            "content": "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract.",
        },
    ],
    max_tokens=500,
)

print(completion.choices[0].message.content)
```

### Detecting a response spent on reasoning

```json
{
  "choices": [
    {
      "index": 0,
      "message": {
        "role": "assistant",
        "content": ""
      },
      "finish_reason": "length"
    }
  ],
  "usage": { "prompt_tokens": 126, "completion_tokens": 64, "total_tokens": 190 }
}
```

Test `message.content` directly—an empty string is easy to pass downstream as if it were
an answer.

```js
const choice = completion.choices[0];

if (choice.finish_reason === "length" && !choice.message.content) {
  // The cap was consumed before the answer began. Retry with
  // reasoning_effort: "none", or with a larger max_tokens.
  // Retrying with the same parameters will produce the same result.
}
```

## Reasoning effort

Set top-level `reasoning_effort` to control how much internal reasoning the model uses before it answers. Possible values are `none`, `minimal`, `low`, `medium`, `high`, `xhigh`, and `max`. Which values are accepted, and what the default is when you omit the field, depends on the model.

- **Reasoning tokens are billed as output tokens.** They are included in `usage.completion_tokens` and counted in `max_tokens`. A one-word classification can bill dozens of times more with reasoning enabled than without.
- **There is no bounded default.** Omitting `reasoning_effort` does not mean light reasoning—the model may reason at length. Set it explicitly on any request with a latency or cost ceiling.
- **The reasoning text itself is never returned.** Assistant messages omit any reasoning trace (`reasoning_content` is not a response field, including on streaming deltas). Do not send `reasoning_content` on later turns — it is unused. To detect a reasoning-only response, check `finish_reason` and an empty `content` — see [Detecting a response spent on reasoning](#token-limits) above.

Only `none` gives a guarantee: zero reasoning tokens, even when `max_tokens` is set.

```json
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": "Classify this transaction dispute into exactly one category: [FRAUD, BILLING, LOAN, TECHNICAL]. Return only the category name.\n\nTicket: 'I see a charge of $45.22 from a gas station in Ohio, but I live in California and haven't traveled all year. Please cancel my card!'"
    }
  ],
  "reasoning_effort": "none"
}
```

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data @- <<'EOF'
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "user",
      "content": "Classify this transaction dispute into exactly one category: [FRAUD, BILLING, LOAN, TECHNICAL]. Return only the category name.\n\nTicket: 'I see a charge of $45.22 from a gas station in Ohio, but I live in California and haven't traveled all year. Please cancel my card!'"
    }
  ],
  "reasoning_effort": "none"
}
EOF
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const completion = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "user",
      content: "Classify this transaction dispute into exactly one category: [FRAUD, BILLING, LOAN, TECHNICAL]. Return only the category name.\n\nTicket: 'I see a charge of $45.22 from a gas station in Ohio, but I live in California and haven't traveled all year. Please cancel my card!'"
    }
  ],
  reasoning_effort: "none"
});

console.log(completion.choices[0]?.message?.content);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

completion = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "user",
            "content": "Classify this transaction dispute into exactly one category: [FRAUD, BILLING, LOAN, TECHNICAL]. Return only the category name.\n\nTicket: 'I see a charge of $45.22 from a gas station in Ohio, but I live in California and haven't traveled all year. Please cancel my card!'",
        },
    ],
    reasoning_effort="none",
)

print(completion.choices[0].message.content)
```

### Choosing a value

Effort selects a reasoning strategy, not a token budget: higher effort does not reliably
mean more tokens, and the relationship differs by prompt and by model version. Benchmark
the candidates on your own prompts rather than assuming an ordering.

| Workload                                           | Suggested effort                  |
| -------------------------------------------------- | --------------------------------- |
| Classification, routing, extraction, short answers | `none`                            |
| Open-ended analysis and multi-step work            | `medium` or `high`; compare both  |
| Tight `max_tokens`                                 | `none`, or expect empty `content` |

For classification and routing with probabilities, use the [Decisions API](/endpoints/decisions-api/).

## Messages

Each message has a `role` and `content`.

| Field     | Type                      | Required | Description                                                   |
| --------- | ------------------------- | -------- | ------------------------------------------------------------- |
| `role`    | string                    | Yes      | One of `system`, `user`, `assistant`, or `tool`.              |
| `content` | string or content part\[] | Yes      | Message text as a plain string, or an array of content parts. |

Use `system` for durable instructions, `user` for user input, `assistant` for prior model responses (including messages that contain `tool_calls`), and `tool` for tool result messages already produced by your application. See [Function calling](/using-the-api/function-calling/).

The simplest content shape is a string:

```json
{
  "role": "user",
  "content": "Summarize this release note."
}
```

You can also send text content parts:

```json
{
  "role": "user",
  "content": [
    { "type": "text", "text": "Summarize this release note." }
  ]
}
```

For document input, send a text instruction and one or more `file` parts in the same `user` message:

```json
{
  "role": "user",
  "content": [
    { "type": "text", "text": "Summarize these documents." },
    {
      "type": "file",
      "filename": "financial-report-2026.pdf",
      "mime_type": "application/pdf",
      "file_data": "JVBERi0xLjcKJdDUxdgK..."
    },
    {
      "type": "file",
      "filename": "meeting-notes.txt",
      "mime_type": "text/plain",
      "file_data": "U3ViUSBkb2N1bWVudCBub3Rlcy4uLg=="
    }
  ]
}
```

Document file parts accept inline base64 (`file_data`) or an uploaded `file_id`. Image, audio, video, URL-based file inputs, and other content part types are rejected. A photo goes to the [Decisions API](/endpoints/decisions-api/#images). See [Sending files](/using-the-api/file-inputs/) for file part examples. For the Responses API, use `input_file` with `file_id` instead — see [Uploaded files](/endpoints/responses-api/#uploaded-files-file_id).

## Metadata

Attach up to 16 key-value string pairs to a request for your own tracking — run IDs, experiment names, customer tags. SubQ does not interpret or act on these values.

- Keys can be at most 64 characters; values at most 512 characters.
- Values must be strings. Numbers and booleans are coerced to strings; objects, arrays, and other non-string values are rejected with a `400` `validation_error`.
- Omit `metadata`, or pass `null` or `{}`, for no metadata — all three are treated the same.

```json
{
  "model": "subq-preview",
  "messages": [{ "role": "user", "content": "Summarize this release note." }],
  "metadata": { "run_id": "eval-2026-08-31-014", "experiment": "reasoning-ablation" }
}
```

A non-streaming response echoes `metadata` back verbatim:

```json
{
  "id": "chatcmpl-e1395060-5a57-4182-a833-c5a208137f70",
  "metadata": { "run_id": "eval-2026-08-31-014", "experiment": "reasoning-ablation" }
}
```

Streaming chunks do not include `metadata`. `metadata` is never forwarded to the underlying model — it is for your own request tracking only.

## Storage

By default SubQ stores each request and response according to your organization's [data-retention policy](/using-the-api/data-retention/). Set `store: false` to keep a single request, including any inline PDF, out of storage:

```json
{
  "model": "subq-preview",
  "messages": [{ "role": "user", "content": "Summarize this patient intake note." }],
  "store": false
}
```

Files you reference by `file_id` stay available.

## Request examples

Use cURL for direct HTTP calls, or use the official OpenAI SDK with SubQ's base URL.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/chat/completions \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "model": "subq-preview",
  "messages": [
    {
      "role": "system",
      "content": "You are concise and practical."
    },
    {
      "role": "user",
      "content": "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract."
    }
  ],
  "temperature": 0.2,
  "max_tokens": 500
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const completion = await client.chat.completions.create({
  model: "subq-preview",
  messages: [
    {
      role: "system",
      content: "You are concise and practical."
    },
    {
      role: "user",
      content: "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract."
    }
  ],
  temperature: 0.2,
  max_tokens: 500
});

console.log(completion.choices[0]?.message?.content);
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

completion = client.chat.completions.create(
    model="subq-preview",
    messages=[
        {
            "role": "system",
            "content": "You are concise and practical.",
        },
        {
            "role": "user",
            "content": "In three bullets, explain the difference between indemnification, limitation of liability, and insurance requirements in a software contract.",
        },
    ],
    temperature=0.2,
    max_tokens=500,
)

print(completion.choices[0].message.content)
```

## Response

A non-streaming request returns a JSON object with the OpenAI-compatible chat completion shape.

```json {10-13}
{
  "id": "chatcmpl-e1395060-5a57-4182-a833-c5a208137f70",
  "object": "chat.completion",
  "created": 1784314379,
  "model": "subq-preview",
  "choices": [
    {
      "index": 0,
      "message": {
        "role": "assistant",
        "content": "*   **Indemnification** is a contractual obligation where one party agrees to compensate the other for losses, damages, or legal costs arising from third-party claims (such as intellectual property infringement or data breaches), effectively shifting the financial risk of those specific external liabilities to the responsible party.\n*   **Limitation of Liability** caps the maximum amount of damages one party can be forced to pay the other for breach of contract or negligence, often excluding consequential or indirect damages, thereby protecting both sides from catastrophic financial exposure beyond a predefined threshold (e.g., fees paid in the prior 12 months).\n*   **Insurance Requirements** mandate that one or both parties maintain specific types and minimum amounts of insurance coverage (such as general liability, professional liability, or cyber insurance) to ensure there are financial resources available to cover potential claims, serving as a verification of financial capacity rather than a direct transfer of risk between the contracting parties."
      },
      "finish_reason": "stop"
    }
  ],
  "usage": {
    "prompt_tokens": 110,
    "completion_tokens": 188,
    "total_tokens": 298
  }
}
```

### Response fields

| Field      | Type    | Description                                                                                                         |
| ---------- | ------- | ------------------------------------------------------------------------------------------------------------------- |
| `id`       | string  | Unique completion ID.                                                                                               |
| `object`   | string  | Object type. Non-streaming responses use `chat.completion`.                                                         |
| `created`  | integer | Unix timestamp, in seconds, for when the completion was created.                                                    |
| `model`    | string  | Model ID used for the completion.                                                                                   |
| `choices`  | array   | Generated choices. SubQ returns at least one choice for a successful request.                                       |
| `usage`    | object  | Token usage for the request.                                                                                        |
| `metadata` | object  | Echo of the request's `metadata`, or `{}` if none was sent. Omitted on streaming chunks. See [Metadata](#metadata). |

### Choice fields

| Field                | Type    | Description                                                                                                                                                                    |
| -------------------- | ------- | ------------------------------------------------------------------------------------------------------------------------------------------------------------------------------ |
| `index`              | integer | Choice index.                                                                                                                                                                  |
| `message.role`       | string  | Role of the returned message, usually `assistant`.                                                                                                                             |
| `message.content`    | string  | Generated text. May be `null` when the model returns tool calls, and an empty string when `max_tokens` was consumed before the answer began—see [Token limits](#token-limits). |
| `message.tool_calls` | array   | Present when the model requests function calls. See [Function calling](/using-the-api/function-calling/).                                                                      |
| `finish_reason`      | string  | Reason generation stopped. Common values include `stop`, `length` (hit `max_tokens` or the remaining window), and `tool_calls`. Handle unknown string values defensively.      |

### Usage fields

| Field               | Type    | Description                                                                                  |
| ------------------- | ------- | -------------------------------------------------------------------------------------------- |
| `prompt_tokens`     | integer | Tokens counted from the request messages.                                                    |
| `completion_tokens` | integer | Tokens generated in the response, including any reasoning tokens. Billed at the output rate. |
| `total_tokens`      | integer | Sum of prompt and completion tokens.                                                         |

`completion_tokens` can be entirely reasoning with nothing visible in `content` — test `message.content` directly rather than inferring from token counts.

---
title: Files API
description: Upload, list, retrieve, and delete org-scoped files for use with Chat Completions and Responses.
---

> Status: Early access

Use the Files API to upload and manage documents for your organization. Files are
org-scoped — a file is only visible to the organization that created it.

After upload, reference a file by `file_id`: a `file` part on
[Chat Completions](/endpoints/chat-completions-api/), or an `input_file` part on
the [Responses API](/endpoints/responses-api/). See [Sending files](/using-the-api/file-inputs/)
for the request shapes and for when to upload rather than inline a document.

## Endpoints

| Method   | Path                  | Description               |
| -------- | --------------------- | ------------------------- |
| `POST`   | `/v1/files`           | Upload a file (multipart) |
| `GET`    | `/v1/files`           | List the org's files      |
| `GET`    | `/v1/files/{file_id}` | Retrieve one file         |
| `DELETE` | `/v1/files/{file_id}` | Delete a file             |

## Limits

- **Max size:** 50 MB per file.
- **Purpose:** `assistants` (only value accepted today).
- **Supported types:** plain text (`.txt`, `.md`, `.csv`, `.tsv`), JSON / JSONL,
  XML, PDF, and Word (`.doc`, `.docx`).

## File object

| Field        | Type           | Description                                                                    |
| ------------ | -------------- | ------------------------------------------------------------------------------ |
| `id`         | string         | File identifier (`file_…`). Use as `file_id` in Chat Completions or Responses. |
| `object`     | string         | Always `"file"`.                                                               |
| `bytes`      | number         | Size in bytes.                                                                 |
| `created_at` | number         | Unix timestamp (seconds) when the file was created.                            |
| `expires_at` | number or null | Expiration timestamp, if any.                                                  |
| `filename`   | string         | Original file name.                                                            |
| `purpose`    | string         | Intended purpose (`assistants`).                                               |
| `status`     | string or null | Lifecycle status (see below).                                                  |

### Statuses

| Status      | Meaning                                                                                  |
| ----------- | ---------------------------------------------------------------------------------------- |
| `uploaded`  | Bytes stored and validated. Non-text files may still be extracting text.                 |
| `processed` | Content available for Chat Completions and Responses. Text files reach this immediately. |
| `error`     | Text extraction failed. A later retry can flip it back to `processed`.                   |

## Upload file

```
POST /v1/files
```

Upload bytes through the API as `multipart/form-data`.

| Field     | Required | Description           |
| --------- | -------- | --------------------- |
| `file`    | Yes      | The file part.        |
| `purpose` | Yes      | Must be `assistants`. |

The `file` part must carry a `Content-Type` from the [supported types](#limits).
A part sent as `application/octet-stream` is rejected with `unsupported_file_type`,
so set the type explicitly when your HTTP client does not infer it from the
filename — as the TypeScript example below does with `toFile()`.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/files \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --form purpose=assistants \
  --form file='@./report.pdf'
```

```ts title="TypeScript"
import { createReadStream } from "node:fs";
import OpenAI, { toFile } from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const file = await client.files.create({
  file: await toFile(createReadStream("./report.pdf"), "report.pdf", {
    type: "application/pdf",
  }),
  purpose: "assistants",
});

console.log(file.id);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

with open("./report.pdf", "rb") as handle:
    file = client.files.create(file=handle, purpose="assistants")

print(file.id)
```

### Response

```json
{
  "id": "file_abc123",
  "object": "file",
  "bytes": 12345,
  "created_at": 1753742400,
  "expires_at": null,
  "filename": "report.pdf",
  "purpose": "assistants",
  "status": "uploaded"
}
```

### Uploading multiple files

Each request uploads one file — call the endpoint once per file and run the
calls concurrently rather than looping with `await` one at a time:

```ts title="TypeScript"
import { createReadStream } from "node:fs";
import OpenAI, { toFile } from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

async function uploadFile(path: string, contentType: string) {
  return client.files.create({
    file: await toFile(createReadStream(path), path.split("/").pop(), {
      type: contentType,
    }),
    purpose: "assistants",
  });
}

// Each request uploads one file — fire the calls concurrently rather than
// looping with `await` one at a time.
const uploads = [
  { path: "./report.pdf", contentType: "application/pdf" },
  { path: "./meeting-notes.txt", contentType: "text/plain" },
];
const files = await Promise.all(
  uploads.map(({ path, contentType }) => uploadFile(path, contentType)),
);

files.forEach((file, i) => console.log(`${uploads[i].path} -> ${file.id}`));
```

```py title="Python"
import asyncio
import os

from openai import AsyncOpenAI

client = AsyncOpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)


async def upload_file(path):
    with open(path, "rb") as handle:
        return await client.files.create(file=handle, purpose="assistants")


async def upload_multiple(paths):
    # Each request uploads one file — gather the calls concurrently rather
    # than awaiting one at a time.
    return await asyncio.gather(*(upload_file(path) for path in paths))


paths = ["./report.pdf", "./meeting-notes.txt"]
files = asyncio.run(upload_multiple(paths))
for path, file in zip(paths, files):
    print(f"{path} -> {file.id}")
```

## List files

```
GET /v1/files
```

| Param     | Type    | Default | Description                              |
| --------- | ------- | ------- | ---------------------------------------- |
| `limit`   | integer | `20`    | Page size (`1`–`10000`).                 |
| `order`   | string  | `desc`  | Sort by creation time: `asc` or `desc`.  |
| `after`   | string  | —       | Keyset cursor; start after this file id. |
| `purpose` | string  | —       | Optional filter (`assistants`).          |

```bash title="cURL"
curl --request GET \
  --url 'https://api.subq.ai/v1/files?limit=20&order=desc' \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const files = await client.files.list({ limit: 20, order: "desc" });

console.log(files.data);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

files = client.files.list(limit=20, order="desc")

print(files.data)
```

### Response

```json
{
  "object": "list",
  "data": [
    {
      "id": "file_abc123",
      "object": "file",
      "bytes": 12345,
      "created_at": 1753742400,
      "expires_at": null,
      "filename": "report.pdf",
      "purpose": "assistants",
      "status": "processed"
    }
  ],
  "first_id": "file_abc123",
  "last_id": "file_abc123",
  "has_more": false
}
```

Paginate with `last_id` as the next `after` value until `has_more` is `false`.

## Retrieve file

```
GET /v1/files/{file_id}
```

```bash title="cURL"
curl --request GET \
  --url https://api.subq.ai/v1/files/file_abc123 \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const file = await client.files.retrieve(process.env.SUBQ_FILE_ID ?? "file_abc123");

console.log(file);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

file = client.files.retrieve(os.getenv("SUBQ_FILE_ID", "file_abc123"))

print(file)
```

Returns the File object, or `404` if missing or owned by another org.

## Delete file

```
DELETE /v1/files/{file_id}
```

Removes stored bytes and metadata.

```bash title="cURL"
curl --request DELETE \
  --url https://api.subq.ai/v1/files/file_abc123 \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const result = await client.files.delete(process.env.SUBQ_FILE_ID ?? "file_abc123");

console.log(result.deleted);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

result = client.files.delete(os.getenv("SUBQ_FILE_ID", "file_abc123"), extra_body={})

print(result.deleted)
```

### Response

```json
{
  "id": "file_abc123",
  "object": "file",
  "deleted": true
}
```

## Errors

Errors use the OpenAI shape:

```json
{
  "error": {
    "message": "No such File object: file_abc123",
    "type": "invalid_request_error",
    "code": "not_found",
    "param": null
  }
}
```

| HTTP  | `code`                  | When                                  |
| ----- | ----------------------- | ------------------------------------- |
| `400` | `validation_error`      | Missing or invalid params             |
| `400` | `unsupported_file_type` | MIME type not in the supported set    |
| `401` | `invalid_api_key`       | Missing or invalid API key            |
| `403` | `org_suspended`         | Organization is suspended or inactive |
| `404` | `not_found`             | File missing or owned by another org  |
| `413` | `file_too_large`        | Upload exceeds 50 MB                  |

## Related

- [Sending files](/using-the-api/file-inputs/) — referencing an uploaded file in a request
- [Chat Completions API](/endpoints/chat-completions-api/) — `file` parts on `messages`
- [Responses API](/endpoints/responses-api/) — `input_file` parts on `input`
- [Authentication](/using-the-api/authentication/) — API keys

---
title: Conversations API
description: Manage conversation history as a stored resource — create, retrieve, update, delete, and manage the items inside it.
---

> Status: Early access

Use the Conversations API to create, inspect, retag, and delete stored
conversations — and the items inside them. These are storage operations —
no inference runs. Continue a conversation directly from `/v1/responses`
with the [`conversation`](/endpoints/responses-api/#request-body) field, or
without a stored resource at all via
[`previous_response_id`](/endpoints/responses-api/#multi-turn-conversations).

## Endpoints

| Method   | Path                                                  | Description                      |
| -------- | ----------------------------------------------------- | -------------------------------- |
| `POST`   | `/v1/conversations`                                   | Create a conversation            |
| `GET`    | `/v1/conversations/{conversation_id}`                 | Retrieve a conversation          |
| `POST`   | `/v1/conversations/{conversation_id}`                 | Update a conversation's metadata |
| `DELETE` | `/v1/conversations/{conversation_id}`                 | Delete a conversation            |
| `POST`   | `/v1/conversations/{conversation_id}/items`           | Add items to a conversation      |
| `GET`    | `/v1/conversations/{conversation_id}/items`           | List a conversation's items      |
| `GET`    | `/v1/conversations/{conversation_id}/items/{item_id}` | Retrieve an item                 |
| `DELETE` | `/v1/conversations/{conversation_id}/items/{item_id}` | Delete an item                   |

## The conversation object

Every endpoint except delete returns a conversation object:

```json
{
  "id": "conv_abc123",
  "object": "conversation",
  "created_at": 1751484000,
  "metadata": { "department": "cardiology", "acuity": "unconfirmed" }
}
```

| Field        | Type    | Description                                                                                                                          |
| ------------ | ------- | ------------------------------------------------------------------------------------------------------------------------------------ |
| `id`         | string  | Conversation ID (`conv_...`).                                                                                                        |
| `object`     | string  | Always `"conversation"`.                                                                                                             |
| `created_at` | integer | Unix timestamp (seconds) of creation. Unchanged on update.                                                                           |
| `metadata`   | object  | String-to-string tags. Always an object (`{}` if untagged, never `null`). Up to 16 keys; keys up to 64 characters, values up to 512. |

## Create a conversation

```
POST /v1/conversations
```

All fields are optional. An empty body creates an untagged conversation.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/conversations \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "metadata": {
    "department": "cardiology",
    "acuity": "unconfirmed"
  }
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const conversation = await client.conversations.create({
  metadata: { department: "cardiology", acuity: "unconfirmed" },
});

console.log(conversation.id);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

conversation = client.conversations.create(
    metadata={"department": "cardiology", "acuity": "unconfirmed"},
)

print(conversation.id)
```

Seed it with prior history by passing `items` — up to 20 user messages, text only (see [Items](#items) to add more later):

```json
{
  "metadata": { "department": "cardiology" },
  "items": [
    { "role": "user", "content": "Patient reports chest pain since this morning." }
  ]
}
```

Orgs configured for [zero data retention](/using-the-api/data-retention/#zero-data-retention)
cannot create conversations (`403` `zero_data_retention`). Send the full
input on each `/v1/responses` request instead.

## Retrieve a conversation

```
GET /v1/conversations/{conversation_id}
```

```bash title="cURL"
curl --request GET \
  --url https://api.subq.ai/v1/conversations/conv_abc123 \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const conversation = await client.conversations.retrieve(
  process.env.SUBQ_CONVERSATION_ID ?? "conv_abc123",
);

console.log(conversation.metadata);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

conversation = client.conversations.retrieve(
    os.getenv("SUBQ_CONVERSATION_ID", "conv_abc123")
)

print(conversation.metadata)
```

Returns the [conversation object](#the-conversation-object). An unknown id,
or one that belongs to another organization, returns `404`
`conversation_not_found`.

## Update a conversation

```
POST /v1/conversations/{conversation_id}
```

`metadata` is required and **replaces** the stored tags. Resend every key
you want to keep; send `{}` to clear them.

```bash title="cURL"
curl --request POST \
  --url https://api.subq.ai/v1/conversations/conv_abc123 \
  --header "Authorization: Bearer $SUBQ_API_KEY" \
  --header 'Content-Type: application/json' \
  --data '
{
  "metadata": {
    "department": "cardiology",
    "acuity": "urgent"
  }
}
'
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

// metadata replaces the stored tags entirely — resend every key you want to keep.
const conversation = await client.conversations.update(
  process.env.SUBQ_CONVERSATION_ID ?? "conv_abc123",
  { metadata: { department: "cardiology", acuity: "urgent" } },
);

console.log(conversation.metadata);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

# metadata replaces the stored tags entirely — resend every key you want to keep.
conversation = client.conversations.update(
    os.getenv("SUBQ_CONVERSATION_ID", "conv_abc123"),
    metadata={"department": "cardiology", "acuity": "urgent"},
)

print(conversation.metadata)
```

## Delete a conversation

```
DELETE /v1/conversations/{conversation_id}
```

Deletes the conversation. Irreversible.

```bash title="cURL"
curl --request DELETE \
  --url https://api.subq.ai/v1/conversations/conv_abc123 \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const result = await client.conversations.delete(
  process.env.SUBQ_CONVERSATION_ID ?? "conv_abc123",
);

console.log(result.deleted);
```

```py title="Python"
client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

result = client.conversations.delete(
    os.getenv("SUBQ_CONVERSATION_ID", "conv_abc123")
)

print(result.deleted)
```

```json
{
  "id": "conv_abc123",
  "object": "conversation.deleted",
  "deleted": true
}
```

## Items

List, add, retrieve, or delete the individual messages, function calls, and
web searches inside a conversation.

| Method   | Path                                                  | Description      |
| -------- | ----------------------------------------------------- | ---------------- |
| `POST`   | `/v1/conversations/{conversation_id}/items`           | Add items        |
| `GET`    | `/v1/conversations/{conversation_id}/items`           | List items       |
| `GET`    | `/v1/conversations/{conversation_id}/items/{item_id}` | Retrieve an item |
| `DELETE` | `/v1/conversations/{conversation_id}/items/{item_id}` | Delete an item   |

Add items the same way you [seed a conversation](#create-a-conversation) —
`role: "user"`, text only:

```json
{
  "items": [
    { "role": "user", "content": "Follow-up: any allergies on file?" }
  ]
}
```

Reasoning and function-call outputs aren't individually addressable — they
stay attached to their parent message, unlike OpenAI's API. List paginates
with `limit` (1–100, default 20), `order`, and an `after` cursor, same as
[Files](/endpoints/files-api/#list-files). Delete returns the parent
conversation object, not a deletion envelope.

## Errors

```json
{
  "error": {
    "message": "Conversation 'conv_abc123' not found.",
    "type": "invalid_request_error",
    "code": "conversation_not_found"
  }
}
```

| HTTP | `code`                   | Meaning                                                                   |
| ---- | ------------------------ | ------------------------------------------------------------------------- |
| 401  | `invalid_api_key`        | Missing or invalid Bearer token                                           |
| 404  | `conversation_not_found` | Id doesn't exist or belongs to another organization                       |
| 404  | `item_not_found`         | Item doesn't exist in the conversation, or isn't individually addressable |
| 403  | `zero_data_retention`    | Org cannot store conversations                                            |
| 403  | `access_denied`          | API key does not belong to an organization                                |
| 503  | `authorization_failed`   | Key lookup temporarily unavailable; retry                                 |

See [Authentication](/using-the-api/authentication/) for auth and credit errors.

## Related

- [Responses API](/endpoints/responses-api/) — continue a stored conversation directly with the `conversation` field, or chain turns with `previous_response_id`; every response includes a `conversation` field either way.
- [Authentication](/using-the-api/authentication/) — API keys and request headers.

---
title: Models API
description: List the model IDs available to your API key.
---

Use the Models API to list the model IDs available to your API key.

## List models

```
GET /v1/models
```

### Request

```bash title="cURL"
curl --request GET \
  --url https://api.subq.ai/v1/models \
  --header "Authorization: Bearer $SUBQ_API_KEY"
```

```ts title="TypeScript"
import OpenAI from "openai";

const client = new OpenAI({
  apiKey: process.env.SUBQ_API_KEY,
  baseURL: "https://api.subq.ai/v1",
});

const models = await client.models.list();
console.log(models.data.map((model) => model.id));
```

```py title="Python"
import os
from openai import OpenAI

client = OpenAI(
    api_key=os.environ["SUBQ_API_KEY"],
    base_url="https://api.subq.ai/v1",
)

models = client.models.list()
print([model.id for model in models.data])
```

### Response

The response follows the OpenAI-compatible list shape. Use a returned `id` with
the endpoint that supports that model.

```json
{
  "object": "list",
  "data": [
    {
      "id": "subq-preview",
      "name": "SubQ Preview",
      "object": "model",
      "created": 0,
      "owned_by": "subquadratic"
    },
    {
      "id": "subq-snap-preview",
      "name": "SubQ Snap Preview",
      "object": "model",
      "created": 0,
      "owned_by": "subquadratic"
    }
  ]
}
```

For current model capabilities and preview constraints, see [Models](/using-the-api/models/).

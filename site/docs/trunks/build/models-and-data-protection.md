# Models and data protection

> Trunks v0.5.0. Source: https://github.com/vegeta-labs/trunks/blob/7b32c954f7017b87fa3686d72b3a303048fd018b/docs/en/models-and-data-protection.md

A language model does two jobs only:

- it **classifies** an email into the categories of `cases.yaml`
- it **extracts fields**, such as amount, payment date and reference.

Each job is one request: the input is redacted text and a JSON Schema, and the output is JSON that the app checks.
There is no agent loop, and the model is given no tools. Everything else is done by fixed code: risk, linking,
deadlines, template choice and the reply text.

## Providers

| `provider` | `location` | What it is |
|---|---|---|
| `anthropic` | always `external` | The hosted model API. Needs `dpa`, `no_training`, `region` and the API key. |
| `ollama` | `local` (as you declare it) | A model on your own machine or network, reached at `ollama_host`. You run Ollama yourself; it is not part of the Compose file. |
| `replay` | `local` | Recorded model replies, read from `replay_dir`. Used for tests, the evaluation and the demo. A missing recording is an error; it never calls a real model. |

`model_id` names the exact model, for example `claude-opus-5-5`. If you change the model, change the configuration. The
configuration change is audited, and every open Case is processed again.

### Example: hosted provider with an agreement

```yaml
model:
  provider: anthropic
  model_id: claude-opus-5-5
  location: external
  region: eu
  dpa: true
  no_training: true
  api_key_env: ANTHROPIC_API_KEY
```

Put the API key in `secrets/anthropic_api_key`.

### Example: local model

```yaml
model:
  provider: ollama
  model_id: <the model name in your Ollama>
  location: local
  dpa: false
  no_training: true
  ollama_host: http://ollama.internal.example:11434
```

- `ollama_host` must not contain a user name or password.
- If the host does not look local (loopback, a private network address, a single-label service name or `.local`), the
  app starts but warns.

## Start-up checks (the model policy)

`serve` checks the model block before anything else starts.

| Situation | Result |
|---|---|
| No `model` block | **refuses to start** |
| `provider: anthropic` with `location: local` | **configuration error**: the hosted provider is always external |
| External provider with `dpa: false` and `allow_without_dpa` not set | **refuses to start** |
| External provider with `dpa: false` and `allow_without_dpa: true` | starts; **warning** in the start-up log and at the top of the review UI |
| External provider whose `region` is not UK / EEA, and no `transfer_basis` | starts; **warning** |
| `no_training: false` | starts; **warning** |
| `provider: anthropic` and the API key is empty | **refuses to start** |
| `ollama` declared local, host does not look local | starts; **warning** |

The UK / EEA test accepts region values such as `uk`, `gb`, `eu`, `eea`, `europe`, or an EEA country code (`de`,
`ie`, `fr` and so on).

These fields are your own **declarations**. The app cannot check a contract. Record the agreement itself, and the
transfer basis, in your [DPIA](https://vegeta-ops.vercel.app/docs/trunks/build/dpia-template.md).

## What is sent to a model

Only **redacted** text. There is no setting that turns redaction off, and it applies to local models too.

The text sent is:

- the subject
- display names
- the body, including quoted earlier emails
- attachment file names
- the text of attachments that are **not** possible-KYC.

Before any model call, code replaces sensitive values with placeholders:

| Value | Placeholder |
|---|---|
| IBAN-shaped strings (whatever the check digits), UK account numbers near "account", "acc", "a/c" or "sort code" | `[ACCOUNT_n]` |
| UK sort codes | `[SORTCODE_n]` |
| UK passport numbers near "passport", UK driving licence numbers, National Insurance numbers | `[ID_n]` |
| Dates of birth near "born", "DOB" or "date of birth" | `[DOB_n]` |
| UK postcodes, with their line and up to three address lines above | `[ADDRESS_n]` |
| Phone numbers | `[PHONE_n]` |
| The local part of email addresses (the domain is kept) | `[EMAIL_n]@domain` |
| Names of people in your directory | `[NAME_n]` |

How the placeholders behave:

- Once a value is recognised anywhere in an email, every occurrence of it in that email gets the same placeholder.
- The table of placeholders and real values stays in your database, encrypted.
- Account, sort code, ID and date-of-birth placeholders are **never** turned back into values. They are shown masked,
  for example "account ending 5432". A model output field that contains one of them is discarded.
- Name, email, phone and address placeholders are restored only for display in the review UI.
- Amounts, payment references and UETRs are not redacted, because classification needs them. A reference is matched
  on the original text before redaction.

### Possible-KYC attachments go to no model

Before any model call, code (not a model) decides whether an attachment **may be a KYC document**. It is treated as
possible-KYC if any of these hold:

1. Its file name contains a KYC word, for example passport, driving licence, utility, bank statement, proof of
   address, certificate of incorporation, or the listed non-English equivalents.
2. Its text contains a passport machine-readable line, a KYC word, or two of "date of birth", "place of birth" and
   "nationality".
3. It is an image, unless it is a small inline signature image (see below).
4. It is a PDF with no text layer on some or all pages.
5. It cannot be checked: parsing failed, timed out, was over a limit, was encrypted, was nested too deep, or the type
   is unknown.

The content of a possible-KYC attachment is **never sent to any model**, local or external. The model sees only its
redacted file name and its type. The Case is marked "possible KYC attachment", and the attachment is transferred to
your KYC target (see [Retention](https://vegeta-ops.vercel.app/docs/trunks/build/retention.md)).

**Small inline signature images** are the one exception. An image is not caught by rule 3 or rule 5 (its file name is still checked by rule 1) when all of these hold:
it sits in the email itself (not in an attached email), it has a `Content-ID` that an `<img src="cid:…">` in the HTML
body points to (and no other part shares that `Content-ID`), it is not marked as an attachment, the virus scan passed,
it is a single-frame PNG, JPEG or GIF whose file structure passes a strict check (no unlisted chunks or segments, no raw
embedded image signature, nothing after the end), and its long side, short side and size are within `kyc.inline_image` (defaults: 400 px,
150 px, 51,200 bytes). The Case shows it as "small inline image (treated as a signature image)".

What this changes: such an image is not transferred and stays in the stored email until normal retention deletes it.
Its content still reaches no model, because images are never read. The accepted cost: an ID document image
scaled down to fit the limits (a whole ID card at 238 × 150 px fits the defaults; a card or passport page at about
470 × 300 px fits the maximum limits and is readable), or data hidden in encoded form in an allowed image's text or metadata (at most 16,384 bytes in total), would also stay in the stored email instead of being transferred. You can widen the limits up to
1280 px, 300 px and 102,400 bytes, which widens this cost. Measure your own mailbox first with
`scripts/measure-inline-images.ts` (Gmail, read-only, prints numbers only).

The app does no OCR. The content of images and scans is never read.

### What is recorded about each model call

Each call is audited with:

- provider, model name and model version
- prompt version and schema version
- a hash of the input.

The full request and response are stored encrypted in the audit detail table. The audit row keeps only their hash.
The detail is deleted with the email at the end of its retention period.

A model call is tried at most twice per request. If both attempts fail, the email is classified `unclassified` and its
model fields are left empty. A person then reviews it as usual.

## What the model never does

- **It writes no outbound text.** Every reply is a fixed template from `templates.yaml`, with values filled in by
  code from your directory, your ledger and fields a person has confirmed.
- **It does not choose the template.** Code chooses the template from the category and the rules. A person may pick
  another template or edit the body of an ordinary template.
- **It cannot lower a risk level.** Risk comes from category floors and fixed rules. Only an approver can lower risk,
  and must give a reason.
- **It has no tools and no access** to mailboxes, the database, the network or any action.
- The prompt marks the email content as untrusted data, not instructions. This is only a secondary defence. The real
  defence is that the output is checked data with no power to act.
- Its output never makes a payment count as received, and never applies bank details. See the
  [Security model](https://vegeta-ops.vercel.app/docs/trunks/build/security-model.md).

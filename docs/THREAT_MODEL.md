# Threat model

What polanon protects against, and what it does not. Read it before relying on the library for
anything that matters. It is engineering documentation, not legal advice.

## What the library is for

An application wants a cloud language model to work on text that holds personal data. polanon
replaces that data with tokens such as `<OSOBA_1>` inside the application's own process, so only
tokens reach the provider, and puts the originals back into the answer, also while it streams.

## Trust boundaries

| Zone | Holds | Trusted? |
|---|---|---|
| Your process | the original text, the mapping, restored answers | yes |
| The mapping, wherever you keep it | token to original value | yes, and as sensitive as the documents |
| The LLM provider | masked text only | **no**, this is the boundary the library exists for |
| A stage-2 judge on Ollama | masked text, on your own machine | yes |
| `RemoteJudge` | masked text, sent to an API | **no**, a testing aid only |
| The key of `Pseudonyms` | what turns a guessed value into its stable token | yes, and as sensitive as the mapping |
| A search index with stable tokens | masked passages and their embeddings | **no** more than the provider: it is masked text |
| `polanon-gateway` | the calls of the tools that use it, in the clear, and their keys | yes: it runs on the operator's machine, and the operator answers for it |

## What is protected

- **Deterministic identifiers.** PESEL, NIP, REGON, ID card numbers, IBAN and payment cards are
  matched by pattern and confirmed by checksum, so detection is near-certain and false positives are
  rare. KRS numbers and passports are recognised next to their label.
- **Contact details and devices.** E-mail addresses, also with "[at]" written out, phone numbers,
  street addresses and postcodes, links to a person's profile (LinkedIn, GitHub and GitHub Pages,
  GitLab, social media) up to the handle, IPv4 and IPv6, MAC addresses, VINs, vehicle registrations
  after their label, birth dates after theirs, in Polish or English.
- **Credentials.** API keys, JWTs, private key blocks and `password=` style assignments, masked whole
  with whatever was found inside them, so pasted logs and configuration files do not leak secrets.
- **People and companies by rule.** Polish first names in all seven cases, in any letter case and
  without Polish letters, with the surname that agrees with them; companies by their legal form
  (`Sp. z o.o.`, `S.A.`, `Ltd`, `GmbH`); names on foreign documents after a form of address, a label
  or a closing formula; and whatever you put on a denylist.
- **Every later occurrence of a masked value.** Pass the mapping from the latest result to the next
  call and a value keeps its token wherever it appears again: in capitals, across a line break or a run of
  spaces, with a no-break space, an invisible character or a decomposed accent in it, and with an
  identifier's groups written apart or together. The surname of a masked person and the handle of a
  masked profile link count as masked values of their own, so "Kowalski" after "Jan Kowalski" and
  "jkowalski" after "github.com/jkowalski" are masked too. `mask_known_values` does the same for
  text masked earlier, such as conversation history sent again.
- **Your own placeholders.** A token such as `<PESEL_1>` already in your text is never handed to real
  data.
- **The answer.** `StreamRestorer` never splits a token across chunks, and `sweep` reports tokens the
  model invented and personal data it introduced.
- **The library's own output.** Errors and log lines name types, counts, lengths and guards, not
  values; a judge that fails says how, without quoting what it was sent or the key it used.

## What is not protected

- **An identifier that fails its checksum.** A PESEL, NIP, IBAN or ID card number with a wrong
  check digit is not masked, even right after its label: a mistyped number, or one an OCR pass
  misread, goes out as written. The checksum is what keeps random digits from being masked, and
  the price is this.
- **Names and places are found partly by rule, partly statistically.** A surname on its own in
  lowercase ("napisz do kowalskiego") or in a text where the full name never appears, a rare or
  foreign first name and every place name depend on the spaCy model, which leans on capital letters and misses what people type in lowercase. A miss
  is a detection gap, not a bypass, but the value still reaches the provider. The stage-2 judge
  exists to narrow this gap, not to close it.
- **A one-word name later written in lowercase.** A capitalised one-word name is not matched in all
  lowercase, because many Polish surnames are also ordinary words (Zima, Kot, Wilk): "kowalska
  dzwoniła" after "Pani Kowalska" goes out unless a detector recognises it on its own. Once one
  does, that spelling has a token of its own.
- **A handle or a personal domain on its own.** A login is recognised inside a link to a profile
  on a known site, and from there wherever it stands. A login with no such link anywhere in the
  text ("mój GitHub to jkowalski") and a personal domain ("jankowalski.dev") are ordinary words to
  the rules: put them on the denylist, or report them from a guard of your own, when you know them.
- **A short number inside a longer one.** A PIN or another number under six digits is not masked
  inside a date, an amount or a longer number ("15.04.2025" when the PIN is 2025), so the model does
  not learn which numbers look like it. Where it stands alone it is masked.
- **Foreign documents are read by their labels and formats.** Tax and company numbers, accounts,
  phones, addresses and postcodes are found where a document prints them next to a label or in an
  official shape. A name in running English or German prose, a city and any format the rules have
  never seen depend on the Polish language model, which reads those languages poorly. On a plainly
  English line, such as the system prompt of an agent, it took ordinary words for names, so there
  only a capitalised name in mid-sentence is kept: one that opens an English sentence is left to
  the rules, which find a Polish first name, and nothing else of it. On a line too short to show
  a language, a name in lowercase is kept only with a Polish first name in it, and a name with a
  "_" only then too: a place typed in lowercase on such a line, "gdynia" alone, is not masked.
- **Identification by context.** "The finance director of the only steelworks in Stalowa Wola" names
  a person without naming them. The judge is asked to catch exactly this; a small local model will
  not catch all of it.
- **Polish inflection of tokens.** A model may write `<OSOBA_1>a`. Restoration matches tokens
  exactly, so the suffix survives and the sentence reads oddly. It does not leak anything.
- **The mapping.** It is the key that undoes the masking. The library keeps it in memory and hands it
  to you; storing it encrypted, expiring it and keeping it out of logs is your application's job.
- **What you send yourself.** The library masks the text you pass it. A system prompt, a file name,
  tool arguments or metadata built from unmasked data are outside it. Before a call,
  `mask_known_values(payload, mapping) == payload` confirms that no value the mapping holds is left
  where the library would mask it.
- **An allowlist that is too generous.** A name on the allowlist reaches the provider whenever a
  model or the judge takes it for a name. The list cannot release an identifier, an e-mail address,
  a denylisted word or a value that already has a token; a client's name added to it is sent.
- **The provider's side.** Masked text and its context are still processed and probably logged by
  the provider, and message sizes and timing are visible to it.
- **The law.** Masking is pseudonymisation, not anonymisation in the GDPR sense: whoever holds the
  mapping holds personal data. So does whoever holds stable tokens and the key that made them.

## Stable pseudonyms for search indexes

With `Anonymizer(pseudonyms=Pseudonyms(key))` a token is no longer numbered per conversation: it is
computed from the value with HMAC-SHA256 under a key, so the same person has the same token in
every document of an index, in every question and in every conversation that uses the key. That
is what lets a masked question find the masked passages, and it changes the risks.

- **Linking.** Whoever reads masked text can tell which passages, questions and conversations are
  about the same person, without knowing who it is. The provider sees it across every call, and so
  does anyone with the index. Tokens numbered per conversation hid that between conversations.
  Use stable tokens only where the linking is the purpose, as for an index, and leave ordinary
  chats numbered per conversation. Give each company its own key, and an index that must not be
  linked to another its own `scope=`: the same value then gets unrelated tokens.
- **Frequency.** The most frequent token of a sales index is probably the biggest client, and a
  token that turns up with a known date, amount or place can be matched to a person by someone who
  knows those. Masking hides names, not the shape of the data around them.
- **The key.** With the key, anyone holding the index can compute the token of a guess and look
  for it. Identifiers fall first: all PESEL numbers of people born from 1900 to 2025 are about
  4.6×10⁸ guesses, which one CPU core computes in a quarter of an hour and a graphics card in well
  under a second. Common first names with common surnames follow. A leaked key is close to a leaked
  mapping for everything that can be enumerated: keep it in a secret manager or a KMS, apart from
  the index and the mapping store, out of the code and the logs. The library never writes it to a
  message, a representation or a pickle.
- **Why not a plain hash.** A hash with no key is the same computation without the secret: anyone
  holding the index can hash every PESEL, phone number or name from a list and read the tokens
  back. HMAC needs the key for each guess. A slow password hash on top of the key would delay
  enumeration after a leak, but every question and every passage computes hundreds of tokens, and
  the key is the protection that has to hold anyway.
- **A masking service is an oracle.** Whatever masks chosen text with the key confirms guesses:
  type a candidate PESEL into a question, read its token in the masked preview, look for it in the
  index. Restrict who can call it, rate-limit it and log it, as one would for the key itself.
- **Erasure.** Deleting a person's entry from the mapping store does not unlink them. The token is
  still in the index, and the key turns a guessed value back into it. To erase a person, delete or
  mask again every passage that holds `pseudonyms.token(value, type)`, and the surname's token
  where nobody else with that surname is indexed; retention that only deletes the mapping leaves
  the index linkable.
- **A new key.** Changing the key, the scope or the number of digits changes every token, so an
  index built before no longer matches the questions: build it again from the sources, or map the
  tokens one to one through the store. `pseudonyms.settings`, stored with the index, tells the
  two apart, and `key_id` names a key without revealing it.
- **Collisions.** Two values of one type can share a twelve-digit token, with a chance of about 1
  in 20,000 at 10,000 values and 1 in 200 at 100,000. Where they meet, in the store or in one text,
  the second gets four digits more and the collision is recorded; a question that collides with an
  indexed value finds nothing instead of the other person's passages. Two processes that index the
  two values at once are kept apart by the store's unique key on the token.
- **What the index holds.** The masked passages and their embeddings: an embedding can be inverted
  into an approximation of its text, so treat it as the masked text itself. A value no detector
  found is in both in the clear, as it would be in a prompt. The mapping store holds the originals
  and must be encrypted and kept apart from the index; a mapping copied into a passage's metadata
  is stored and searched with it.
- **Names the store already holds.** The store keeps the surname of every indexed person whose
  first name the rules know, and a question or a passage is looked up in it for every run of up to
  four words that could be a name. That masks a surname written alone, which no rule would, and it
  never releases one: the allowlist does not apply to a value the store holds. One surname is one
  token, so two people who share it are linked by it, as they are by the surname itself. A word
  that names no stored value, and a lone word in lowercase, are not masked this way.

## Haystack pipelines

The components in `polanon.integrations.haystack` keep the document store and the embeddings to
masked text: tokens in the content and in every string of `meta`, an `id` computed from the masked
text, and in place of every string of `meta` shaped like a SHA-256, which is what splitters write
there and a plain hash of an original text, the `id` of its masked twin or a keyed fingerprint. A
document with a `blob` or an embedding is refused. What the pipeline around them does is the
application's part:

- **Content tracing.** With `HAYSTACK_CONTENT_TRACING_ENABLED`, Haystack sends what every component
  receives to the tracing backend, and the maskers receive the originals. It is off by default;
  keep it off, or the tracer holds the documents and the questions in the clear.
- **Failure snapshots.** A run that fails attaches a snapshot of the inputs to its
  `PipelineRuntimeError`, and writes it to disk with `HAYSTACK_PIPELINE_SNAPSHOT_SAVE_ENABLED`.
  Do not log the snapshot. The error's message names what failed, not the values.
- **What is not masked.** Numbers and dates in `meta` stay as they are, and so do the positions a
  splitter records, which tell where a passage stood and how long it was, not what it said. Put
  personal data in strings, as everywhere in this library.
- **What comes out of `PolanonRestorer`.** Restored replies and documents are originals. Never
  write them back to a document store or send them to a model.
- **Order.** Masking after a splitter reads each passage alone, and a value cut in two by the
  splitter may not be recognised. Mask whole documents, before the splitter, and split by words,
  sentences or passages: a splitter that counts characters cuts tokens in two.
- **Two documents that differ only in a value written differently**, such as "Jan Kowalski" and
  "JAN KOWALSKI", mask to one text and one `id`, and a writer keeps one of them.
- **An `id` you choose** is masked like text and stays in the store; keep personal data out of it
  where you can.
- **A saved pipeline** holds the name of the key's variable, never the key, and the mapping store
  only as its own `to_dict` describes it.

## The gateway

`polanon-gateway` masks the calls of tools that speak the OpenAI API and restores their answers.
It is software the operator runs on their own machine, not a service: nobody else holds the
calls, the keys or the logs. What it protects:

- **What reaches the provider.** Every message, tool result and earlier tool call is masked, and
  so are the descriptions, titles and example values of the tools and of an answer format; a
  participant's `name` is left out, and before a call leaves its whole payload is searched once more
  for every original value, by the rules the masking follows; a call that still holds one is not
  sent. Endpoints other than chat completions, the Responses API, embeddings and the list of
  models are refused rather than passed on, and so are images, files and audio, unless
  `--drop-unsupported` leaves them out. A Responses API call that keeps the conversation at the
  provider, with `previous_response_id` or `conversation`, is refused: the gateway holds no mapping
  between calls to restore it with. Encrypted reasoning and compaction pass unread; the provider
  sealed them from masked text, so they hold tokens, not values.
- **Who can use it.** It listens on `127.0.0.1`. On any other address it refuses to start without
  `POLANON_GATEWAY_KEY`, which every client must then send, compared in constant time.
- **What it keeps.** Nothing on disk: each call is masked and restored with a mapping that lives as
  long as the call. The log holds the path, the status, the time and counts of masked types.

What it does not protect, and is the operator's part:

- **The machine.** Calls arrive in the clear and answers leave restored. Anyone who can read the
  gateway's memory, or a tool's own history, reads them; so can anything the operator puts in
  front of it, such as a reverse proxy that logs bodies.
- **The keys.** By default the client's key is passed on to the provider; `POLANON_UPSTREAM_KEY`
  and `POLANON_GATEWAY_KEY` are read from the environment and never printed. Keep them out of shell
  history and out of files others can read.
- **Encryption on the network.** The gateway speaks plain HTTP. Beyond `127.0.0.1`, put it behind
  TLS, or keep it on a network the operator trusts.
- **Detection.** The gateway masks what the guards find, no more: run it with the spaCy model, and
  read "Residual risk" below. The stage-2 judge is not used.
- **What the provider learns anyway.** The structure of the conversation, its length and timing,
  the shape of the tools (their names, types and parameter names), and whatever the tokens' context
  gives away.

## Residual risk to accept consciously

Detection is imperfect, so the right mental model is "much less personal data leaves, not none".
Measure on documents like yours before you rely on it: `benchmarks/run.py` scores the library on
annotated documents and shows what it misses.

## Reporting

See `SECURITY.md`. A way to get a value that has a token past the masking, or into a log or an
error, is a security bug and we want to hear about it privately.

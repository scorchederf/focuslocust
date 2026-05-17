---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Adreno A7xx SDS->RB privilege bypass (GPU SMMU takeover to Kernel R/W)

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-binary-exploitation-linux-kernel-exploitation-adreno-a7xx-sds-rb-priv-bypass-gpu-smmu-kernel-rw` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/binary-exploitation/linux-kernel-exploitation/adreno-a7xx-sds-rb-priv-bypass-gpu-smmu-kernel-rw.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Adreno A7xx SDS->RB privilege bypass (GPU SMMU takeover to Kernel R/W)](../../topics/binary-exploitation/adreno-a7xx-sds-rb-privilege-bypass-gpu-smmu-takeover-to-kernel-r-w.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-binary-exploitation-linux-kernel-exploitation-adreno-a7xx-sds-rb-priv-bypass-gpu-smmu-kernel-rw |
| name | Adreno A7xx SDS->RB privilege bypass (GPU SMMU takeover to Kernel R/W) |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/binary-exploitation/linux-kernel-exploitation/adreno-a7xx-sds-rb-priv-bypass-gpu-smmu-kernel-rw.md |

## Preserved Source Material

````yaml
_body: "# Adreno A7xx SDS->RB privilege bypass (GPU SMMU takeover to Kernel R/W)\n\n{{#include ../../banners/hacktricks-training.md}}\n\
  \nThis page abstracts an in-the-wild Adreno A7xx microcode logic bug (CVE-2025-21479) into reproducible exploitation techniques:\
  \ abusing IB-level masking in Set Draw State (SDS) to execute privileged GPU packets from an unprivileged app, pivoting\
  \ to GPU SMMU takeover and then to a fast, stable kernel R/W via a dirty-pagetable trick.\n\n- Affected: Qualcomm Adreno\
  \ A7xx GPU firmware prior to a microcode fix that changed masking of register $12 from 0x3 to 0x7.\n- Primitive: Execute\
  \ privileged CP packets (e.g., CP_SMMU_TABLE_UPDATE) from SDS, which is user-controlled.\n- Outcome: Arbitrary physical/virtual\
  \ kernel memory R/W, SELinux disable, root.\n- Prereq: Ability to create a KGSL GPU context and submit command buffers that\
  \ enter SDS (normal app capability).\n\n## Background: IB levels, SDS and the $12 mask\n\n- The kernel maintains a ringbuffer\
  \ (RB=IB0). Userspace submits IB1 via CP_INDIRECT_BUFFER, chaining to IB2/IB3.\n- SDS is a special command stream entered\
  \ via CP_SET_DRAW_STATE:\n  - A6xx: SDS is treated as IB3\n  - A7xx: SDS moved to IB4\n- Microcode tracks the current IB\
  \ level in register $12 and gates privileged packets so they are only accepted when the effective level corresponds to IB0\
  \ (kernel RB).\n- Bug: A7xx microcode kept masking $12 with 0x3 (2 bits) instead of 0x7 (3 bits). Since IB4 & 0x3 == 0,\
  \ SDS was misidentified as IB0, allowing privileged packets from user-controlled SDS.\n\nWhy it matters:\n\n```\nA6XX  \
  \              | A7XX\nRB  & 3       == 0  |  RB  & 3       == 0\nIB1 & 3       == 1  |  IB1 & 3       == 1\nIB2 & 3   \
  \    == 2  |  IB2 & 3       == 2\nIB3 (SDS) & 3 == 3  |  IB3 & 3       == 3\n                    |  IB4 (SDS) & 3 == 0 \
  \  <-- misread as IB0 if mask is 0x3\n```\n\nMicrocode diff example (patch switched the mask to 0x7):\n\n```\n@@ CP_SMMU_TABLE_UPDATE\n\
  - and $02, $12, 0x3\n+ and $02, $12, 0x7\n@@ CP_FIXED_STRIDE_DRAW_TABLE\n- and $02, $12, 0x3\n+ and $02, $12, 0x7\n```\n\
  \n## Exploitation overview\n\nGoal: From SDS (misread as IB0) issue privileged CP packets to re-point the GPU SMMU to attacker-crafted\
  \ page tables, then use GPU copy/write packets for arbitrary physical R/W. Finally, pivot to a fast CPU-side R/W via dirty\
  \ pagetable.\n\nHigh-level chain\n- Craft a fake GPU pagetable in shared memory\n- Enter SDS and execute:\n  - CP_SMMU_TABLE_UPDATE\
  \ -> switch to fake pagetable\n  - CP_MEM_WRITE / CP_MEM_TO_MEM -> implement write/read primitives\n  - CP_SET_DRAW_STATE\
  \ with run-now flags (dispatch immediately)\n\nGPU R/W primitives via fake pagetable\n- Write: CP_MEM_WRITE to an attacker-chosen\
  \ GPU VA whose PTEs you map to a chosen PA -> arbitrary physical write\n- Read: CP_MEM_TO_MEM copies 4/8 bytes from target\
  \ PA to a userspace-shared buffer (batch for larger reads)\n\nNotes\n- Each Android process gets a KGSL context (IOCTL_KGSL_GPU_CONTEXT_CREATE).\
  \ Switching contexts normally updates SMMU tables in the RB; the bug lets you do it in SDS.\n- Excessive GPU traffic can\
  \ cause UI blackouts and reboots; reads are small (4/8B) and sync is slow by default.\n\n## Building the SDS command sequence\n\
  \n- Spray a fake GPU pagetable into shared memory so at least one instance lands at a known physical address (e.g., via\
  \ allocator grooming and repetition).\n- Construct an SDS buffer containing, in order:\n  1) CP_SMMU_TABLE_UPDATE to the\
  \ physical address of the fake pagetable\n  2) One or more CP_MEM_WRITE and/or CP_MEM_TO_MEM packets to implement R/W using\
  \ your new translations\n  3) CP_SET_DRAW_STATE with flags to run-now\n\nThe exact packet encodings vary by firmware; use\
  \ freedreno’s afuc/packet docs to assemble the words, and ensure the SDS submission path is taken by the driver.\n\n## Finding\
  \ Samsung kernel physbase under physical KASLR\n\nSamsung randomizes the kernel physical base within a known region on Snapdragon\
  \ devices. Brute-force the expected range and look for the first 16 bytes of _stext.\n\nRepresentative loop\n\n```c\nwhile\
  \ (!ctx->kernel.pbase) {\n  offset += 0x8000;\n  uint64_t d1 = kernel_physread_u64(ctx, base + offset);\n  if (d1 != 0xd10203ffd503233f)\
  \ continue;   // first 8 bytes of _stext\n  uint64_t d2 = kernel_physread_u64(ctx, base + offset + 8);\n  if (d2 == 0x910083fda9027bfd)\
  \ {           // second 8 bytes of _stext\n    ctx->kernel.pbase = base + offset - 0x10000;\n    break;\n  }\n}\n```\n\n\
  Once physbase is known, compute the kernel virtual with the linear map:\n\n```\n_stext = 0xffffffc008000000 + (Kernel Code\
  \ & ~0xa8000000)\n```\n\n## Stabilizing to fast, reliable CPU-side kernel R/W (dirty pagetable)\n\nGPU R/W is slow and small-granularity.\
  \ Pivot to a fast/stable primitive by corrupting your own process PTEs (“dirty pagetable”):\n\nSteps\n- Locate current task_struct\
  \ -> mm_struct -> mm_struct->pgd using the slow GPU R/W primitives\n- mmap two adjacent userspace pages A and B (e.g., at\
  \ 0x1000)\n- Walk PGD->PMD->PTE to resolve A/B’s PTE physical addresses (helpers: get_pgd_offset, get_pmd_offset, get_pte_offset)\n\
  - Overwrite B’s PTE to point to the last-level pagetable managing A/B with RW attributes (phys_to_readwrite_pte)\n- Write\
  \ via B’s VA to mutate A’s PTE to map target PFNs; read/write kernel memory via A’s VA, flushing TLB until a sentinel flips\n\
  \n<details>\n<summary>Example dirty-pagetable pivot snippet</summary>\n\n```c\nuint64_t *map = mmap((void*)0x1000, PAGE_SIZE*2,\
  \ PROT_READ|PROT_WRITE,\n                     MAP_PRIVATE|MAP_ANONYMOUS, 0, 0);\nuint64_t *page_map = (void*)((uint64_t)map\
  \ + PAGE_SIZE);\npage_map[0] = 0x4242424242424242;\n\nuint64_t tsk = get_curr_task_struct(ctx);\nuint64_t mm = kernel_vread_u64(ctx,\
  \ tsk + OFFSETOF_TASK_STRUCT_MM);\nuint64_t mm_pgd = kernel_vread_u64(ctx, mm + OFFSETOF_MM_PGD);\n\nuint64_t pgd_off =\
  \ get_pgd_offset((uint64_t)map);\nuint64_t phys_pmd = kernel_vread_u64(ctx, mm_pgd + pgd_off) & ~((1<<12)-1);\nuint64_t\
  \ pmd_off = get_pmd_offset((uint64_t)map);\nuint64_t phys_pte = kernel_pread_u64(ctx, phys_pmd + pmd_off) & ~((1<<12)-1);\n\
  uint64_t pte_off = get_pte_offset((uint64_t)map);\nuint64_t pte_addr = phys_pte + pte_off;\nuint64_t new_pte = phys_to_readwrite_pte(pte_addr);\n\
  kernel_write_u64(ctx, pte_addr + 8, new_pte, false);\nwhile (page_map[0] == 0x4242424242424242) flush_tlb();\n```\n\n</details>\n\
  \n## Detection\n\n- Telemetry: alert if CP_SMMU_TABLE_UPDATE (or similar privileged opcodes) appears outside RB/IB0, especially\
  \ in SDS; monitor anomalous bursts of 4/8-byte CP_MEM_TO_MEM and excessive TLB flush patterns\n\n## Impact\n\nA local app\
  \ with GPU access can execute privileged GPU packets, hijack the GPU SMMU, achieve arbitrary kernel physical/virtual R/W,\
  \ disable SELinux and obtain root on affected Snapdragon A7xx devices (e.g., Samsung S23). Severity: High (kernel compromise).\n\
  \n### See also\n\n{{#ref}}\npixel-bigwave-bigo-job-timeout-uaf-kernel-write.md\n{{#endref}}\n\n## References\n\n- [CVE-2025-21479:\
  \ Adreno A7xx SDS->RB privilege bypass to kernel R/W (Samsung S23)](https://xploitbengineer.github.io/CVE-2025-21479)\n\
  - [Mesa freedreno afuc disassembler README (microcode + packets)](https://gitlab.freedesktop.org/mesa/mesa/-/blob/c0f56fc64cad946d5c4fda509ef3056994c183d9/src/freedreno/afuc/README.rst)\n\
  - [Google Project Zero: Attacking Qualcomm Adreno GPU (SMMU takeover via CP packets)](https://googleprojectzero.blogspot.com/2020/09/attacking-qualcomm-adreno-gpu.html)\n\
  - [Dirty pagetable (archive)](https://web.archive.org/web/20240425043203/https://yanglingxi1993.github.io/dirty_pagetable/dirty_pagetable.html)\n\
  \n{{#include ../../banners/hacktricks-training.md}}"
_relative_path: binary-exploitation/linux-kernel-exploitation/adreno-a7xx-sds-rb-priv-bypass-gpu-smmu-kernel-rw.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/binary-exploitation/linux-kernel-exploitation/adreno-a7xx-sds-rb-priv-bypass-gpu-smmu-kernel-rw.md
````

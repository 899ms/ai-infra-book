<!-- 从 ultra-architecture.html 迁移的资料快照；原始 HTML SHA-256: 227bffbd0832549ab72790574f1bf34d5262b87ac617802cbe5b2d83aba5a550。 -->

[Data Center / Cloud](https://developer.nvidia.com/blog/category/data-center-cloud/)

English中文

# Inside NVIDIA Blackwell Ultra: The Chip Powering the AI Factory Era

![Blackwell Ultra illustration.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/Blackwell-Ultra-1024x576-png.webp)

Aug 22, 2025

By [Kyle Aubrey](https://developer.nvidia.com/blog/author/kaubrey/ "Posts by Kyle Aubrey") and [Nick Stam](https://developer.nvidia.com/blog/author/nstam/ "Posts by Nick Stam")

Like

[ Discuss (1)](#entry-content-comments)

- [L](https://www.linkedin.com/sharing/share-offsite/?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Finside-nvidia-blackwell-ultra-the-chip-powering-the-ai-factory-era%2F)
- [T](https://twitter.com/intent/tweet?text=Inside+NVIDIA+Blackwell+Ultra%3A+The+Chip+Powering+the+AI+Factory+Era+%7C+NVIDIA+Technical+Blog+https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Finside-nvidia-blackwell-ultra-the-chip-powering-the-ai-factory-era%2F)
- [F](https://www.facebook.com/sharer/sharer.php?u=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Finside-nvidia-blackwell-ultra-the-chip-powering-the-ai-factory-era%2F)
- [R](https://www.reddit.com/submit?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Finside-nvidia-blackwell-ultra-the-chip-powering-the-ai-factory-era%2F&title=Inside+NVIDIA+Blackwell+Ultra%3A+The+Chip+Powering+the+AI+Factory+Era+%7C+NVIDIA+Technical+Blog)
- [E](mailto:?subject=I'd%20like%20to%20share%20a%20link%20with%20you&body=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Finside-nvidia-blackwell-ultra-the-chip-powering-the-ai-factory-era%2F)

![](data:image/svg+xml;base64,<svg class="nv-ai-summary__icon" xmlns="http://www.w3.org/2000/svg" width="25" height="25" viewbox="0 0 25 25" fill="none" aria-hidden="true">
                <path fill="currentColor" fill-rule="evenodd" clip-rule="evenodd" d="M22.4915 15.3019C22.294 15.3047 22.0976 15.3316 21.9066 15.3819L20.254 12.9019L21.905 10.4219C22.0967 10.4731 22.2933 10.4987 22.4915 10.5019C22.8844 10.5032 23.2716 10.4078 23.619 10.2241C23.9665 10.0404 24.2635 9.77405 24.4839 9.44845C24.7044 9.12285 24.8415 8.74799 24.8832 8.35687C24.925 7.96575 24.8701 7.57035 24.7233 7.20547C24.5766 6.84059 24.3425 6.51741 24.0417 6.26437C23.7409 6.01134 23.3825 5.8362 22.9982 5.75437C22.6139 5.67255 22.2154 5.68654 21.8378 5.79512C21.4601 5.9037 21.1149 6.10354 20.8326 6.37706L15.2709 3.59305C15.2868 3.49705 15.2964 3.39946 15.2996 3.30186C15.2996 2.66534 15.0471 2.05489 14.5975 1.6048C14.1479 1.15471 13.5381 0.901855 12.9023 0.901855C12.2665 0.901855 11.6568 1.15471 11.2072 1.6048C10.7576 2.05489 10.5051 2.66534 10.5051 3.30186C10.5083 3.39946 10.5178 3.49705 10.5338 3.59305L4.97211 6.37706C4.68976 6.10267 4.34433 5.90202 3.96626 5.79281C3.58818 5.6836 3.18908 5.66918 2.80412 5.75082C2.41916 5.83245 2.06018 6.00764 1.7588 6.26093C1.45743 6.51423 1.22292 6.83786 1.07595 7.20329C0.928981 7.56872 0.874058 7.96474 0.916028 8.35644C0.957998 8.74813 1.09557 9.12348 1.31662 9.44939C1.53767 9.7753 1.8354 10.0418 2.18358 10.2253C2.53176 10.4088 2.9197 10.5038 3.31319 10.5019C3.51136 10.4987 3.70794 10.4715 3.89813 10.4219L5.55066 12.9019L3.89973 15.3819C3.70818 15.3314 3.51122 15.3046 3.31319 15.3019C2.92029 15.3005 2.53308 15.3959 2.18565 15.5796C1.83822 15.7633 1.54122 16.0297 1.32077 16.3553C1.10032 16.6809 0.963189 17.0557 0.921442 17.4468C0.879695 17.838 0.934613 18.2334 1.08136 18.5982C1.22811 18.9631 1.46219 19.2863 1.76301 19.5393C2.06382 19.7924 2.42215 19.9675 2.80646 20.0493C3.19077 20.1312 3.58928 20.1172 3.96691 20.0086C4.34455 19.9 4.68974 19.7002 4.97211 19.4267L10.5338 22.2107C10.5178 22.3067 10.5083 22.4043 10.5051 22.5019C10.5051 23.1384 10.7576 23.7488 11.2072 24.1989C11.6568 24.649 12.2665 24.9019 12.9023 24.9019C13.5381 24.9019 14.1479 24.649 14.5975 24.1989C15.0471 23.7488 15.2996 23.1384 15.2996 22.5019C15.2958 22.4043 15.2862 22.3071 15.2709 22.2107L20.8326 19.4267C21.1149 19.701 21.4604 19.9017 21.8384 20.0109C22.2165 20.1201 22.6156 20.1345 23.0006 20.0529C23.3855 19.9713 23.7445 19.7961 24.0459 19.5428C24.3473 19.2895 24.5818 18.9659 24.7287 18.6004C24.8757 18.235 24.9306 17.839 24.8887 17.4473C24.8467 17.0556 24.7091 16.6802 24.4881 16.3543C24.267 16.0284 23.9693 15.7619 23.6211 15.5784C23.2729 15.3949 22.885 15.2999 22.4915 15.3019ZM12.8884 2.50274C13.0185 2.50324 13.1465 2.53552 13.2613 2.59679C13.3761 2.65805 13.4742 2.74644 13.5471 2.85429C13.62 2.96214 13.6655 3.08617 13.6797 3.21563C13.6939 3.34509 13.6763 3.47605 13.6284 3.59714L13.606 3.64194C13.5429 3.77981 13.4416 3.89664 13.3141 3.97855C13.1866 4.06045 13.0383 4.10399 12.8868 4.10399C12.7353 4.10399 12.587 4.06045 12.4596 3.97855C12.3321 3.89664 12.2307 3.77981 12.1676 3.64194L12.1453 3.59874C12.097 3.47731 12.0791 3.34589 12.0933 3.21596C12.1074 3.08603 12.1532 2.96156 12.2265 2.85342C12.2998 2.74528 12.3985 2.65678 12.5139 2.59564C12.6293 2.53451 12.7579 2.50261 12.8884 2.50274ZM23.2767 8.10274C23.2767 8.31491 23.1925 8.5184 23.0426 8.66843C22.8928 8.81845 22.6895 8.90274 22.4776 8.90274C22.2656 8.90274 22.0624 8.81845 21.9125 8.66843C21.7627 8.5184 21.6785 8.31491 21.6785 8.10274C21.6785 7.89057 21.7627 7.68708 21.9125 7.53705C22.0624 7.38702 22.2656 7.30274 22.4776 7.30274C22.6895 7.30274 22.8928 7.38702 23.0426 7.53705C23.1925 7.68708 23.2767 7.89057 23.2767 8.10274ZM2.50017 8.10274C2.503 7.92305 2.56617 7.74956 2.67951 7.6102C2.79285 7.47085 2.94976 7.37376 3.12495 7.33458C3.30014 7.2954 3.4834 7.31641 3.6452 7.39423C3.807 7.47205 3.93792 7.60214 4.01685 7.76354L4.03923 7.80834C4.09871 7.95306 4.11376 8.11225 4.08244 8.26558C4.05113 8.4189 3.97488 8.55941 3.86343 8.66914C3.75158 8.78076 3.60921 8.8567 3.45428 8.88737C3.29936 8.91805 3.13883 8.90207 2.99297 8.84147C2.8471 8.78086 2.72245 8.67835 2.63474 8.54687C2.54703 8.41539 2.5002 8.26084 2.50017 8.10274ZM2.50017 17.7027C2.50017 17.4906 2.58436 17.2871 2.73422 17.1371C2.88408 16.987 3.08733 16.9027 3.29927 16.9027C3.5112 16.9027 3.71445 16.987 3.86431 17.1371C4.01417 17.2871 4.09836 17.4906 4.09836 17.7027C4.09836 17.9149 4.01417 18.1184 3.86431 18.2684C3.71445 18.4185 3.5112 18.5027 3.29927 18.5027C3.08733 18.5027 2.88408 18.4185 2.73422 18.2684C2.58436 18.1184 2.50017 17.9149 2.50017 17.7027ZM12.8884 23.3027C12.7566 23.3028 12.6268 23.2702 12.5106 23.2078C12.3944 23.1455 12.2955 23.0553 12.2225 22.9454C12.1496 22.8355 12.1049 22.7092 12.0926 22.5778C12.0802 22.4464 12.1005 22.314 12.1517 22.1923C12.2128 22.0519 12.3129 21.9319 12.4401 21.8468C12.5673 21.7616 12.7163 21.7148 12.8693 21.712C13.0223 21.7091 13.1729 21.7503 13.3032 21.8306C13.4336 21.911 13.5381 22.0271 13.6044 22.1651L13.6268 22.2099C13.6868 22.3541 13.7024 22.5129 13.6716 22.6659C13.6409 22.819 13.5651 22.9594 13.4542 23.0691C13.3798 23.1434 13.2916 23.2022 13.1945 23.2423C13.0974 23.2824 12.9934 23.3029 12.8884 23.3027ZM22.4776 18.5027C22.3267 18.5016 22.1793 18.4577 22.0523 18.3761C21.9253 18.2946 21.824 18.1787 21.76 18.0419L21.7376 17.9971C21.6981 17.9029 21.6777 17.8017 21.6777 17.6995C21.6777 17.5973 21.6981 17.4962 21.7376 17.4019L21.752 17.3747C21.8098 17.2422 21.9023 17.1279 22.0199 17.0438C22.1374 16.9598 22.2755 16.9092 22.4194 16.8974C22.5633 16.8857 22.7078 16.9132 22.8373 16.9771C22.9669 17.0409 23.0768 17.1388 23.1552 17.2601C23.2337 17.3815 23.2778 17.5219 23.283 17.6664C23.2881 17.8109 23.254 17.9541 23.1843 18.0808C23.1146 18.2074 23.012 18.3128 22.8872 18.3857C22.7625 18.4586 22.6204 18.4963 22.476 18.4947L22.4776 18.5027ZM18.0186 9.80834L20.1714 8.73154C20.1554 8.63554 20.1458 8.53794 20.1426 8.44034C20.1458 8.34274 20.1554 8.24514 20.1714 8.14914L15.2841 5.70274L18.0186 9.80834ZM10.6158 5.70434L5.73012 8.14914C5.74545 8.24555 5.75505 8.34279 5.75888 8.44034C5.75569 8.53794 5.7461 8.63554 5.73012 8.73154L7.88288 9.80834L10.6158 5.70434ZM5.73012 17.7491L7.88288 16.6723L10.6174 20.7779L5.73012 18.3315C5.7461 18.2355 5.75569 18.1379 5.75888 18.0403C5.75505 17.9428 5.74545 17.8456 5.73012 17.7491ZM12.2108 13.5363L12.2332 13.5795H12.2364C12.3 13.7175 12.4021 13.8341 12.5303 13.9155C12.6585 13.9968 12.8074 14.0395 12.9592 14.0383C13.1109 14.0371 13.2592 13.9921 13.3861 13.9088C13.513 13.8255 13.6132 13.7072 13.6747 13.5683L13.6891 13.5411C13.7292 13.444 13.7498 13.3398 13.7497 13.2347C13.7496 13.1296 13.7288 13.0255 13.6885 12.9284C13.6482 12.8313 13.5892 12.7431 13.5148 12.6688C13.4405 12.5946 13.3523 12.5357 13.2552 12.4955C13.1581 12.4554 13.0541 12.4348 12.9491 12.4349C12.8441 12.435 12.7401 12.4559 12.6431 12.4962C12.5461 12.5365 12.4581 12.5956 12.3839 12.67C12.3097 12.7444 12.2509 12.8328 12.2108 12.9299C12.1706 13.026 12.1499 13.129 12.1499 13.2331C12.1499 13.3373 12.1706 13.4403 12.2108 13.5363ZM14.6097 14.9715C14.3637 15.2066 14.0706 15.3866 13.7498 15.4995V20.1987L16.5786 15.9571L14.6097 14.9715ZM15.348 13.2403C15.3448 13.3395 15.3353 13.4387 15.3193 13.5379L17.4736 14.6083L18.3846 13.2403L17.472 11.8723L15.3193 12.9491C15.3346 13.0456 15.3442 13.1428 15.348 13.2403ZM13.7498 10.9939C14.0706 11.1069 14.3637 11.2869 14.6097 11.5219L16.5786 10.5299L13.7498 6.28194V10.9939ZM12.1517 10.9875V6.28194L9.32285 10.5299L11.2918 11.5155C11.5378 11.2805 11.8309 11.1005 12.1517 10.9939ZM10.5535 13.2403C10.5567 13.1427 10.5662 13.0451 10.5822 12.9491L8.42787 11.8723L7.5169 13.2403L8.42946 14.6083L10.5822 13.5315C10.5662 13.4355 10.5567 13.3379 10.5535 13.2403ZM12.1517 15.4931C11.8309 15.3802 11.5378 15.2002 11.2918 14.9651L9.32285 15.9507L12.1517 20.1987V15.4931ZM20.1714 17.7491L18.0186 16.6723L15.2841 20.7779L20.1714 18.3315C20.1554 18.2355 20.1458 18.1379 20.1426 18.0403C20.1458 17.9427 20.1554 17.8451 20.1714 17.7491ZM18.912 15.3299L20.2049 15.9779L19.3435 14.6803L18.912 15.3299ZM20.2049 10.5027L18.912 11.1507L19.3435 11.8003L20.2049 10.5027ZM6.98949 11.1443L5.69656 10.5043L6.55798 11.8003L6.98949 11.1443ZM5.69656 15.9779L6.98949 15.3299L6.55798 14.6803L5.69656 15.9779Z" />
            </svg>)

## AI-Generated Summary

![](data:image/svg+xml;base64,PHN2ZyBjbGFzcz0ibnYtYWktc3VtbWFyeV9fdG9nZ2xlLWljb24iIHdpZHRoPSIxNCIgaGVpZ2h0PSI5IiB2aWV3Ym94PSIwIDAgMTQgOSIgZmlsbD0ibm9uZSIgeG1sbnM9Imh0dHA6Ly93d3cudzMub3JnLzIwMDAvc3ZnIiBhcmlhLWhpZGRlbj0idHJ1ZSI+CiAgICAgICAgPHBhdGggZD0iTTEyLjU3NDIgMkw3LjQ0OTIzIDdMMi4zMjQyNSAyIiBzdHJva2U9ImN1cnJlbnRDb2xvciIgc3Ryb2tlLXdpZHRoPSIyIiBzdHJva2UtbGluZWNhcD0ic3F1YXJlIiAvPgogICAgPC9zdmc+)

- [NVIDIA Blackwell Ultra GPU](https://www.nvidia.com/en-us/data-center/technologies/blackwell-architecture/) delivers 15 petaFLOPS of dense NVFP4 compute through 640 fifth-generation Tensor Cores across 160 Streaming Multiprocessors.
- The dual-reticle design connects two dies with NV-HBI at 10 TB/s, functioning as a single CUDA-programmed accelerator with 208B transistors manufactured on TSMC 4NP.
- HBM3E memory capacity reaches 288 GB with 8 TB/s bandwidth, enabling 300B+ parameter models to reside entirely on-chip without offloading.
- Accelerated softmax execution doubles SFU throughput for attention-layer operations, delivering up to 2x faster attention compute compared to Blackwell GPUs.
- NVLink 5 provides 1.8 TB/s bidirectional GPU-to-GPU bandwidth supporting up to 576 GPUs in non-blocking fabric, while NVLink-C2C enables 900 GB/s coherent CPU-GPU communication.
- Enterprise features include enhanced GigaThread scheduling, Multi-Instance GPU partitioning, confidential computing with TEE-I/O, and AI-powered RAS for predictive failure monitoring.

### Next Steps

- Download the [Blackwell Architecture Technical Brief](https://resources.nvidia.com/en-us-blackwell-architecture/blackwell-architecture-technical-brief) to explore the full silicon-to-system story.
- Explore the [Pareto Frontier explainer](https://resources.nvidia.com/en-us-inference-contact-us/discover-ai-inference) to see how hardware and deployment innovations impact data center efficiency and user experience.
- Learn about [GB300 NVL72](https://www.nvidia.com/en-us/data-center/gb300-nvl72/) rack-scale system capabilities for AI factory deployments.

Powered by NVIDIA Nemotron. AI-generated content may summarize information incompletely. Verify important information. [Learn more](https://www.nvidia.com/en-us/agreements/trustworthy-ai/terms/)

As the latest member of the NVIDIA Blackwell architecture family, the NVIDIA Blackwell Ultra GPU builds on core innovations to accelerate training and AI reasoning. It fuses silicon innovations with new levels of system-level integration, delivering next-level performance, scalability, and efficiency for AI factories and the large-scale, real-time AI services they power.

With its energy-efficient dual-reticle design, high bandwidth and large-capacity HBM3E memory subsystem, fifth-generation Tensor Cores, and breakthrough [NVFP4](https://developer.nvidia.com/blog/introducing-nvfp4-for-efficient-and-accurate-low-precision-inference/) precision format, Blackwell Ultra is raising the bar for accelerated computing. This in-depth look explains the architectural advances, why they matter, and how they translate into measurable gains for AI workloads.

## Dual-reticle design: one GPU[](#dual-reticle_design_one_gpu)

Blackwell Ultra is composed of two reticle-sized dies connected using NVIDIA High-Bandwidth Interface (NV-HBI), a custom, power-efficient die-to-die interconnect technology that provides 10 TB/s of bandwidth. Blackwell Ultra is manufactured using TSMC 4NP and features 208B transistors–2.6x more than the [NVIDIA Hopper GPU](https://www.nvidia.com/en-us/data-center/technologies/hopper-architecture/)—all while functioning as a single, NVIDIA CUDA-programmed accelerator. This enables a large increase in performance while also maintaining the familiar CUDA programming model that developers have enjoyed for nearly two decades.

### Benefits[](#benefits)

- **Unified compute domain:** 160\* Streaming Multiprocessors (SMs) across two dies, providing 640 fifth-generation Tensor Cores with 15 PetaFLOPS dense NVFP4 compute.
- **Full coherence:** Shared L2 cache with fully coherent memory accesses.
- **Maximum silicon utilization:** Peak performance per square millimeter.

![Diagram of NVIDIA Blackwell Ultra GPU showing dual reticle dies linked by a 10 TB/s NV-HBI interface. Each die contains a GigaThread Engine with MIG control, L2 cache, and 8 GPCs with a total of 640 5th generation Tensor Cores (15 PFLOPS dense NVFP4). Callouts highlight PCIe Gen 6 (256 GB/s), NVLink v5 (1,800 GB/s to NVSwitch), NVLink-C2C (900 GB/s CPU–GPU), and 288 GB HBM3E (12-hi stacks, up to 8 TB/s).](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/NVIDIA-Blackwell-Ultra-GPU-chip-png.webp)

![Diagram of NVIDIA Blackwell Ultra GPU showing dual reticle dies linked by a 10 TB/s NV-HBI interface. Each die contains a GigaThread Engine with MIG control, L2 cache, and 8 GPCs with a total of 640 5th generation Tensor Cores (15 PFLOPS dense NVFP4). Callouts highlight PCIe Gen 6 (256 GB/s), NVLink v5 (1,800 GB/s to NVSwitch), NVLink-C2C (900 GB/s CPU–GPU), and 288 GB HBM3E (12-hi stacks, up to 8 TB/s).](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%202182%201420%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 1. NVIDIA Blackwell Ultra GPU chip explained*  
\* Blackwell Ultra GPUs contain up to 160 SMs and 288GB HBM3E Memory. Available SM count and HBM capacity varies by SKU.

## Streaming multiprocessors: compute engines for the AI Factory[](#streaming_multiprocessors_compute_engines_for_the_ai_factory)

As shown in Figure 1, the heart of Blackwell Ultra is its 160 Streaming Multiprocessors (SMs) organized into eight Graphics Processing Clusters (GPCs) in the full GPU implementation. Every SM, shown in Figure 2, is a self-contained compute engine housing:

- **128 CUDA Cores** for FP32 and INT32 operations, also FP16/BF16 and other precisions.
- **4 fifth-generation Tensor Cores** with NVIDIA second-generation Transformer Engine, optimized for FP8, FP6, and NVFP4.
- **256 KB of Tensor Memory (TMEM)** for warp-synchronous storage of intermediate results, enabling higher reuse and reduced off-chip memory traffic.
- **Special Function Units (SFUs)** for transcendental math and special operations used in AI kernels.

![Diagram of Blackwell Ultra Streaming Multiprocessor (SM) architecture showing CUDA cores, Tensor Cores, TMEM, shared memory, SFUs, Tex blocks, and other SM units.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/Blackwell-Ultra-SM-architecture-png.webp)

![Diagram of Blackwell Ultra Streaming Multiprocessor (SM) architecture showing CUDA cores, Tensor Cores, TMEM, shared memory, SFUs, Tex blocks, and other SM units.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201435%201999%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 2. Blackwell Ultra SM architecture*

## NVIDIA Tensor Cores, AI compute powerhouses[](#nvidia_tensor_cores_ai_compute_powerhouses)

When NVIDIA first introduced Tensor Cores in the Volta architecture, they fundamentally changed what GPUs could do for deep learning. Instead of executing scalar or vector operations one element at a time, Tensor Cores operate directly on small matrices—performing matrix multiply-accumulate (MMA) in a single instruction. This was a perfect match for neural networks, where the vast majority of computation comes down to multiplying and summing large grids of numbers.

Over successive generations, Tensor Cores have expanded in capability, precision formats, and parallelism:

- **NVIDIA Volta:** 8-thread MMA units, FP16 with FP32 accumulation for training.
- **NVIDIA Ampere:** Full warp-wide MMA, BF16, and TensorFloat-32 formats.
- **NVIDIA Hopper:** Warp-group MMA across 128 threads, Transformer Engine with FP8 support.

Blackwell and Blackwell Ultra take this to the next level with their fifth-generation Tensor Cores and second-generation Transformer Engine, delivering [higher throughput and lower latency](https://www.nvidia.com/en-us/data-center/technologies/blackwell-architecture/%20https://resources.nvidia.com/en-us-blackwell-architecture/blackwell-architecture-technical-brief) for both dense and sparse AI workloads. Each Streaming Multiprocessor (SM) contains four Tensor Cores across the 160 SMs in Blackwell Ultra, adding up to 640 Tensor Cores upgraded to handle the newest precision format, NVFP4.

These enhancements aren’t just about raw FLOPS. The new Tensor Cores are tightly integrated with 256 KB of Tensor Memory (TMEM) per SM, optimized to keep data close to the compute units. They also support dual-thread-block MMA, where paired SMs cooperate on a single MMA operation, sharing operands and reducing redundant memory traffic.

The result is higher sustained throughput, better memory efficiency, and faster large-batch pre-training, reinforcement learning for post-training, and low-batch, high-interactivity inference.

## Ultra-charged NVFP4 performance[](#ultra-charged_nvfp4_performance)

The [introduction of NVIDIA NVFP4](https://developer.nvidia.com/blog/introducing-nvfp4-for-efficient-and-accurate-low-precision-inference/), the new 4‑bit floating‑point format in the Blackwell GPU architecture, combines two-level scaling—an FP8 (E4M3) micro-block scale applied to 16‑value blocks plus a tensor-level FP32 scale—enabling hardware‑accelerated quantization with markedly lower error rates than standard FP4. This Tensor Core capability delivers nearly FP8‑equivalent accuracy (with often less than ~1% difference), while reducing memory footprint by [~1.8x compared to FP8 and up to ~3.5x vs. FP16](https://developer.nvidia.com/blog/introducing-nvfp4-for-efficient-and-accurate-low-precision-inference/). NVFP4 strikes an optimal balance of accuracy, efficiency, and performance for low‑precision AI inference.

The Blackwell Ultra dense NVFP4 compute capability provides a substantial performance uplift over the original Blackwell GPU. While the base architecture delivers 10 petaFLOPS of NVFP4 performance, Ultra pushes that to 15 petaFLOPS—a [1.5x increase compared to Blackwell GPU and 7.5x increase](https://resources.nvidia.com/en-us-blackwell-architecture/blackwell-architecture-technical-brief) from NVIDIA Hopper [H100](https://www.nvidia.com/en-us/data-center/h100/) and [H200](https://www.nvidia.com/en-us/data-center/h200/) GPUs, as shown in Figure 3. This boost directly benefits large-scale inference, enabling more concurrent model instances, faster response times, and lower costs per token generated.

![Bar chart comparing dense FP8 performance on Hopper, which includes H100 and H200 at 2 petaFLOPS, vs NVFP4 performance for Blackwell (10 petaFLOPS) vs Blackwell Ultra (15 petaFLOPS) with an arrow indicating a 7.5x increase from Hopper to Blackwell Ultra and 1.5x increase from Blackwell to Blackwell Ultra.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/Blackwell-Ultra-Throughput-png.webp)

![Bar chart comparing dense FP8 performance on Hopper, which includes H100 and H200 at 2 petaFLOPS, vs NVFP4 performance for Blackwell (10 petaFLOPS) vs Blackwell Ultra (15 petaFLOPS) with an arrow indicating a 7.5x increase from Hopper to Blackwell Ultra and 1.5x increase from Blackwell to Blackwell Ultra.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201388%20796%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 3. Blackwell Ultra GPU delivers 1.5x more dense NVFP4 throughput compared to Blackwell*

## Accelerated softmax in the attention layer[](#accelerated_softmax_in_the_attention_layer)

Modern AI workloads rely heavily on attention processing with long input contexts and long output sequences for “thinking”. Transformer attention layers, in turn, stress exponentials, divisions, and other transcendental operations executed by the SM’s SFUs.

In Blackwell Ultra, SFU throughput has been doubled for key instructions used in attention, delivering up to [2x faster attention-layer](https://nvdam.widen.net/s/xqt56dflgh/nvidia-blackwell-architecture-technical-brief#%5B%7B%22num%22%3A13%2C%22gen%22%3A0%7D%2C%7B%22name%22%3A%22XYZ%22%7D%2C73%2C325%2C0%5D) compute compared to Blackwell GPUs. This improvement accelerates both short and long-sequence attention, but is especially impactful for reasoning models with large context windows—where the softmax stage can become a latency bottleneck.

By accelerating the attention mechanism within transformer models, Blackwell Ultra enables:

- Faster AI reasoning with lower time-to-first-token in interactive applications.
- Lower compute costs by reducing total processing cycles per query.
- Higher system efficiency—more attention sequences processed per watt.

As depicted in Figure 4, the performance gains from the accelerated attention-layer instructions in Blackwell Ultra compound with NVFP4 precision, resulting in a step-function improvement for LLM and multimodal inference.

![Diagram showing the attention computation pipeline with doubled SFU throughput for exponential operations and 50% faster NVFP4 during batched matrix multiplies, reducing overall Softmax latency.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/Blackwell-Ultra-attention-layer-acceleration-png.webp)

![Diagram showing the attention computation pipeline with doubled SFU throughput for exponential operations and 50% faster NVFP4 during batched matrix multiplies, reducing overall Softmax latency.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%20796%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 4. Blackwell Ultra attention-layer acceleration*

## Memory: high capacity and bandwidth for multi-trillion-parameter models[](#memory_high_capacity_and_bandwidth_for_multi-trillion-parameter_models)

Blackwell Ultra doesn’t just scale compute—it scales memory capacity to meet the demands of the largest AI models. With 288 GB of HBM3e per GPU, it offers 3.6x more on-package memory than H100 and 50% more than Blackwell, as shown in Figure 5. This capacity is critical for hosting trillion-parameter models, extending context length without KV-cache offloading, and enabling high-concurrency inference in AI factories.

### High bandwidth memory features[](#high_bandwidth_memory_features)

- **Max capacity:** 288 GB, 3.6x increase over H100
- **HBM configuration:** Eight 12-Hi stacks, 16 × 512-bit controllers (8,192-bit total width)
- **Bandwidth:** 8 TB/s per GPU, 2.4x improvement over H100 (3.35 TB/s)

![Bar chart comparing GPU HBM capacity: Hopper H100 (80 GB), Hopper H200 (141 GB), Blackwell (192 GB), and Blackwell Ultra (288 GB), with an arrow labeled “3.6x” between Hopper and Blackwell Ultra.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/capacity-scaling-png.webp)

![Bar chart comparing GPU HBM capacity: Hopper H100 (80 GB), Hopper H200 (141 GB), Blackwell (192 GB), and Blackwell Ultra (288 GB), with an arrow labeled “3.6x” between Hopper and Blackwell Ultra.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201110%20596%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 5. HBM capacity scaling across GPU generations*

This massive memory footprint enables:

- **Complete model residence:** 300B+ parameter models without memory offloading.
- **Extended context lengths:** Larger KV cache capacity for transformer models.
- **Improved compute efficiency:** Higher compute-to-memory ratios for diverse workloads.

## Interconnect: built for scale[](#interconnect_built_for_scale)

Blackwell and Blackwell Ultra support fifth-generation NVIDIA NVLink for GPU-to-GPU communication over NVLink Switch, NVLink-C2C for coherent interconnect to an NVIDIA Grace CPU, and x16 PCI-Express Gen 6 interface for connection to host CPUs.

### NVLink 5 Specifications[](#nvlink_5_specifications)

- **Per-GPU Bandwidth:** 1.8 TB/s bidirectional (18 links x 100 GB/s)
- **Performance Scaling:** 2x improvement over NVLink 4 (Hopper GPU)
- **Maximum Topology:** 576 GPUs in non-blocking compute fabric
- **Rack-Scale Integration:** 72-GPU NVL72 configurations with 130 TB/s aggregate bandwidth

### Host connectivity:[](#host_connectivity)

- **PCIe Interface:** Gen6 × 16 lanes (256 GB/s bidirectional)
- **NVLink-C2C:** Grace CPU-GPU communication with memory coherency (900 GB/s)

Table 1 provides a comparison of the interconnects across generations.

| **Interconnect** | **Hopper GPU** | **Blackwell GPU** | **Blackwell Ultra GPU** |
|----|----|----|----|
| NVLink (GPU-GPU) | 900 | 1,800 | 1,800 |
| NVLink-C2C (CPU-GPU) | 900 | 900 | 900 |
| PCIe Interface | 128 (Gen 5) | 256 (Gen 6) | 256 (Gen 6) |

*Table 1. Interconnect comparison of Hopper compared to Blackwell and Blackwell Ultra (in BiD*ir GB/s)

## Advancing performance-efficiency[](#advancing_performance-efficiency)

Blackwell Ultra delivers a decisive leap over Blackwell by adding 50% more NVFP4 compute and 50% more HBM capacity per chip, enabling larger models and faster throughput without compromising efficiency. Accelerated softmax execution further boosts real-world inference speeds, driving up tokens per second per user (TPS/user) while improving data center tokens per second per megawatt (TPS/MW). Every architectural enhancement was purpose-built to push both user experience and operational efficiency to the next level.

As shown in Figure 6, plotting these two metrics for the NVIDIA Hopper HGX H100 NVL8 system, NVIDIA Blackwell HGX B200 NVL8 system, NVIDIA Blackwell GB200 NVL72 system, and NVIDIA Blackwell Ultra GB300 NVL72 system reveals a generational leap. The curve starts with Hopper NVL8 at FP8 precision and ends with Blackwell Ultra NVL72 at NVFP4 precision—showing how each architectural advance pushes the Pareto frontier up and to the right.

![Animated Pareto frontier chart transitioning through three generations of NVIDIA architecture: starting with Hopper (lowest curve), then expanding to Blackwell (mid-tier curve), and finally to Blackwell Ultra (top curve). ](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/AI-factory-output.gif)

![Animated Pareto frontier chart transitioning through three generations of NVIDIA architecture: starting with Hopper (lowest curve), then expanding to Blackwell (mid-tier curve), and finally to Blackwell Ultra (top curve). ](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201920%201080%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 6. AI factory output evolution from Hopper to Blackwell Ultra*

These architectural innovations improve the [economics of AI inference](https://blogs.nvidia.com/blog/ai-inference-economics/) and redefine what’s possible in AI factory design—delivering more model instances, faster responses, and higher output per megawatt than any previous NVIDIA platform.

To see firsthand how innovations in hardware and deployment configurations impact data center efficiency and user experience, check out our interactive [Pareto Frontier explainer.](https://resources.nvidia.com/en-us-inference-contact-us/discover-ai-inference)

## Enterprise-grade features[](#enterprise-grade_features)

Blackwell Ultra isn’t just about raw performance—it’s designed with enterprise-grade features that simplify operations, strengthen security, and deliver reliable performance at scale.

### Advanced scheduling and management[](#advanced_scheduling_and_management)

- **Enhanced GigaThread Engine:** Next-generation work scheduler providing improved context switching performance and optimized workload distribution across all 160 SMs.
- **Multi-Instance GPU (MIG):** Blackwell Ultra GPUs can be partitioned into different-sized [MIG](https://www.nvidia.com/en-us/technologies/multi-instance-gpu/) instances. For example, an administrator can create two instances with 140 GB of memory each, four instances with 70 GB each, or seven instances with 34 GB each, enabling secure multi-tenancy with predictable performance isolation.

### Security and reliability[](#security_and_reliability)

- [**Confidential computing and secure AI**](https://www.nvidia.com/en-us/data-center/solutions/confidential-computing/)**:** Secure and performant protection for sensitive AI models and data, extending hardware-based Trusted Execution Environment (TEE) to GPUs with industry-first TEE-I/O capabilities in the Blackwell architecture and inline NVLink protection for near-identical throughput when compared to unencrypted modes.
- **[Advanced NVIDIA **Reliability, Availability, and Serviceability** (RAS) engine](https://nvdam.widen.net/s/xqt56dflgh/nvidia-blackwell-architecture-technical-brief#%5B%7B%22num%22%3A20%2C%22gen%22%3A0%7D%2C%7B%22name%22%3A%22XYZ%22%7D%2C70%2C720%2C0%5D):** AI-powered reliability system monitoring thousands of parameters to predict failures, optimize maintenance schedules, and maximize system uptime in large-scale deployments.

## AI video and data processing enhancements[](#ai_video_and_data_processing_enhancements)

Blackwell Ultra also integrates specialized engines for modern AI workloads requiring multimodal data processing:

- **Video and JPEG decoding:** The NVIDIA Video Decoder (NVDEC) and NVIDIA JPEG Decoder (NVJPEG) engines are specialized fixed-function hardware units for high-throughput image and video processing.
  - NVDEC supports modern codecs like AV1, HEVC, and H.264, enabling batch or real-time video decoding directly on the GPU without using CUDA Cores. 
  - NVJPEG accelerates JPEG decompression in hardware, making large-scale image pipelines dramatically faster. 
  - Both engines are leveraged by [NVIDIA DALI](https://developer.nvidia.com/dali) (Data Loading Library), which integrates them into AI training and inference workflows for tasks like image augmentation, dataset preprocessing, and multimodal model input preparation.
- **Decompression engine:** Hardware-accelerated data decompression at 800 GB/s throughput, reducing CPU overhead and accelerating compressed dataset loading for analytics workloads. NVIDIA [nvCOMP](https://developer.nvidia.com/nvcomp) enables portable programming of the decompression engine.

## NVIDIA GPU chip summary comparison[](#nvidia_gpu_chip_summary_comparison)

To put Blackwell Ultra’s advances in perspective, Table 2 compares key chip specifications across Hopper, Blackwell, and Blackwell Ultra. It highlights the generational leap in transistor count, memory capacity, interconnect bandwidth, and precision compute throughput—as well as the architectural enhancements like attention acceleration and NVFP4. This side-by-side view shows how Blackwell Ultra scales up performance and extends capabilities critical for AI factory deployments at both node and rack scale.

[TABLE]

*Table 2. NVIDIA GPU chip comparison*

## From chip to AI factory[](#from_chip_to_ai_factory)

Blackwell Ultra GPUs form the backbone of NVIDIA’s next-generation AI infrastructure—delivering transformative performance from desktop superchips to full AI factory racks.  

### NVIDIA Grace Blackwell Ultra Superchip[](#nvidia_grace_blackwell_ultra_superchip)

This superchip couples one Grace CPU with two Blackwell Ultra GPUs through NVLink‑C2C, offering up to 30 PFLOPS dense, and 40 PFLOPS sparse, NVFP4 AI compute, and boasts 1 TB of unified memory combining HBM3E and LPDDR5X for unprecedented on-node capacity. ConnectX-8 SuperNICs provide 800 Gb/s high-speed network connectivity (See Figure 7). The NVIDIA Grace Blackwell Ultra Superchip is the foundational computing component of the GB300 NVL 72 rack-scale system.

![Photograph of the NVIDIA Grace Blackwell Ultra Superchip board, featuring a Grace CPU surrounded by LPDDR5X memory, and two Blackwell Ultra GPUs on a single module, surrounded by HBM3E memory stacks, with integrated NVIDIA ConnectX-8 SuperNICs providing high-speed network connectivity.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/ConnectX-8-SuperNICs-png.webp)

![Photograph of the NVIDIA Grace Blackwell Ultra Superchip board, featuring a Grace CPU surrounded by LPDDR5X memory, and two Blackwell Ultra GPUs on a single module, surrounded by HBM3E memory stacks, with integrated NVIDIA ConnectX-8 SuperNICs providing high-speed network connectivity.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201294%20942%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 7. NVIDIA Grace Blackwell Ultra Superchip with ConnectX-8 SuperNICs*

- **NVIDIA GB300 NVL72 rack-scale system:** This liquid-cooled rack integrates 36 Grace Blackwell Superchips, interconnected through NVLink 5 and NVLink Switching, enabling it to achieve 1.1  exaFLOPS dense FP4 compute. The [GB300 NVL72](https://www.nvidia.com/en-us/data-center/gb300-nvl72/) also enables a 50x higher AI factory output, combining 10x better latency (TPS per user) and 5x higher throughput per megawatt relative to Hopper platforms. GB300 systems also redefine rack power management. They rely on multiple power-shelf configurations to handle synchronous GPU load ramps. NVIDIA [power smoothing](https://developer.nvidia.com/blog/how-new-gb300-nvl72-features-provide-steady-power-for-ai) innovations—including energy storage and burn mechanisms—help stabilize power draw across training workloads.
- **NVIDIA HGX and DGX B300 systems:** Standardized 8 GPU Blackwell Ultra configurations. NVIDIA [HGX B300](https://www.nvidia.com/en-us/data-center/hgx/) and NVIDIA [DGX B300](https://www.nvidia.com/en-us/data-center/dgx-b300/) Systems continue to support flexible deployment models for AI infrastructure while maintaining full CUDA and NVLink compatibility.

## Complete CUDA compatibility[](#complete_cuda_compatibility)

Blackwell Ultra maintains full backward compatibility with the entire CUDA ecosystem while introducing optimizations for next-generation AI frameworks:

- **Framework integration:** Native support in SGLang, TensorRT-LLM, and vLLM with optimized kernels for NVFP4 precision and dual-die architecture.
- **NVIDIA Dynamo:** A distributed inference and scheduling framework that intelligently orchestrates workloads across thousands of GPUs, delivering up to [30x higher](https://developer.nvidia.com/blog/introducing-nvidia-dynamo-a-low-latency-distributed-inference-framework-for-scaling-reasoning-ai-models/) throughput for large-scale deployments.
- **NVIDIA Enterprise AI:** End-to-end, cloud-native AI software platform delivering optimized frameworks, SDKs, microservices, and enterprise-grade tools for developing, deploying, and managing AI workloads at scale.
- **NVIDIA development tools and CUDA libraries:**
  - CUTLASS for custom kernel development
  - Nsight Systems and Nsight Compute for profiling and tuning
  - Model Optimizer for precision-aware graph optimization
  - cuDNN for deep learning primitives
  - NCCL for multi-GPU communication
  - CUDA Graphs for reducing launch overhead

## The bottom line[](#the_bottom_line)

NVIDIA Blackwell Ultra establishes the foundation for AI factories to train and deploy intelligence at unprecedented scale and efficiency. With breakthrough innovations in dual-die integration, NVFP4 acceleration, massive memory capacity, and advanced interconnect technology, Blackwell Ultra enables AI applications that were previously computationally impossible.

As the industry transitions from proof-of-concept AI to production AI factories, Blackwell Ultra provides the computational foundation to turn AI ambitions into reality with unmatched performance, efficiency, and scale.

## Learn more[](#learn_more)

Dive deeper into the innovations powering the trillion-token era. Download the [Blackwell Architecture Technical Brief](https://resources.nvidia.com/en-us-blackwell-architecture/blackwell-architecture-technical-brief) to explore the full silicon-to-system story.

## Acknowledgments[](#acknowledgments)

*We’d like to thank Manas Mandal, Ronny Krashinsky, Vishal Mehta, Greg Palmer, Michael Andersch, Eduardo Alvarez, Ashraf Eassa, Joe DeLaere, and many other NVIDIA GPU architects, engineers, and product leaders who contributed to this post.*

*This post was updated on 9/24/25 to correct Figure 1 and the HBM configuration section to show the proper 12 HBM stacks instead of 8.*

[ Discuss (1)](#entry-content-comments)

Like

## Tags

[Data Center / Cloud](https://developer.nvidia.com/blog/category/data-center-cloud/) \| [Networking / Communications](https://developer.nvidia.com/blog/category/networking-communications/) \| [Hardware / Semiconductor](https://developer.nvidia.com/blog/recent-posts/?industry=Hardware+%2F+Semiconductor) \| [Blackwell](https://developer.nvidia.com/blog/recent-posts/?products=Blackwell) \| [GB200](https://developer.nvidia.com/blog/recent-posts/?products=GB200) \| [H100](https://developer.nvidia.com/blog/recent-posts/?products=H100) \| [H200](https://developer.nvidia.com/blog/recent-posts/?products=H200) \| [NVLink](https://developer.nvidia.com/blog/recent-posts/?products=NVLink) \| [TensorRT](https://developer.nvidia.com/blog/recent-posts/?products=TensorRT) \| [Intermediate Technical](https://developer.nvidia.com/blog/recent-posts/?learning_levels=Intermediate+Technical) \| [Deep dive](https://developer.nvidia.com/blog/recent-posts/?content_types=Deep+dive) \| [featured](https://developer.nvidia.com/blog/tag/featured/) \| [Inference Performance](https://developer.nvidia.com/blog/tag/inference-performance/)

## About the Authors

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2025/04/cropped-kyle-aubrey-131x131.png)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Kyle Aubrey**  
Kyle Aubrey is the director of Technical Marketing at NVIDIA, where he leads initiatives in AI inference and training across NVIDIA accelerated computing platforms, including Hopper, Blackwell, Rubin, and beyond. With a passion for demystifying complex technologies, he empowers diverse audiences to harness the full potential of NVIDIA's cutting-edge solutions. Kyle holds a bachelor’s degree in Electrical Engineering from Rose-Hulman Institute of Technology and an MBA from Pepperdine University.

[View all posts by Kyle Aubrey![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/kaubrey/)

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Nick-Stam-131x131.jpg)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Nick Stam**  
Nick Stam is a senior technical marketing director at NVIDIA. His team provides tech support to media and industry analysts, while also generating whitepapers and reviewer collateral. Prior to NVIDIA, Nick worked at PC Magazine USA for many years, and co-founded the ExtremeTech website. Nick has worked in various technical and management positions in the computer industry since 1980.

[View all posts by Nick Stam![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/nstam/)

## Comments

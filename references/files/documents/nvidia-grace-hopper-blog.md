<!-- 从 nvidia-grace-hopper-blog.html 迁移的资料快照；原始 HTML SHA-256: 1857975b830810a388df90cddbd9b5bac6de50e11560bb09e362802ac3dfe93f。 -->

<div class="main-content col-lg-9 col-md-9 mt-0" role="main">

<div class="post-card--single">

<div class="row">

<div class="col-lg-12 mb-0">

<div class="card--post-attributes">

<span class="category-name content-s"> <a href="https://developer.nvidia.com/blog/category/data-science/" data-wpel-link="internal" target="_self" rel="follow">Data Science</a> </span> <span class="post-rate-widget content-s"></span> <span class="post-lang-switcher"> </span>

<div class="posts-filter-form">

<div class="filter-item form-type-select">

English日本語

</div>

</div>

</div>

# NVIDIA Grace Hopper Superchip Architecture In-Depth

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-1024x576.png" class="attachment-full-page-width size-full-page-width wp-post-image" decoding="async" data-fetchpriority="high" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-1024x576.png 1024w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-300x169.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-625x352.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-179x101.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-768x432.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-500x281.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-160x90.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-362x204.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880-195x110.png 195w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-1-e1670969676880.png 1077w" sizes="(max-width: 1024px) 100vw, 1024px" width="1024" height="576" />

<div class="post-info">

<div class="post-published-date">

Nov 10, 2022

</div>

<div class="post-authors">

By <a href="https://developer.nvidia.com/blog/author/jevans/" class="author url fn" rel="author follow" data-wpel-link="internal" target="_self" title="Posts by Jonathon Evans">Jonathon Evans</a>, <a href="https://developer.nvidia.com/blog/author/mandersch/" class="author url fn" rel="author follow" data-wpel-link="internal" target="_self" title="Posts by Michael Andersch">Michael Andersch</a>, <a href="https://developer.nvidia.com/blog/author/vsethi/" class="author url fn" rel="author follow" data-wpel-link="internal" target="_self" title="Posts by Vikram Sethi">Vikram Sethi</a>, <a href="https://developer.nvidia.com/blog/author/gonzalob/" class="author url fn" rel="author follow" data-wpel-link="internal" target="_self" title="Posts by Gonzalo Brito">Gonzalo Brito</a> and <a href="https://developer.nvidia.com/blog/author/vishalm/" class="author url fn" rel="author follow" data-wpel-link="internal" target="_self" title="Posts by Vishal Mehta">Vishal Mehta</a>

</div>

<div class="card--post-attributes-secondary card--post-attributes-header">

<div class="post--rate secondary--attribute">

<div class="wpulike wpulike-heart">

<div class="wp_ulike_general_class wp_ulike_is_not_liked">

<span class="count-box wp_ulike_counter_up" ulike-counter-value="+52"></span>

</div>

</div>

Like

</div>

<div class="post--comments-count secondary--attribute">

[ Discuss (12)](#entry-content-comments)

</div>

</div>

</div>

</div>

</div>

</div>

<div class="entry-meta-social">

- <a href="https://www.linkedin.com/sharing/share-offsite/?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Fnvidia-grace-hopper-superchip-architecture-in-depth%2F" class="for-linkedin" data-wpel-link="external" target="_blank" rel="follow">L</a>
- <a href="https://twitter.com/intent/tweet?text=NVIDIA+Grace+Hopper+Superchip+Architecture+In-Depth+%7C+NVIDIA+Technical+Blog+https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Fnvidia-grace-hopper-superchip-architecture-in-depth%2F" class="for-twitter" data-wpel-link="external" target="_blank" rel="follow">T</a>
- <a href="https://www.facebook.com/sharer/sharer.php?u=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Fnvidia-grace-hopper-superchip-architecture-in-depth%2F" class="for-facebook" data-wpel-link="external" target="_blank" rel="follow">F</a>
- <a href="https://www.reddit.com/submit?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Fnvidia-grace-hopper-superchip-architecture-in-depth%2F&amp;title=NVIDIA+Grace+Hopper+Superchip+Architecture+In-Depth+%7C+NVIDIA+Technical+Blog" class="for-reddit" data-wpel-link="external" target="_blank" rel="follow">R</a>
- <a href="mailto:?subject=I&#39;d%20like%20to%20share%20a%20link%20with%20you&amp;body=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Fnvidia-grace-hopper-superchip-architecture-in-depth%2F" class="for-mail">E</a>

</div>

<img src="data:image/svg+xml;base64,<svg class="nv-ai-summary__icon" xmlns="http://www.w3.org/2000/svg" width="25" height="25" viewbox="0 0 25 25" fill="none" aria-hidden="true">
                <path fill="currentColor" fill-rule="evenodd" clip-rule="evenodd" d="M22.4915 15.3019C22.294 15.3047 22.0976 15.3316 21.9066 15.3819L20.254 12.9019L21.905 10.4219C22.0967 10.4731 22.2933 10.4987 22.4915 10.5019C22.8844 10.5032 23.2716 10.4078 23.619 10.2241C23.9665 10.0404 24.2635 9.77405 24.4839 9.44845C24.7044 9.12285 24.8415 8.74799 24.8832 8.35687C24.925 7.96575 24.8701 7.57035 24.7233 7.20547C24.5766 6.84059 24.3425 6.51741 24.0417 6.26437C23.7409 6.01134 23.3825 5.8362 22.9982 5.75437C22.6139 5.67255 22.2154 5.68654 21.8378 5.79512C21.4601 5.9037 21.1149 6.10354 20.8326 6.37706L15.2709 3.59305C15.2868 3.49705 15.2964 3.39946 15.2996 3.30186C15.2996 2.66534 15.0471 2.05489 14.5975 1.6048C14.1479 1.15471 13.5381 0.901855 12.9023 0.901855C12.2665 0.901855 11.6568 1.15471 11.2072 1.6048C10.7576 2.05489 10.5051 2.66534 10.5051 3.30186C10.5083 3.39946 10.5178 3.49705 10.5338 3.59305L4.97211 6.37706C4.68976 6.10267 4.34433 5.90202 3.96626 5.79281C3.58818 5.6836 3.18908 5.66918 2.80412 5.75082C2.41916 5.83245 2.06018 6.00764 1.7588 6.26093C1.45743 6.51423 1.22292 6.83786 1.07595 7.20329C0.928981 7.56872 0.874058 7.96474 0.916028 8.35644C0.957998 8.74813 1.09557 9.12348 1.31662 9.44939C1.53767 9.7753 1.8354 10.0418 2.18358 10.2253C2.53176 10.4088 2.9197 10.5038 3.31319 10.5019C3.51136 10.4987 3.70794 10.4715 3.89813 10.4219L5.55066 12.9019L3.89973 15.3819C3.70818 15.3314 3.51122 15.3046 3.31319 15.3019C2.92029 15.3005 2.53308 15.3959 2.18565 15.5796C1.83822 15.7633 1.54122 16.0297 1.32077 16.3553C1.10032 16.6809 0.963189 17.0557 0.921442 17.4468C0.879695 17.838 0.934613 18.2334 1.08136 18.5982C1.22811 18.9631 1.46219 19.2863 1.76301 19.5393C2.06382 19.7924 2.42215 19.9675 2.80646 20.0493C3.19077 20.1312 3.58928 20.1172 3.96691 20.0086C4.34455 19.9 4.68974 19.7002 4.97211 19.4267L10.5338 22.2107C10.5178 22.3067 10.5083 22.4043 10.5051 22.5019C10.5051 23.1384 10.7576 23.7488 11.2072 24.1989C11.6568 24.649 12.2665 24.9019 12.9023 24.9019C13.5381 24.9019 14.1479 24.649 14.5975 24.1989C15.0471 23.7488 15.2996 23.1384 15.2996 22.5019C15.2958 22.4043 15.2862 22.3071 15.2709 22.2107L20.8326 19.4267C21.1149 19.701 21.4604 19.9017 21.8384 20.0109C22.2165 20.1201 22.6156 20.1345 23.0006 20.0529C23.3855 19.9713 23.7445 19.7961 24.0459 19.5428C24.3473 19.2895 24.5818 18.9659 24.7287 18.6004C24.8757 18.235 24.9306 17.839 24.8887 17.4473C24.8467 17.0556 24.7091 16.6802 24.4881 16.3543C24.267 16.0284 23.9693 15.7619 23.6211 15.5784C23.2729 15.3949 22.885 15.2999 22.4915 15.3019ZM12.8884 2.50274C13.0185 2.50324 13.1465 2.53552 13.2613 2.59679C13.3761 2.65805 13.4742 2.74644 13.5471 2.85429C13.62 2.96214 13.6655 3.08617 13.6797 3.21563C13.6939 3.34509 13.6763 3.47605 13.6284 3.59714L13.606 3.64194C13.5429 3.77981 13.4416 3.89664 13.3141 3.97855C13.1866 4.06045 13.0383 4.10399 12.8868 4.10399C12.7353 4.10399 12.587 4.06045 12.4596 3.97855C12.3321 3.89664 12.2307 3.77981 12.1676 3.64194L12.1453 3.59874C12.097 3.47731 12.0791 3.34589 12.0933 3.21596C12.1074 3.08603 12.1532 2.96156 12.2265 2.85342C12.2998 2.74528 12.3985 2.65678 12.5139 2.59564C12.6293 2.53451 12.7579 2.50261 12.8884 2.50274ZM23.2767 8.10274C23.2767 8.31491 23.1925 8.5184 23.0426 8.66843C22.8928 8.81845 22.6895 8.90274 22.4776 8.90274C22.2656 8.90274 22.0624 8.81845 21.9125 8.66843C21.7627 8.5184 21.6785 8.31491 21.6785 8.10274C21.6785 7.89057 21.7627 7.68708 21.9125 7.53705C22.0624 7.38702 22.2656 7.30274 22.4776 7.30274C22.6895 7.30274 22.8928 7.38702 23.0426 7.53705C23.1925 7.68708 23.2767 7.89057 23.2767 8.10274ZM2.50017 8.10274C2.503 7.92305 2.56617 7.74956 2.67951 7.6102C2.79285 7.47085 2.94976 7.37376 3.12495 7.33458C3.30014 7.2954 3.4834 7.31641 3.6452 7.39423C3.807 7.47205 3.93792 7.60214 4.01685 7.76354L4.03923 7.80834C4.09871 7.95306 4.11376 8.11225 4.08244 8.26558C4.05113 8.4189 3.97488 8.55941 3.86343 8.66914C3.75158 8.78076 3.60921 8.8567 3.45428 8.88737C3.29936 8.91805 3.13883 8.90207 2.99297 8.84147C2.8471 8.78086 2.72245 8.67835 2.63474 8.54687C2.54703 8.41539 2.5002 8.26084 2.50017 8.10274ZM2.50017 17.7027C2.50017 17.4906 2.58436 17.2871 2.73422 17.1371C2.88408 16.987 3.08733 16.9027 3.29927 16.9027C3.5112 16.9027 3.71445 16.987 3.86431 17.1371C4.01417 17.2871 4.09836 17.4906 4.09836 17.7027C4.09836 17.9149 4.01417 18.1184 3.86431 18.2684C3.71445 18.4185 3.5112 18.5027 3.29927 18.5027C3.08733 18.5027 2.88408 18.4185 2.73422 18.2684C2.58436 18.1184 2.50017 17.9149 2.50017 17.7027ZM12.8884 23.3027C12.7566 23.3028 12.6268 23.2702 12.5106 23.2078C12.3944 23.1455 12.2955 23.0553 12.2225 22.9454C12.1496 22.8355 12.1049 22.7092 12.0926 22.5778C12.0802 22.4464 12.1005 22.314 12.1517 22.1923C12.2128 22.0519 12.3129 21.9319 12.4401 21.8468C12.5673 21.7616 12.7163 21.7148 12.8693 21.712C13.0223 21.7091 13.1729 21.7503 13.3032 21.8306C13.4336 21.911 13.5381 22.0271 13.6044 22.1651L13.6268 22.2099C13.6868 22.3541 13.7024 22.5129 13.6716 22.6659C13.6409 22.819 13.5651 22.9594 13.4542 23.0691C13.3798 23.1434 13.2916 23.2022 13.1945 23.2423C13.0974 23.2824 12.9934 23.3029 12.8884 23.3027ZM22.4776 18.5027C22.3267 18.5016 22.1793 18.4577 22.0523 18.3761C21.9253 18.2946 21.824 18.1787 21.76 18.0419L21.7376 17.9971C21.6981 17.9029 21.6777 17.8017 21.6777 17.6995C21.6777 17.5973 21.6981 17.4962 21.7376 17.4019L21.752 17.3747C21.8098 17.2422 21.9023 17.1279 22.0199 17.0438C22.1374 16.9598 22.2755 16.9092 22.4194 16.8974C22.5633 16.8857 22.7078 16.9132 22.8373 16.9771C22.9669 17.0409 23.0768 17.1388 23.1552 17.2601C23.2337 17.3815 23.2778 17.5219 23.283 17.6664C23.2881 17.8109 23.254 17.9541 23.1843 18.0808C23.1146 18.2074 23.012 18.3128 22.8872 18.3857C22.7625 18.4586 22.6204 18.4963 22.476 18.4947L22.4776 18.5027ZM18.0186 9.80834L20.1714 8.73154C20.1554 8.63554 20.1458 8.53794 20.1426 8.44034C20.1458 8.34274 20.1554 8.24514 20.1714 8.14914L15.2841 5.70274L18.0186 9.80834ZM10.6158 5.70434L5.73012 8.14914C5.74545 8.24555 5.75505 8.34279 5.75888 8.44034C5.75569 8.53794 5.7461 8.63554 5.73012 8.73154L7.88288 9.80834L10.6158 5.70434ZM5.73012 17.7491L7.88288 16.6723L10.6174 20.7779L5.73012 18.3315C5.7461 18.2355 5.75569 18.1379 5.75888 18.0403C5.75505 17.9428 5.74545 17.8456 5.73012 17.7491ZM12.2108 13.5363L12.2332 13.5795H12.2364C12.3 13.7175 12.4021 13.8341 12.5303 13.9155C12.6585 13.9968 12.8074 14.0395 12.9592 14.0383C13.1109 14.0371 13.2592 13.9921 13.3861 13.9088C13.513 13.8255 13.6132 13.7072 13.6747 13.5683L13.6891 13.5411C13.7292 13.444 13.7498 13.3398 13.7497 13.2347C13.7496 13.1296 13.7288 13.0255 13.6885 12.9284C13.6482 12.8313 13.5892 12.7431 13.5148 12.6688C13.4405 12.5946 13.3523 12.5357 13.2552 12.4955C13.1581 12.4554 13.0541 12.4348 12.9491 12.4349C12.8441 12.435 12.7401 12.4559 12.6431 12.4962C12.5461 12.5365 12.4581 12.5956 12.3839 12.67C12.3097 12.7444 12.2509 12.8328 12.2108 12.9299C12.1706 13.026 12.1499 13.129 12.1499 13.2331C12.1499 13.3373 12.1706 13.4403 12.2108 13.5363ZM14.6097 14.9715C14.3637 15.2066 14.0706 15.3866 13.7498 15.4995V20.1987L16.5786 15.9571L14.6097 14.9715ZM15.348 13.2403C15.3448 13.3395 15.3353 13.4387 15.3193 13.5379L17.4736 14.6083L18.3846 13.2403L17.472 11.8723L15.3193 12.9491C15.3346 13.0456 15.3442 13.1428 15.348 13.2403ZM13.7498 10.9939C14.0706 11.1069 14.3637 11.2869 14.6097 11.5219L16.5786 10.5299L13.7498 6.28194V10.9939ZM12.1517 10.9875V6.28194L9.32285 10.5299L11.2918 11.5155C11.5378 11.2805 11.8309 11.1005 12.1517 10.9939ZM10.5535 13.2403C10.5567 13.1427 10.5662 13.0451 10.5822 12.9491L8.42787 11.8723L7.5169 13.2403L8.42946 14.6083L10.5822 13.5315C10.5662 13.4355 10.5567 13.3379 10.5535 13.2403ZM12.1517 15.4931C11.8309 15.3802 11.5378 15.2002 11.2918 14.9651L9.32285 15.9507L12.1517 20.1987V15.4931ZM20.1714 17.7491L18.0186 16.6723L15.2841 20.7779L20.1714 18.3315C20.1554 18.2355 20.1458 18.1379 20.1426 18.0403C20.1458 17.9427 20.1554 17.8451 20.1714 17.7491ZM18.912 15.3299L20.2049 15.9779L19.3435 14.6803L18.912 15.3299ZM20.2049 10.5027L18.912 11.1507L19.3435 11.8003L20.2049 10.5027ZM6.98949 11.1443L5.69656 10.5043L6.55798 11.8003L6.98949 11.1443ZM5.69656 15.9779L6.98949 15.3299L6.55798 14.6803L5.69656 15.9779Z" />
            </svg>" class="nv-ai-summary__icon" />

## AI-Generated Summary

<img src="data:image/svg+xml;base64,PHN2ZyBjbGFzcz0ibnYtYWktc3VtbWFyeV9fdG9nZ2xlLWljb24iIHdpZHRoPSIxNCIgaGVpZ2h0PSI5IiB2aWV3Ym94PSIwIDAgMTQgOSIgZmlsbD0ibm9uZSIgeG1sbnM9Imh0dHA6Ly93d3cudzMub3JnLzIwMDAvc3ZnIiBhcmlhLWhpZGRlbj0idHJ1ZSI+CiAgICAgICAgPHBhdGggZD0iTTEyLjU3NDIgMkw3LjQ0OTIzIDdMMi4zMjQyNSAyIiBzdHJva2U9ImN1cnJlbnRDb2xvciIgc3Ryb2tlLXdpZHRoPSIyIiBzdHJva2UtbGluZWNhcD0ic3F1YXJlIiAvPgogICAgPC9zdmc+" class="nv-ai-summary__toggle-icon" />

<div class="nv-ai-summary__body">

<div class="nv-ai-summary__content">

- The <a href="https://nvda.ws/3TKV7KV" data-wpel-link="external" target="_blank" rel="follow">NVIDIA Grace Hopper Superchip Architecture</a> combines the NVIDIA Grace CPU and NVIDIA Hopper GPU with a coherent 900 GB/s NVLink-C2C interconnect to create the first true heterogeneous accelerated platform for high-performance computing and AI workloads.
- NVLink-C2C hardware memory coherency enables CPU and GPU threads to concurrently access both CPU-resident LPDDR5X memory and GPU-resident HBM3 memory without explicit data movement, providing up to 608 GB of GPU-addressable memory per superchip and up to 150 TB across 256 NVLink-connected superchips.
- The platform supports a unified programming model across ISO C++, ISO Fortran, Python, OpenACC, OpenMP, CUDA C++, and CUDA Fortran through the <a href="https://developer.nvidia.com/hpc-sdk" data-wpel-link="internal" target="_self" rel="follow">NVIDIA HPC SDK</a>, with applications transparently benefiting from NVLink-C2C's higher bandwidth, lower latency, and hardware-accelerated atomic operations.
- The NVIDIA Grace CPU delivers up to 72 Arm Neoverse V2 cores with up to 512 GB of LPDDR5X memory at 546 GB/s bandwidth, while the NVIDIA Hopper GPU provides fourth-generation Tensor Cores, a Transformer Engine, and up to 96 GB of HBM3 memory at 3000 GB/s bandwidth.
- The NVLink Switch System connects up to 256 Grace Hopper Superchips with 115.2 TB/s all-to-all bandwidth, enabling GPU threads to address all system memory using standard load, store, and atomic operations through communication libraries such as MPI, NCCL, and NVSHMEM.

### Next Steps

- Read the <a href="https://nvda.ws/3frjtKQ" data-wpel-link="external" target="_blank" rel="follow">NVIDIA Grace Hopper Architecture whitepaper</a> for detailed performance breakthroughs over PCIe-based accelerated platforms.
- Explore the <a href="https://developer.nvidia.com/blog/nvidia-hopper-architecture-in-depth/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA Hopper Architecture In-Depth</a> technical overview.
- Review the <a href="https://developer.nvidia.com/hpc-sdk" data-wpel-link="internal" target="_self" rel="follow">NVIDIA HPC SDK</a> for accelerated libraries, compilers, and profiling tools supporting the Grace Hopper programming model.

</div>

<div class="nv-ai-summary__disclosure">

Powered by NVIDIA Nemotron. AI-generated content may summarize information incompletely. Verify important information. <a href="https://www.nvidia.com/en-us/agreements/trustworthy-ai/terms/" rel="noreferrer noopener follow" target="_self" data-wpel-link="internal">Learn more</a>

</div>

</div>

<div class="entry-content">

The <a href="https://nvda.ws/3TKV7KV" data-wpel-link="external" target="_blank" rel="follow">NVIDIA Grace Hopper Superchip Architecture</a> is the first true heterogeneous accelerated platform for <a href="https://www.nvidia.com/en-us/high-performance-computing/" data-wpel-link="internal" target="_self" rel="follow"></a> <a href="https://www.nvidia.com/en-us/high-performance-computing/" data-wpel-link="internal" target="_self" rel="follow">high-performance computing</a> (HPC) and <a href="https://www.nvidia.com/en-us/deep-learning-ai/products/solutions/" data-wpel-link="internal" target="_self" rel="follow">AI</a> workloads. It accelerates applications with the strengths of both GPUs and CPUs while providing the simplest and most productive distributed heterogeneous programming model to date. Scientists and engineers can focus on solving the world’s most important problems.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance.png" class="wp-image-57224" style="width:1000px;height:518px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-300x155.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-625x324.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-179x93.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-768x398.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-1536x796.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-500x259.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-160x83.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-362x188.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-212x110.png 212w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-1024x531.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="1036" alt="Bar chart shows the simulations of the speedups delivered by Grace Hopper over x86 + Hopper platforms for ML Training, Databases, and HPC Applications. For ML Training: up to 4x for Natural Language Processing (NLP), 3.5x for Deep Learning Recommender Models (DLRM), and 1.9x for Graph Neural Networks (GNN). Up to 4.4x for Database Hash Join. For HPC applications, up to 3.6x for ABINIT, 1.75x for OpenFOAM, and 1.3x for multi-node GROMACS." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%201036%22%3E%3C/svg%3E" class="lazyload wp-image-57224" style="width:1000px;height:518px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-300x155.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-625x324.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-179x93.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-768x398.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-1536x796.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-500x259.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-160x83.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-362x188.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-212x110.png 212w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-1024x531.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="1036" alt="Bar chart shows the simulations of the speedups delivered by Grace Hopper over x86 + Hopper platforms for ML Training, Databases, and HPC Applications. For ML Training: up to 4x for Natural Language Processing (NLP), 3.5x for Deep Learning Recommender Models (DLRM), and 1.9x for Graph Neural Networks (GNN). Up to 4.4x for Database Hash Join. For HPC applications, up to 3.6x for ABINIT, 1.75x for OpenFOAM, and 1.3x for multi-node GROMACS." />
<figcaption><em>Figure 1. End-user application performance simulations of Grace Hopper vs x86+Hopper (Source:</em> <a href="https://nvda.ws/3frjtKQ" data-wpel-link="external" target="_blank" rel="follow"><em>NVIDIA Grace Hopper Architecture whitepaper</em></a><em>)</em></figcaption>
</figure>

</div>

In this post, you learn all about the Grace Hopper Superchip and highlight the performance breakthroughs that NVIDIA Grace Hopper delivers. For more information about the speedups that Grace Hopper achieves  over the most powerful PCIe-based accelerated platforms using NVIDIA Hopper H100 GPUs, see the <a href="https://nvda.ws/3frjtKQ" data-wpel-link="external" target="_blank" rel="follow">NVIDIA Grace Hopper Superchip Architecture</a> whitepaper.

## Performance and productivity for strong-scaling HPC and giant AI workloads<a href="#performance_and_productivity_for_strong-scaling_hpc_and_giant_ai_workloads" class="heading-anchor-link" aria-label="Scroll to Performance and productivity for strong-scaling HPC and giant AI workloads section"><em></em></a>

The NVIDIA Grace Hopper Superchip architecture brings together the groundbreaking performance of the <a href="https://developer.nvidia.com/blog/nvidia-hopper-architecture-in-depth/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA Hopper GPU</a> with the versatility of the <a href="https://www.nvidia.com/en-us/data-center/grace-cpu/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA Grace CPU</a>, connected with a high bandwidth and memory coherent <a href="https://www.nvidia.com/en-us/data-center/nvlink-c2c/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA NVLink Chip-2-Chip (C2C)</a> interconnect in a single superchip, and support for the new <a href="https://www.nvidia.com/en-us/data-center/nvlink/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA NVLink Switch System</a>.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview.png" class="wp-image-57226" style="width:1000px;height:509px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-300x153.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-625x318.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-179x91.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-768x391.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-1536x782.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-500x255.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-160x81.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-362x184.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-216x110.png 216w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-1024x521.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="1018" alt="Diagram of the NVIDIA Grace Hopper Superchip showing the LPDDR5X, HBM3, NVLink, and I/O bandwidths as well as memory capacities. Hopper has up to 96 GB HBM3 at up to 3000 GB/s bandwidth. Grace has up to 512 GB LPDDR5X at up to 546 GB/s bandwidth. Grace and Hopper are connected with NVLink C2C at up to 900 GB/s bandwidth. The Grace Hopper Superchip has up to 64 PCIe Gen 5 lanes delivering up to 512 GB/s bandwidth and up to 18x NVLink for lanes delivering up to 900 GB/s to the NVLink Switch network." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%201018%22%3E%3C/svg%3E" class="lazyload wp-image-57226" style="width:1000px;height:509px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-300x153.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-625x318.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-179x91.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-768x391.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-1536x782.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-500x255.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-160x81.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-362x184.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-216x110.png 216w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-overview-1024x521.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="1018" alt="Diagram of the NVIDIA Grace Hopper Superchip showing the LPDDR5X, HBM3, NVLink, and I/O bandwidths as well as memory capacities. Hopper has up to 96 GB HBM3 at up to 3000 GB/s bandwidth. Grace has up to 512 GB LPDDR5X at up to 546 GB/s bandwidth. Grace and Hopper are connected with NVLink C2C at up to 900 GB/s bandwidth. The Grace Hopper Superchip has up to 64 PCIe Gen 5 lanes delivering up to 512 GB/s bandwidth and up to 18x NVLink for lanes delivering up to 900 GB/s to the NVLink Switch network." />
<figcaption><em>Figure 2. NVIDIA Grace Hopper Superchip logical overview</em></figcaption>
</figure>

</div>

NVIDIA NVLink-C2C is an NVIDIA memory coherent, high-bandwidth, and low-latency superchip interconnect. It is the heart of the Grace Hopper Superchip and delivers up to 900 GB/s total bandwidth. This is 7x higher bandwidth than x16 PCIe Gen5 lanes commonly used in accelerated systems.

NVLink-C2C memory coherency increases developer productivity and performance and enables GPUs to access large amounts of memory.CPU and GPU threads can now concurrently and transparently access both CPU– and GPU-resident memory, enabling you to focus on algorithms instead of explicit memory management.

Memory coherency enables  you to transfer only the data you need, and not migrate entire pages to and from the GPU. It also enables lightweight synchronization primitives across GPU and CPU threads by enabling native atomic operations from both the CPU and GPU. NVLink-C2C with Address Translation Services (ATS) leverages the NVIDIA Hopper Direct Memory Access (DMA) copy engines for accelerating bulk transfers of pageable memory across host and device.

NVLink-C2C enables applications to oversubscribe the GPU’s memory and directly utilize NVIDIA Grace CPU’s memory at high bandwidth. With up to 512 GB of LPDDR5X CPU memory per Grace Hopper Superchip, the GPU has direct high-bandwidth access to 4x more memory than what is available with HBM. Combined with the NVIDIA NVLink Switch System, all GPU threads running on up to 256 NVLink-connected GPUs can now access up to 150 TB of memory at high bandwidth. Fourth-generation NVLink enables accessing peer memory using direct loads, stores, and atomic operations, enabling accelerated applications to solve larger problems more easily than ever.

Together with NVIDIA networking technologies, Grace Hopper Superchips provide the recipe for the next generation of HPC supercomputers and AI factories. Customers can take on larger datasets, more complex models, and new workloads, solving them more quickly than before.

The main innovations of the NVIDIA Grace Hopper Superchip are as follows:

- NVIDIA Grace CPU:
  - Up to 72x Arm Neoverse V2 cores with Armv9.0-A ISA and 4×128-bit SIMD units per core.
  - Up to 117 MB of L3 Cache.
  - Up to 512 GB of LPDDR5X memory delivering up to 546 GB/s of memory bandwidth.
  - Up to 64x PCIe Gen5 lanes.
  - NVIDIA Scalable Coherency Fabric (SCF) mesh and distributed cache with up to 3.2 TB/s memory bandwidth.
  - High developer productivity with a single CPU NUMA node.
- NVIDIA Hopper GPU:
  - Up to 144 SMs with fourth-generation Tensor Cores, Transformer Engine, DPX, and 3x higher FP32 and FP64 throughout compared to the NVIDIA A100 GPU.
  - Up to 96 GB of HBM3 memory delivering up to 3000 GB/s.
  - 60 MB L2 Cache.
  - NVLink 4 and PCIe 5.
- NVIDIA NVLink-C2C:
  - Hardware-coherent interconnect between the Grace CPU and Hopper GPU.
  - Up to 900 GB/s total bandwidth, 450 GB/s/dir.
  - The Extended GPU Memory feature enables the Hopper GPU to address all CPU memory as GPU memory. Each Hopper GPU can address up to 608 GB of memory within a superchip.
- NVIDIA NVLink Switch System:
  - Connects up to 256x NVIDIA Grace Hopper Superchips using NVLink 4.
  - Each NVLink-connected Hopper GPU can address all HBM3 and LPDDR5X memory of all superchips in the network, for up to 150 TB of GPU addressable memory.

## Programming model for performance, portability, and productivity<a href="#programming_model_for_performance_portability_and_productivity" class="heading-anchor-link" aria-label="Scroll to Programming model for performance, portability, and productivity section"><em></em></a>

Traditional heterogeneous platforms with PCIe-connected accelerators require users to follow a complex programming model that involves manually managing device memory allocations and data transfer to and from the host.

The NVIDIA Grace Hopper Superchip platform is heterogeneous and easy to program, and NVIDIA is committed to making it accessible to all developers and applications, independent of the programming language of choice.

Both the Grace Hopper Superchip and the platform are built to enable you to pick the right language for the task at hand, and the <a href="https://developer.nvidia.com/cuda-llvm-compiler" data-wpel-link="internal" target="_self" rel="follow">NVIDIA CUDA LLVM Compiler</a> APIs enable you to bring your preferred programming language to the CUDA platform with the same level of code-generation quality and optimizations as NVIDIA compilers and tools.

The languages provided by NVIDIA for the CUDA platform (Figure 3) include accelerated standard languages like ISO C++, ISO Fortran, and Python. The platform also supports directive-based programming models like OpenACC, OpenMP, CUDA C++, and CUDA Fortran. The <a href="https://developer.nvidia.com/hpc-sdk" data-wpel-link="internal" target="_self" rel="follow">NVIDIA HPC SDK</a> supports all these approaches, along with a rich set of accelerated libraries and tools for profiling and debugging.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models.png" class="wp-image-57227" style="width:1000px;height:329px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-300x99.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-625x205.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-179x59.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-768x252.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-1536x505.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-500x164.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-160x53.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-362x119.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-335x110.png 335w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-1024x337.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="657" alt="The three pillars of the NVIDIA Grace Hopper Superchip programming models are built on top of accelerated libraries, frameworks, and SDKs. The first pillar is Accelerated Standard Languages and includes programming languages like ISO C++, ISO Fortran, and Python. The second pillar is Incremental Portable Optimization and includes OpenMP and OpenACC directives. Finally, maximum performance can be obtained by specializing applications for the CUDA platform using CUDA C++ or CUDA Fortran." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%20657%22%3E%3C/svg%3E" class="lazyload wp-image-57227" style="width:1000px;height:329px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-300x99.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-625x205.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-179x59.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-768x252.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-1536x505.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-500x164.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-160x53.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-362x119.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-335x110.png 335w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-superchip-programming-models-1024x337.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="657" alt="The three pillars of the NVIDIA Grace Hopper Superchip programming models are built on top of accelerated libraries, frameworks, and SDKs. The first pillar is Accelerated Standard Languages and includes programming languages like ISO C++, ISO Fortran, and Python. The second pillar is Incremental Portable Optimization and includes OpenMP and OpenACC directives. Finally, maximum performance can be obtained by specializing applications for the CUDA platform using CUDA C++ or CUDA Fortran." />
<figcaption><em>Figure 3.</em> <strong><em></em></strong> <em>NVIDIA Grace Hopper Superchip programming models</em></figcaption>
</figure>

</div>

NVIDIA is a member of the ISO C++ and ISO Fortran programming-language communities, which have enabled ISO C++ and ISO Fortran standard-compliant applications to run on both NVIDIA CPUs and NVIDIA GPUs without any language extensions. For more information about running ISO-conforming applications on GPUs, see <a href="https://developer.nvidia.com/blog/multi-gpu-programming-with-standard-parallel-c-part-1/" data-wpel-link="internal" target="_self" rel="follow">Multi-GPU Programming with Standard Parallel C++</a> and <a href="https://developer.nvidia.com/blog/using-fortran-standard-parallel-programming-for-gpu-acceleration/" data-wpel-link="internal" target="_self" rel="follow">Using Fortran Standard Parallel Programming For GPU Acceleration</a>.

This technology relies heavily on the hardware-accelerated memory coherency provided by NVIDIA NVLink-C2C and NVIDIA Unified Virtual Memory. As shown in Figure 4, in traditional PCIe-connected x86+Hopper systems without ATS, the CPU and the GPU have independent per-process page tables, and system-allocated memory is not directly accessible from the GPU. When a program allocates memory with the system allocator but the page entry is not available in the GPU’s page table, then accessing the memory from a GPU thread fails.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables.jpg" class="wp-image-57228" style="width:721px;height:330px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables.jpg 1441w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-300x137.jpg 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-625x286.jpg 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-179x82.jpg 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-768x351.jpg 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-500x229.jpg 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-160x73.jpg 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-362x166.jpg 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-241x110.jpg 241w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-1024x468.jpg 1024w" sizes="(max-width: 1441px) 100vw, 1441px" width="1441" height="659" alt="Diagram shows that, on noncoherent platforms with disjoint page tables, when CPU or GPU threads attempt to access a page that is not available in their own separate page tables, the access faults." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201441%20659%22%3E%3C/svg%3E" class="lazyload wp-image-57228" style="width:721px;height:330px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables.jpg 1441w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-300x137.jpg 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-625x286.jpg 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-179x82.jpg 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-768x351.jpg 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-500x229.jpg 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-160x73.jpg 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-362x166.jpg 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-241x110.jpg 241w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-system-disjoint-page-tables-1024x468.jpg 1024w" data-sizes="(max-width: 1441px) 100vw, 1441px" width="1441" height="659" alt="Diagram shows that, on noncoherent platforms with disjoint page tables, when CPU or GPU threads attempt to access a page that is not available in their own separate page tables, the access faults." />
<figcaption><em>Figure 4. NVIDIA Hopper System with disjoint page tables</em></figcaption>
</figure>

</div>

In NVIDIA Grace Hopper Superchip-based systems, ATS enables the CPU and GPU to share a single per-process page table, enabling all CPU and GPU threads to access all system-allocated memory, which can reside on physical CPU or GPU memory. The CPU heap, CPU thread stack, global variables, memory-mapped files, and interprocess memory are accessible to all CPU and GPU threads.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip.png" class="wp-image-57230" style="width:718px;height:336px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip.png 1435w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-300x140.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-625x292.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-179x84.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-768x359.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-500x234.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-160x75.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-362x169.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-235x110.png 235w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-1024x479.png 1024w" sizes="(max-width: 1435px) 100vw, 1435px" width="1435" height="671" alt="Diagram shows that, on NVIDIA Grace Hopper Superchip systems with ATS, the CPU and GPU can both access the system page table. This enables GPU and CPU threads to access all-system allocated memory, independently of where it resides." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201435%20671%22%3E%3C/svg%3E" class="lazyload wp-image-57230" style="width:718px;height:336px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip.png 1435w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-300x140.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-625x292.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-179x84.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-768x359.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-500x234.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-160x75.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-362x169.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-235x110.png 235w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/address-translation-services-grace-hopper-superchip-1024x479.png 1024w" data-sizes="(max-width: 1435px) 100vw, 1435px" width="1435" height="671" alt="Diagram shows that, on NVIDIA Grace Hopper Superchip systems with ATS, the CPU and GPU can both access the system page table. This enables GPU and CPU threads to access all-system allocated memory, independently of where it resides." />
<figcaption><em>Figure 5. Address Translation Services in an NVIDIA Grace Hopper Superchip system</em></figcaption>
</figure>

</div>

NVIDIA NVLink-C2C hardware-coherency enables the Grace CPU to cache GPU memory at cache-line granularity and for the GPU and CPU to access each other’s memory without page-migrations.

NVLink-C2C also accelerates all atomic operations supported by the CPU and GPU on system-allocated memory. <a href="https://docs.nvidia.com/cuda/cuda-programming-guide/03-advanced/advanced-kernel-programming.html#scoped-atomics" data-wpel-link="internal" target="_self" rel="follow">Scoped atomic operations</a> are fully supported and enable fine-grained and scalable synchronization across all threads in the system.

The runtime backs system-allocated memory with physical memory on first touch, either on LPDDR5X or HBM3, depending on whether a CPU or a GPU thread accesses it first. From an OS perspective, the Grace CPU and Hopper GPU are just two separate NUMA nodes. System-allocated memory is migratable so the runtime can change its physical memory backing to improve application performance or deal with memory pressure.

For PCIe-based platforms such as x86 or Arm, you can use the same Unified Memory programming model as the NVIDIA Grace Hopper model. That will eventually be possible through the <a href="https://on-demand.gputechconf.com/gtc/2017/presentation/s7764_john-hubbardgpus-using-hmm-blur-the-lines-between-cpu-and-gpu.pdf" data-wpel-link="external" target="_blank" rel="follow">Heterogeneous Memory Management (HMM) feature</a>, which is a combination of Linux kernel features and NVIDIA driver features that use software to emulate memory coherence between CPUs and GPUs.

On NVIDIA Grace Hopper, these applications transparently benefit from the higher-bandwidth, lower-latency, higher atomic throughput, and hardware acceleration for memory coherency provided by NVLink-C2C, without any software changes.

## Superchip architectural features<a href="#superchip_architectural_features" class="heading-anchor-link" aria-label="Scroll to Superchip architectural features section"><em></em></a>

Here’s a look at the main innovations of the NVIDIA Grace Hopper architecture:

- NVIDIA Grace CPU
- NVIDIA Hopper GPU
- NVLink-C2C
- NVLink Switch System
- Extended GPU memory

### NVIDIA Grace CPU<a href="#nvidia_grace_cpu" class="heading-anchor-link" aria-label="Scroll to NVIDIA Grace CPU section"><em></em></a>

As the parallel compute capabilities of GPUs continue to triple every generation, a fast and efficient CPU is critical to prevent the serial and CPU-only fractions of modern workloads from dominating performance.

NVIDIA Grace CPU is the <a href="https://www.nvidia.com/en-us/data-center/" data-wpel-link="internal" target="_self" rel="follow">first NVIDIA data center</a> <a href="https://www.nvidia.com/en-us/data-center/" data-wpel-link="internal" target="_self" rel="follow">CPU</a>, and it is <a href="https://developer.nvidia.com/blog/inside-nvidia-grace-cpu-nvidia-amps-up-superchip-engineering-for-hpc-and-ai/" data-wpel-link="internal" target="_self" rel="follow">built from the ground up to create HPC and AI</a> <a href="https://developer.nvidia.com/blog/inside-nvidia-grace-cpu-nvidia-amps-up-superchip-engineering-for-hpc-and-ai/" data-wpel-link="internal" target="_self" rel="follow">superchips</a>. Grace provides up to 72 Arm Neoverse V2 CPU cores with the <a href="https://www.arm.com/company/news/2021/03/arms-answer-to-the-future-of-ai-armv9-architecture" data-wpel-link="external" target="_blank" rel="follow">Armv9.0-A ISA</a>, and 4×128-bit wide SIMD units per core with support for Arm’s <a href="https://developer.arm.com/documentation/102340/0001/Introducing-SVE2" data-wpel-link="external" target="_blank" rel="follow">Scalable Vector Extensions 2</a> <a href="https://developer.arm.com/documentation/102340/0001/Introducing-SVE2" data-wpel-link="external" target="_blank" rel="follow">(SVE2)</a> SIMD instruction set.

NVIDIA Grace delivers leading per-thread performance, while providing higher energy efficiency than traditional CPUs. The 72 CPU cores deliver up to a 370 (estimated) score on <a href="http://spec.org/cpu2017/" data-wpel-link="external" target="_blank" rel="follow">SPECrate 2017_int_base</a>, ensuring high-performance to satisfy the demands of both HPC and AI heterogeneous workloads.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu.png" class="wp-image-57231" style="width:1000px;height:482px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-300x145.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-625x301.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-179x86.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-768x370.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-1536x740.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-500x241.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-160x77.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-362x174.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-228x110.png 228w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-1024x493.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="963" alt="Bar chart hows simulations of the speedups and energy savings delivered by the Grace CPUs in NVIDIA Grace Hopper Superchips over AMD Milan 7763. OpenFOAM HPC Motorbike Large benchmark is 2.5x faster and uses 3.5x less energy. NEMO GYRE_PISCES, scaling factor nn_GYRE=25, benchmark is 1.6x faster and uses 2.2x less energy. BWA Whole Human Genome (HG002 30x) benchmark is 1.5x faster and uses 2.0x less energy." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%20963%22%3E%3C/svg%3E" class="lazyload wp-image-57231" style="width:1000px;height:482px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-300x145.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-625x301.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-179x86.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-768x370.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-1536x740.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-500x241.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-160x77.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-362x174.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-228x110.png 228w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/end-user-app-performance-grace-cpu-1024x493.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="963" alt="Bar chart hows simulations of the speedups and energy savings delivered by the Grace CPUs in NVIDIA Grace Hopper Superchips over AMD Milan 7763. OpenFOAM HPC Motorbike Large benchmark is 2.5x faster and uses 3.5x less energy. NEMO GYRE_PISCES, scaling factor nn_GYRE=25, benchmark is 1.6x faster and uses 2.2x less energy. BWA Whole Human Genome (HG002 30x) benchmark is 1.5x faster and uses 2.0x less energy." />
<figcaption><em>Figure 6. End-user application performance and energy saving simulations of the NVIDIA Grace CPU in the Grace Hopper Superchip vs AMD Milan 7763 shows that the Grace CPU is up to 2.5x faster while using 4x less energy</em></figcaption>
</figure>

</div>

Modern GPU workloads in machine learning and data science need access to huge amounts of memory. Typically, these workloads would have to use multiple GPUs to store the dataset in HBM memory.

The NVIDIA Grace CPU provides up to 512 GB of LPDDR5X memory, which delivers the optimal balance between memory capacity, energy efficiency, and performance. It supplies up to 546 GB/s of LPDDR5X memory bandwidth, which NVLink-C2C makes accessible to the GPU at 900 GB/s total bandwidth.

A single NVIDIA Grace Hopper Superchip provides the Hopper GPU with a total of 608 GB of fast-accessible memory, almost the total amount of slow memory available in a DGX-A100-80; an eight-GPU system of the previous generation.

This is made possible by the NVIDIA SCF shown in Figure 7, a mesh fabric and distributed cache that provides up to 3.2 TB/s of total bisection bandwidth to realize the full performance of CPU cores, memory, system I/Os, and NVLink-C2C. The CPU cores and SCF Cache partitions (SCCs) are distributed throughout the mesh, while Cache Switch Nodes (CSNs) route data through the fabric and serve as interfaces between the CPU cores, cache memory, and the rest of the system.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized wp-lightbox-container" data-wp-context="{&quot;imageId&quot;:&quot;6aa397b80dbfa&quot;}" data-wp-interactive="core/image" data-wp-key="6aa397b80dbfa">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview.png" class="wp-image-57232" style="width:797px;height:658px" decoding="async" data-wp-class--hide="state.isContentHidden" data-wp-class--show="state.isContentVisible" data-wp-init="callbacks.setButtonStyles" data-wp-on--click="actions.showLightbox" data-wp-on--load="callbacks.setButtonStyles" data-wp-on--pointerdown="actions.preloadImage" data-wp-on--pointerenter="actions.preloadImageWithDelay" data-wp-on--pointerleave="actions.cancelPreload" data-wp-on-window--resize="callbacks.setButtonStyles" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview.png 1062w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-300x248.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-625x516.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-139x115.png 139w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-768x634.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-363x300.png 363w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-109x90.png 109w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-362x299.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-133x110.png 133w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-1024x846.png 1024w" sizes="(max-width: 1062px) 100vw, 1062px" width="1062" height="877" alt="Diagram shows how two cores and two groups of SCC are connected to the CSNs that route data traffic to LPDDR5X, PCIe, and NVLink." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201062%20877%22%3E%3C/svg%3E" class="lazyload wp-image-57232" style="width:797px;height:658px" decoding="async" data-wp-class--hide="state.isContentHidden" data-wp-class--show="state.isContentVisible" data-wp-init="callbacks.setButtonStyles" data-wp-on--click="actions.showLightbox" data-wp-on--load="callbacks.setButtonStyles" data-wp-on--pointerdown="actions.preloadImage" data-wp-on--pointerenter="actions.preloadImageWithDelay" data-wp-on--pointerleave="actions.cancelPreload" data-wp-on-window--resize="callbacks.setButtonStyles" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview.png 1062w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-300x248.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-625x516.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-139x115.png 139w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-768x634.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-363x300.png 363w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-109x90.png 109w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-362x299.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-133x110.png 133w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/scf-overview-1024x846.png 1024w" data-sizes="(max-width: 1062px) 100vw, 1062px" width="1062" height="877" alt="Diagram shows how two cores and two groups of SCC are connected to the CSNs that route data traffic to LPDDR5X, PCIe, and NVLink." />
<img src="data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=" />
<figcaption><em>Figure 7. SCF logical overview</em></figcaption>
</figure>

</div>

### NVIDIA Hopper GPU<a href="#nvidia_hopper_gpu" class="heading-anchor-link" aria-label="Scroll to NVIDIA Hopper GPU section"><em></em></a>

The <a href="https://resources.nvidia.com/en-us-tensor-core/gtc22-whitepaper-hopper" data-wpel-link="internal" target="_self" rel="follow">NVIDIA Hopper GPU</a> is the ninth-generation NVIDIA data center GPU. It is designed to deliver orders-of-magnitude improvements for large-scale AI and HPC applications compared to previous NVIDIA Ampere GPU generations. The Hopper GPU also features multiple innovations:

- New fourth-generation Tensor Cores perform faster matrix computations than ever before on an even broader array of AI and HPC tasks.
- A new transformer engine enables H100 to deliver up to 9x faster AI training and up to 30x faster AI inference speedups on large language models compared to the prior generation NVIDIA A100 GPU.
- Improved features for spatial and temporal data locality and asynchronous execution enable applications to always keep all units busy and maximize power efficiency.
- Secure <a href="https://www.nvidia.com/en-us/technologies/multi-instance-gpu/" data-wpel-link="internal" target="_self" rel="follow">Multi-Instance GPU (MIG</a><a href="https://www.nvidia.com/en-us/technologies/multi-instance-gpu/" data-wpel-link="internal" target="_self" rel="follow">)</a> partitions the GPU into isolated, right-sized instances to maximize quality of service (QoS) for smaller workloads.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai.png" class="wp-image-57233" style="width:1000px;height:434px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-300x130.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-625x271.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-179x78.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-768x333.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-1536x667.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-500x217.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-160x69.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-362x157.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-253x110.png 253w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-1024x445.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="868" alt="First chart shows performance improvements on HPC applications (climate modeling, genomics, Lattice QCD, or 3D FFT). Second chart shows AI inference latency improvements for Megatron Turing NLG 530B. Third chart shows AI training covering Mask R-CNN, GPT-3 with 16B and 175B parameters, DLRM with 14-TB Embedding tables, and MoE Switch-XXL with 395B parameters." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%20868%22%3E%3C/svg%3E" class="lazyload wp-image-57233" style="width:1000px;height:434px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-300x130.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-625x271.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-179x78.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-768x333.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-1536x667.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-500x217.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-160x69.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-362x157.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-253x110.png 253w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-next-gen-ai-1024x445.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="868" alt="First chart shows performance improvements on HPC applications (climate modeling, genomics, Lattice QCD, or 3D FFT). Second chart shows AI inference latency improvements for Megatron Turing NLG 530B. Third chart shows AI training covering Mask R-CNN, GPT-3 with 16B and 175B parameters, DLRM with 14-TB Embedding tables, and MoE Switch-XXL with 395B parameters." />
<figcaption><em>Figure 8. NVIDIA Hopper GPU enables next-generation AI and HPC breakthroughs</em></figcaption>
</figure>

</div>

<span id="_msocom_1"></span>NVIDIA Hopper is the first truly asynchronous GPU. Its Tensor Memory Accelerator (TMA) and asynchronous transaction barrier enable threads to overlap and pipeline independent data movement and data processing, enabling applications to fully utilize all units.

New spatial and temporal locality features like thread block clusters, distributed shared memory, and thread block reconfiguration provide applications with fast access to larger amounts of shared memory and tools. This enables applications to better reuse data while it’s on-chip, further improving application performance.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution.png" class="wp-image-57235" style="width:1000px;height:362px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-300x109.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-625x226.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-179x65.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-768x278.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-1536x556.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-500x181.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-160x58.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-362x131.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-304x110.png 304w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-1024x370.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="723" alt="On the left, the diagram shows a pipeline that overlaps independent data processing and data movement between producer and consumer threads, which enables keeping all units fully utilized. On the right, the bar chart shows the impact of leveraging Hopper’s new spatial and temporal locality features on application performance." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%20723%22%3E%3C/svg%3E" class="lazyload wp-image-57235" style="width:1000px;height:362px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-300x109.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-625x226.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-179x65.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-768x278.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-1536x556.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-500x181.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-160x58.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-362x131.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-304x110.png 304w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hopper-gpu-async-execution-1024x370.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="723" alt="On the left, the diagram shows a pipeline that overlaps independent data processing and data movement between producer and consumer threads, which enables keeping all units fully utilized. On the right, the bar chart shows the impact of leveraging Hopper’s new spatial and temporal locality features on application performance." />
<figcaption><em>Figure 9. NVIDIA Hopper GPU asynchronous execution enables overlapping independent data-movement with computation (left). New spatial and temporal locality features improve application performance (right).</em></figcaption>
</figure>

</div>

For more information, see <a href="https://resources.nvidia.com/en-us-tensor-core" data-wpel-link="internal" target="_self" rel="follow">NVIDIA H100 Tensor Core Architecture Overview</a> and <a href="https://developer.nvidia.com/blog/nvidia-hopper-architecture-in-depth/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA Hopper Architecture In-Depth</a>.

### NVLink-C2C: A high-bandwidth, chip-to-chip interconnect for superchips<a href="#nvlink-c2c_a_high-bandwidth_chip-to-chip_interconnect_for_superchips" class="heading-anchor-link" aria-label="Scroll to NVLink-C2C: A high-bandwidth, chip-to-chip interconnect for superchips section"><em></em></a>

NVIDIA Grace Hopper fuses an NVIDIA Grace CPU and NVIDIA Hopper GPU into a single superchip through the NVIDIA NVLink-C2C, a 900 GB/s chip-to-chip coherent interconnect that enables programming the Grace Hopper Superchip with a unified programming model.

The NVLink Chip-2-Chip (C2C) interconnect provides a high-bandwidth direct connection between a Grace CPU and a Hopper GPU to create the Grace Hopper Superchip, which is designed for drop-in acceleration of AI and HPC applications.

With 900 GB/s of bidirectional bandwidth, NVLink-C2C provides 7x the bandwidth of x16 PCIe Gen links at lower latency. NVLink-C2C also only uses 1.3 picojoules per bit transferred, which is greater than 5x more energy-efficient than PCIe Gen 5.

Furthermore, NVLink-C2C is a coherent memory interconnect with native hardware support for system-wide atomic operations. This improves the performance of memory accesses to non-local memory, such as CPU and GPU threads accessing memory resident in the other device. Hardware coherency also improves the performance of synchronization primitives, reducing the time the GPU or CPU wait on each other and increasing total system utilization.

Finally, hardware coherency also simplifies the development of heterogeneous computing applications using popular programming languages and frameworks. For more information, see the NVIDIA Grace Hopper Programming Model section.

### NVLink Switch System<a href="#nvlink_switch_system" class="heading-anchor-link" aria-label="Scroll to NVLink Switch System section"><em></em></a>

The NVIDIA NVLink Switch System combines fourth-generation NVIDIA NVLink technology with the new third-generation NVIDIA NVSwitch. A single level of the NVSwitch connects up to eight Grace Hopper Superchips, and a second level in a fat-tree topology enables networking up to 256 Grace Hopper Superchips with NVLink. A Grace Hopper Superchip pair exchanges data at up to 900 GB/s.

With up to 256 Grace Hopper Superchips, the network delivers up to 115.2 TB/s all-to-all bandwidth. This is 9x the all-to-all bandwidth of the <a href="https://www.nvidia.com/en-us/networking/products/infiniband/" data-wpel-link="internal" target="_self" rel="follow">NVIDIA InfiniBand</a> NDR400.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch.png" class="wp-image-57236" style="width:678px;height:338px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch.png 1356w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-300x149.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-625x311.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-179x89.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-768x382.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-500x249.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-160x80.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-362x180.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-221x110.png 221w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-1024x510.png 1024w" sizes="(max-width: 1356px) 100vw, 1356px" width="1356" height="675" alt="Logical overview of the NVLink 4 NVSwitch chip including the PHY Lanes, PORT logic and SHARP accelerators, and cross-bar." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201356%20675%22%3E%3C/svg%3E" class="lazyload wp-image-57236" style="width:678px;height:338px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch.png 1356w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-300x149.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-625x311.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-179x89.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-768x382.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-500x249.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-160x80.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-362x180.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-221x110.png 221w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/nvlink-4-nvswitch-1024x510.png 1024w" data-sizes="(max-width: 1356px) 100vw, 1356px" width="1356" height="675" alt="Logical overview of the NVLink 4 NVSwitch chip including the PHY Lanes, PORT logic and SHARP accelerators, and cross-bar." />
<figcaption><em>Figure 10. Logical overview of NVIDIA NVLink 4 NVSwitch</em></figcaption>
</figure>

</div>

The fourth-generation NVIDIA NVLink technology enables GPU threads to address up to 150 TB of memory provided by all superchips in the NVLink network using normal memory operations, atomic operations, and bulk transfers. Communication libraries like <a href="https://developer.nvidia.com/networking/hpc-x" data-wpel-link="internal" target="_self" rel="follow">MPI</a>, <a href="https://developer.nvidia.com/nccl" data-wpel-link="internal" target="_self" rel="follow">NCCL</a>, or <a href="https://developer.nvidia.com/nvshmem" data-wpel-link="internal" target="_self" rel="follow">NVSHMEM</a> transparently leverage the NVLink Switch System when available.

### Extended GPU memory<a href="#extended_gpu_memory" class="heading-anchor-link" aria-label="Scroll to Extended GPU memory section"><em></em></a>

The NVIDIA Grace Hopper Superchip is designed to accelerate applications with exceptionally large memory footprints, larger than the capacity of the HBM3 and LPDDR5X memory of a single superchip. For more information, see the NVIDIA Grace Hopper Accelerated Applications section.

The Extended GPU Memory (EGM) feature over the high-bandwidth NVLink-C2C enables GPUs to access all the system memory efficiently. EGM provides up to 150 TBs of system memory in a multi-node NVSwitch-connected system. With EGM, physical memory can be allocated to be accessible from any GPU thread in the multi-node system. All GPUs can access EGM at the minimum of GPU-GPU NVLink or NVLink-C2C speed.

Memory accesses within a Grace Hopper Superchip configuration go through the local high-bandwidth NVLink-C2C at 900 GB/s total. Remote memory accesses are performed through GPU NVLink and, depending on the memory being accessed, also NVLink-C2C (Figure 11). With EGM, GPU threads can now access all memory resources available over the NVSwitch fabric, both LPDDR5X and HBM3, at 450 GB/s.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip.png" class="wp-image-57237" style="width:1000px;height:281px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-300x84.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-625x176.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-179x50.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-768x216.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-1536x432.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-500x141.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-160x45.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-362x102.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-391x110.png 391w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-1024x288.png 1024w" sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="562" alt="Diagram shows the access paths taken by memory accesses from a Hopper GPU to its local LPPDR5X (path via C2C), to a peer GPU HBM3 (path via NVLink), and to a peer CPU LPDDR5X (path via NVLink to peer GPU, then C2C to LPDDR5X)." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%20562%22%3E%3C/svg%3E" class="lazyload wp-image-57237" style="width:1000px;height:281px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip.png 1999w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-300x84.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-625x176.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-179x50.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-768x216.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-1536x432.png 1536w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-500x141.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-160x45.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-362x102.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-391x110.png 391w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/memory-access-grace-hopper-superchip-1024x288.png 1024w" data-sizes="(max-width: 1999px) 100vw, 1999px" width="1999" height="562" alt="Diagram shows the access paths taken by memory accesses from a Hopper GPU to its local LPPDR5X (path via C2C), to a peer GPU HBM3 (path via NVLink), and to a peer CPU LPDDR5X (path via NVLink to peer GPU, then C2C to LPDDR5X)." />
<figcaption><em>Figure 11. Memory accesses across NVLink-connected Grace Hopper Superchips</em></figcaption>
</figure>

</div>

## NVIDIA HGX Grace Hopper<a href="#nvidia_hgx_grace_hopper" class="heading-anchor-link" aria-label="Scroll to NVIDIA HGX Grace Hopper section"><em></em></a>

NVIDIA HGX Grace Hopper has a single Grace Hopper Superchip per node, paired with BlueField-3 NICs or OEM-Defined I/O and optionally an NVLink Switch System. It can be air– or liquid-cooled and has up to 1,000W TDP.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband.jpg" class="wp-image-57238" style="width:276px;height:259px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband.jpg 551w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-300x281.jpg 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-123x115.jpg 123w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-320x300.jpg 320w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-96x90.jpg 96w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-362x340.jpg 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-117x110.jpg 117w" sizes="(max-width: 551px) 100vw, 551px" width="551" height="517" alt="3D Render of an NVIDIA HGX Grace Hopper with InfiniBand system." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20551%20517%22%3E%3C/svg%3E" class="lazyload wp-image-57238" style="width:276px;height:259px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband.jpg 551w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-300x281.jpg 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-123x115.jpg 123w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-320x300.jpg 320w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-96x90.jpg 96w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-362x340.jpg 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-117x110.jpg 117w" data-sizes="(max-width: 551px) 100vw, 551px" width="551" height="517" alt="3D Render of an NVIDIA HGX Grace Hopper with InfiniBand system." />
<figcaption><em>Figure 12. NVIDIA HGX Grace Hopper with InfiniBand</em></figcaption>
</figure>

</div>

## NVIDIA HGX Grace Hopper with InfiniBand<a href="#nvidia_hgx_grace_hopper_with_infiniband" class="heading-anchor-link" aria-label="Scroll to NVIDIA HGX Grace Hopper with InfiniBand section"><em></em></a>

NVIDIA HGX Grace Hopper ** **with Infiniband (Figure 13) is ideal for the scale-out of traditional machine learning (ML) and HPC workloads that are not bottlenecked by network communication overheads of InfiniBand, which is one of the fastest interconnects available.

Each node contains one Grace Hopper Superchip and one or more PCIe devices like NVMe solid-state drives and BlueField-3 DPUs, NVIDIA ConnectX-7 NICs, or OEM-defined I/O. With 16x PCIe Gen 5 lanes, an NDR400 InfiniBand NIC provides up to 100 GB/s of total bandwidth across the superchips. Combined with NVIDIA BlueField-3 DPUs, this platform is easy to manage and deploy and uses a traditional HPC and AI cluster networking architecture.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc.png" class="wp-image-57239" style="width:1055px;height:465px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc.png 1406w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-300x132.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-625x276.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-179x79.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-768x339.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-500x220.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-160x71.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-362x160.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-249x110.png 249w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-1024x452.png 1024w" sizes="(max-width: 1406px) 100vw, 1406px" width="1406" height="620" alt="Diagram shows an NVIDIA HGX Grace Hopper Superchip with Infiniband networking system. There is hardware coherency within each Grace Hopper Superchip. Each Superchip is connected with a BlueField 3 DPU through PCIe, which are then connected at 100 GB/s total bandwidth with NVIDIA Quantum-2 InfiniBand NDR400 Switches." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201406%20620%22%3E%3C/svg%3E" class="lazyload wp-image-57239" style="width:1055px;height:465px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc.png 1406w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-300x132.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-625x276.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-179x79.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-768x339.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-500x220.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-160x71.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-362x160.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-249x110.png 249w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/hgx-grace-hopper-infiniband-scale-out-ml-hpc-1024x452.png 1024w" data-sizes="(max-width: 1406px) 100vw, 1406px" width="1406" height="620" alt="Diagram shows an NVIDIA HGX Grace Hopper Superchip with Infiniband networking system. There is hardware coherency within each Grace Hopper Superchip. Each Superchip is connected with a BlueField 3 DPU through PCIe, which are then connected at 100 GB/s total bandwidth with NVIDIA Quantum-2 InfiniBand NDR400 Switches." />
<figcaption><em>Figure 13. NVIDIA HGX Grace Hopper with InfiniBand for scale-out ML and HPC workloads</em></figcaption>
</figure>

</div>

## NVIDIA HGX Grace Hopper with NVLink Switch<a href="#nvidia_hgx_grace_hopper_with_nvlink_switch" class="heading-anchor-link" aria-label="Scroll to NVIDIA HGX Grace Hopper with NVLink Switch section"><em></em></a>

NVIDIA HGX Grace Hopper with NVLink Switch is ideal for strong scaling giant machine learning and HPC workloads. It enables all GPU threads in the NVLink-connected domain to address up to 150 TB of memory at up to 900 GB/s total bandwidth per superchip in a 256-GPU NVLink-connected system. The a simple programming model uses pointer load, store, and atomic operations. Its 450 GB/s all-reduce bandwidth and up to 115.2 TB/s bisection bandwidth make this platform ideal for strong-scaling the world’s largest and most challenging AI training and HPC workloads.

NVLink-connected domains are networked with NVIDIA InfiniBand networking, for example, NVIDIA ConnectX-7 NICs or NVIDIA BlueField-3 data processing units (DPUs) paired with NVIDIA Quantum 2 NDR switches or OEM-defined I/O solutions.

<div class="wp-block-image">

<figure class="aligncenter size-full is-resized">
<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system.png" class="wp-image-57240" style="width:1058px;height:529px" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system.png 1410w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-300x150.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-625x313.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-179x90.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-768x384.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-500x250.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-160x80.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-362x181.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-220x110.png 220w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-1024x512.png 1024w" sizes="(max-width: 1410px) 100vw, 1410px" width="1410" height="705" alt="Diagram shows an NVIDIA HGX Grace Hopper with NVLink Switch System . There is hardware coherency within each Grace Hopper Superchip. Each Grace Hopper Superchip within a cluster of up to 256 Grace Hopper Superchips is connected with each other via the NVLink Switch System. Each Superchip is also connected with a BlueField 3 DPU through PCIe, which are then connected at 100 GB/s total bandwidth with NVIDIA Quantum-2 InfiniBand NDR400 Switches." />
<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201410%20705%22%3E%3C/svg%3E" class="lazyload wp-image-57240" style="width:1058px;height:529px" decoding="async" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system.png 1410w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-300x150.png 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-625x313.png 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-179x90.png 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-768x384.png 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-500x250.png 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-160x80.png 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-362x181.png 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-220x110.png 220w, https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/grace-hopper-nvlink-switch-system-1024x512.png 1024w" data-sizes="(max-width: 1410px) 100vw, 1410px" width="1410" height="705" alt="Diagram shows an NVIDIA HGX Grace Hopper with NVLink Switch System . There is hardware coherency within each Grace Hopper Superchip. Each Grace Hopper Superchip within a cluster of up to 256 Grace Hopper Superchips is connected with each other via the NVLink Switch System. Each Superchip is also connected with a BlueField 3 DPU through PCIe, which are then connected at 100 GB/s total bandwidth with NVIDIA Quantum-2 InfiniBand NDR400 Switches." />
<figcaption><em>Figure 14. NVIDIA HGX Grace Hopper with NVLink Switch System for strong-scaling giant ML and HPC workloads</em></figcaption>
</figure>

</div>

## Delivering performance breakthroughs<a href="#delivering_performance_breakthroughs" class="heading-anchor-link" aria-label="Scroll to Delivering performance breakthroughs section"><em></em></a>

The <a href="https://resources.nvidia.com/en-us-grace-cpu/nvidia-grace-hopper" data-wpel-link="internal" target="_self" rel="follow">NVIDIA Grace Hopper Superchip Architecture</a> whitepaper expands on the details covered in this post. It walks you through how Grace Hopper delivers the performance breakthroughs shown on Figure 1 over what is currently the most powerful PCIe-based accelerated platforms powered by NVIDIA Hopper H100 PCIe GPUs.

Do you have any applications that would be perfect for the NVIDIA Grace Hopper Superchip? Let us know in the comments\!

### Acknowledgments<a href="#acknowledgments" class="heading-anchor-link" aria-label="Scroll to Acknowledgments section"><em></em></a>

*We would like to thank Jack Choquette, Ronny Krashinsky, John Hubbard, Mark Hummel, Greg Palmer, Ryan Wells, Alex Ishii, Jonah Alben, and* *the many NVIDIA architects and engineers who contributed to this post*.

</div>

<div class="card--post-attributes-secondary">

<div class="post--comments-count secondary--attribute">

[ Discuss (12)](#entry-content-comments)

</div>

<div class="post--rate secondary--attribute">

<div class="wpulike wpulike-heart">

<div class="wp_ulike_general_class wp_ulike_is_not_liked">

<span class="count-box wp_ulike_counter_up" ulike-counter-value="+52"></span>

</div>

</div>

Like

</div>

</div>

<div class="card--post-attributes-secondary tags">

<div class="caption">

## Tags

</div>

<div class="content-s post-tags--list mt-0">

<a href="https://developer.nvidia.com/blog/category/data-center-cloud/" data-wpel-link="internal" target="_self" rel="follow">Data Center / Cloud</a> \| <a href="https://developer.nvidia.com/blog/category/data-science/" data-wpel-link="internal" target="_self" rel="follow">Data Science</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?industry=HPC+%2F+Scientific+Computing" data-wpel-link="internal" target="_self" rel="follow">HPC / Scientific Computing</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?products=CUDA" data-wpel-link="internal" target="_self" rel="follow">CUDA</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?products=Grace+CPU" data-wpel-link="internal" target="_self" rel="follow">Grace CPU</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?learning_levels=Intermediate+Technical" data-wpel-link="internal" target="_self" rel="follow">Intermediate Technical</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?content_types=Tutorial" data-wpel-link="internal" target="_self" rel="follow">Tutorial</a> \| <a href="https://developer.nvidia.com/blog/tag/featured/" data-wpel-link="internal" target="_self" rel="follow">featured</a>

</div>

</div>

<div class="post-authors-list">

<div class="entry-content-author">

<div class="caption">

## About the Authors

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/image2-e1660679098753-131x131.jpg" class="avatar avatar-131 photo" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/image2-e1660679098753-262x262.jpg 2x" decoding="async" width="131" height="131" alt="Jonathon Evans" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/image2-e1660679098753-131x131.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/image2-e1660679098753-262x262.jpg 2x" decoding="async" width="131" height="131" alt="Jonathon Evans" />

</div>

<div class="author-media-body media-body">

**About Jonathon Evans**  
Jonathon Evans is an NVIDIA Distinguished Engineer and architecture lead for the NVIDIA Grace CPU. Jonathon joined NVIDIA in 2007 as a member of the GPU Architecture team. His prior work on GPU includes leading the GPU’s context management and scheduling HW team, and contributions to Async Compute, Unified Memory, Multi Instance GPU, and WDDM HW Scheduling.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/jevans/" rel="author follow" data-wpel-link="internal" target="_self">View all posts by Jonathon Evans<img src="data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Michael-Andersch-131x131.jpg" class="avatar avatar-131 photo" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Michael-Andersch.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Michael-Andersch-131x131.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Michael-Andersch.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Michael Andersch**  
Michael Andersch is a principal GPU architect and senior architecture manager at NVIDIA. He started his career in the Compute Architecture team, where he focused on advancing the GPU's capabilities for the world's diverse set of CUDA workloads. In recent years, Michael has driven both hardware and software improvements specifically to increase the performance of deep neural network training, and his team is now involved wherever training performance is critical; from tuning the latest neural networks in the deep learning community to designing next-generation GPUs.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/mandersch/" rel="author follow" data-wpel-link="internal" target="_self">View all posts by Michael Andersch<img src="data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/vikram-sethi-131x131.jpg" class="avatar avatar-131 photo" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/vikram-sethi.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/vikram-sethi-131x131.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/vikram-sethi.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Vikram Sethi**  
Vikram Sethi is an NVIDIA Distinguished Engineer and software and system architect with over 20 years of experience working on hypervisors, kernels, device drivers, and firmware. He is the lead system software architect for NVIDIA Grace. Vikram represents NVIDIA software in industry consortiums, including Compute Express Link (CXL), PCIe, and UCIe.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/vsethi/" rel="author follow" data-wpel-link="internal" target="_self">View all posts by Vikram Sethi<img src="data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Gonzalo-Brito-1.jpg" class="avatar avatar-131 photo" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Gonzalo-Brito-1.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Gonzalo-Brito-1.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/03/Gonzalo-Brito-1.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Gonzalo Brito**  
Gonzalo Brito is a GPU architect at NVIDIA, focusing on the Memory Consistency and Programming Model. He is also an ISO C++ committee member, contributing to the Concurrency and Parallelism Study Group. With a background in HPC performance modeling and optimization, he is passionate about simplifying heterogeneous programming models and teaching parallel programming. Before joining NVIDIA, he researched HPC methods for multi-physics problems in particle-laden flows at the Institute of Aerodynamics of RWTH Aachen.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/gonzalob/" rel="author follow" data-wpel-link="internal" target="_self">View all posts by Gonzalo Brito<img src="data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2021/02/vishal-131x131.png" class="avatar avatar-131 photo" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2021/02/vishal-262x262.png 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2021/02/vishal-131x131.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2021/02/vishal-262x262.png 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Vishal Mehta**  
Vishal works as a senior developer technology engineer at NVIDIA, with focus on performance optimization for GPU applications. He has been working in the field of GPU computing for over 10 years. He is keen on teaching CUDA and GPU computing to users and drives the content for the CUDA programming guide. His day-to-day activities involve collaborations with domain scientists and industry experts to improve their workloads on GPUs.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/vishalm/" rel="author follow" data-wpel-link="internal" target="_self">View all posts by Vishal Mehta<img src="data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

</div>

</div>

<div id="entry-content-comments" class="entry-content-comments">

<div id="pf-disqus-thread" class="container">

<div id="respond" class="row">

<div class="col-md-12 related-posts-comments mb-0">

## Comments

</div>

</div>

<div class="row">

<div class="col-lg-12 col-md-12 col-sm-12 col-xs-12">

<div id="wpdc-comments" class="wpdc-comments-loading" post-id="57192">

</div>

</div>

</div>

</div>

</div>

<div id="main-content-end">

</div>

</div>

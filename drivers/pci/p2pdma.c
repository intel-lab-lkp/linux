// SPDX-License-Identifier: GPL-2.0
/*
 * PCI Peer 2 Peer DMA support.
 *
 * Copyright (c) 2016-2018, Logan Gunthorpe
 * Copyright (c) 2016-2017, Microsemi Corporation
 * Copyright (c) 2017, Christoph Hellwig
 * Copyright (c) 2018, Eideticom Inc.
 */

#define pr_fmt(fmt) "pci-p2pdma: " fmt
#include <linux/ctype.h>
#include <linux/dma-map-ops.h>
#include <linux/pci-p2pdma.h>
#include <linux/module.h>
#include <linux/slab.h>
#include <linux/genalloc.h>
#include <linux/memremap.h>
#include <linux/percpu-refcount.h>
#include <linux/random.h>
#include <linux/seq_buf.h>
#include <linux/xarray.h>

#include "pci.h"

struct pci_p2pdma {
	struct gen_pool *pool;
	bool p2pmem_published;
	bool ats_per_mapping;
	struct xarray map_types;
	struct p2pdma_provider mem[PCI_STD_NUM_BARS];
};

struct pci_p2pdma_pagemap {
	struct dev_pagemap pgmap;
	struct p2pdma_provider *mem;
};

static struct pci_p2pdma_pagemap *to_p2p_pgmap(struct dev_pagemap *pgmap)
{
	return container_of(pgmap, struct pci_p2pdma_pagemap, pgmap);
}

static ssize_t size_show(struct device *dev, struct device_attribute *attr,
			 char *buf)
{
	struct pci_dev *pdev = to_pci_dev(dev);
	struct pci_p2pdma *p2pdma;
	size_t size = 0;

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);
	if (p2pdma && p2pdma->pool)
		size = gen_pool_size(p2pdma->pool);
	rcu_read_unlock();

	return sysfs_emit(buf, "%zd\n", size);
}
static DEVICE_ATTR_RO(size);

static ssize_t available_show(struct device *dev, struct device_attribute *attr,
			      char *buf)
{
	struct pci_dev *pdev = to_pci_dev(dev);
	struct pci_p2pdma *p2pdma;
	size_t avail = 0;

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);
	if (p2pdma && p2pdma->pool)
		avail = gen_pool_avail(p2pdma->pool);
	rcu_read_unlock();

	return sysfs_emit(buf, "%zd\n", avail);
}
static DEVICE_ATTR_RO(available);

static ssize_t published_show(struct device *dev, struct device_attribute *attr,
			      char *buf)
{
	struct pci_dev *pdev = to_pci_dev(dev);
	struct pci_p2pdma *p2pdma;
	bool published = false;

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);
	if (p2pdma)
		published = p2pdma->p2pmem_published;
	rcu_read_unlock();

	return sysfs_emit(buf, "%d\n", published);
}
static DEVICE_ATTR_RO(published);

static int p2pmem_alloc_mmap(struct file *filp, struct kobject *kobj,
		const struct bin_attribute *attr, struct vm_area_struct *vma)
{
	struct pci_dev *pdev = to_pci_dev(kobj_to_dev(kobj));
	size_t len = vma->vm_end - vma->vm_start;
	struct pci_p2pdma *p2pdma;
	struct percpu_ref *ref;
	unsigned long vaddr;
	void *kaddr;
	int ret;

	/* prevent private mappings from being established */
	if ((vma->vm_flags & VM_MAYSHARE) != VM_MAYSHARE) {
		pci_info_ratelimited(pdev,
				     "%s: fail, attempted private mapping\n",
				     current->comm);
		return -EINVAL;
	}

	if (vma->vm_pgoff) {
		pci_info_ratelimited(pdev,
				     "%s: fail, attempted mapping with non-zero offset\n",
				     current->comm);
		return -EINVAL;
	}

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);
	if (!p2pdma) {
		ret = -ENODEV;
		goto out;
	}

	kaddr = (void *)gen_pool_alloc_owner(p2pdma->pool, len, (void **)&ref);
	if (!kaddr) {
		ret = -ENOMEM;
		goto out;
	}

	/*
	 * vm_insert_page() can sleep, so a reference is taken to mapping
	 * such that rcu_read_unlock() can be done before inserting the
	 * pages
	 */
	if (unlikely(!percpu_ref_tryget_live_rcu(ref))) {
		ret = -ENODEV;
		goto out_free_mem;
	}
	rcu_read_unlock();

	for (vaddr = vma->vm_start; vaddr < vma->vm_end; vaddr += PAGE_SIZE) {
		struct page *page = virt_to_page(kaddr);

		/*
		 * Initialise the refcount for the freshly allocated page. As
		 * we have just allocated the page no one else should be
		 * using it.
		 */
		VM_WARN_ON_ONCE_PAGE(page_ref_count(page), page);
		set_page_count(page, 1);
		ret = vm_insert_page(vma, vaddr, page);
		if (ret) {
			gen_pool_free(p2pdma->pool, (uintptr_t)kaddr, len);

			/*
			 * Reset the page count. We don't use put_page()
			 * because we don't want to trigger the
			 * p2pdma_folio_free() path.
			 */
			set_page_count(page, 0);
			percpu_ref_put(ref);
			return ret;
		}
		percpu_ref_get(ref);
		put_page(page);
		kaddr += PAGE_SIZE;
		len -= PAGE_SIZE;
	}

	percpu_ref_put(ref);

	return 0;
out_free_mem:
	gen_pool_free(p2pdma->pool, (uintptr_t)kaddr, len);
out:
	rcu_read_unlock();
	return ret;
}

static const struct bin_attribute p2pmem_alloc_attr = {
	.attr = { .name = "allocate", .mode = 0660 },
	.mmap = p2pmem_alloc_mmap,
	/*
	 * Some places where we want to call mmap (ie. python) will check
	 * that the file size is greater than the mmap size before allowing
	 * the mmap to continue. To work around this, just set the size
	 * to be very large.
	 */
	.size = SZ_1T,
};

static struct attribute *p2pmem_attrs[] = {
	&dev_attr_size.attr,
	&dev_attr_available.attr,
	&dev_attr_published.attr,
	NULL,
};

static const struct bin_attribute *const p2pmem_bin_attrs[] = {
	&p2pmem_alloc_attr,
	NULL,
};

static const struct attribute_group p2pmem_group = {
	.attrs = p2pmem_attrs,
	.bin_attrs = p2pmem_bin_attrs,
	.name = "p2pmem",
};

static void p2pdma_folio_free(struct folio *folio)
{
	struct page *page = &folio->page;
	struct pci_p2pdma_pagemap *pgmap = to_p2p_pgmap(page_pgmap(page));
	/* safe to dereference while a reference is held to the percpu ref */
	struct pci_p2pdma *p2pdma = rcu_dereference_protected(
		to_pci_dev(pgmap->mem->owner)->p2pdma, 1);
	struct percpu_ref *ref;

	gen_pool_free_owner(p2pdma->pool, (uintptr_t)page_to_virt(page),
			    PAGE_SIZE, (void **)&ref);
	percpu_ref_put(ref);
}

static const struct dev_pagemap_ops p2pdma_pgmap_ops = {
	.folio_free = p2pdma_folio_free,
};

static void pci_p2pdma_release(void *data)
{
	struct pci_dev *pdev = data;
	struct pci_p2pdma *p2pdma;

	p2pdma = rcu_dereference_protected(pdev->p2pdma, 1);
	if (!p2pdma)
		return;

	/* Flush and disable pci_alloc_p2p_mem() */
	RCU_INIT_POINTER(pdev->p2pdma, NULL);
	synchronize_rcu();
	xa_destroy(&p2pdma->map_types);

	if (!p2pdma->pool)
		return;

	gen_pool_destroy(p2pdma->pool);
	sysfs_remove_group(&pdev->dev.kobj, &p2pmem_group);
}

/**
 * pcim_p2pdma_init - Initialise peer-to-peer DMA providers
 * @pdev: The PCI device to enable P2PDMA for
 *
 * This function initializes the peer-to-peer DMA infrastructure
 * for a PCI device. It allocates and sets up the necessary data
 * structures to support P2PDMA operations, including mapping type
 * tracking.
 */
int pcim_p2pdma_init(struct pci_dev *pdev)
{
	struct pci_p2pdma *p2p;
	int i, ret;

	if (pdev->non_mappable_bars)
		return -EOPNOTSUPP;

	p2p = rcu_dereference_protected(pdev->p2pdma, 1);
	if (p2p)
		return 0;

	p2p = devm_kzalloc(&pdev->dev, sizeof(*p2p), GFP_KERNEL);
	if (!p2p)
		return -ENOMEM;

	xa_init(&p2p->map_types);
	/*
	 * Iterate over all standard PCI BARs and record only those that
	 * correspond to MMIO regions. Skip non-memory resources (e.g. I/O
	 * port BARs) since they cannot be used for peer-to-peer (P2P)
	 * transactions.
	 */
	for (i = 0; i < PCI_STD_NUM_BARS; i++) {
		if (!(pci_resource_flags(pdev, i) & IORESOURCE_MEM))
			continue;

		p2p->mem[i].owner = &pdev->dev;
		p2p->mem[i].bus_offset =
			pci_bus_address(pdev, i) - pci_resource_start(pdev, i);
	}

	ret = devm_add_action_or_reset(&pdev->dev, pci_p2pdma_release, pdev);
	if (ret)
		goto out_p2p;

	rcu_assign_pointer(pdev->p2pdma, p2p);
	return 0;

out_p2p:
	devm_kfree(&pdev->dev, p2p);
	return ret;
}
EXPORT_SYMBOL_GPL(pcim_p2pdma_init);

/**
 * pcim_p2pdma_provider - Get peer-to-peer DMA provider
 * @pdev: The PCI device to enable P2PDMA for
 * @bar: BAR index to get provider
 *
 * This function gets peer-to-peer DMA provider for a PCI device. The lifetime
 * of the provider (and of course the MMIO) is bound to the lifetime of the
 * driver. A driver calling this function must ensure that all references to the
 * provider, and any DMA mappings created for any MMIO, are all cleaned up
 * before the driver remove() completes.
 *
 * Since P2P is almost always shared with a second driver this means some system
 * to notify, invalidate and revoke the MMIO's DMA must be in place to use this
 * function. For example a revoke can be built using DMABUF.
 */
struct p2pdma_provider *pcim_p2pdma_provider(struct pci_dev *pdev, int bar)
{
	struct pci_p2pdma *p2p;

	if (!(pci_resource_flags(pdev, bar) & IORESOURCE_MEM) ||
	    pdev->non_mappable_bars)
		return NULL;

	p2p = rcu_dereference_protected(pdev->p2pdma, 1);
	if (WARN_ON(!p2p))
		/* Someone forgot to call to pcim_p2pdma_init() before */
		return NULL;

	return &p2p->mem[bar];
}
EXPORT_SYMBOL_GPL(pcim_p2pdma_provider);

static int pci_p2pdma_setup_pool(struct pci_dev *pdev)
{
	struct pci_p2pdma *p2pdma;
	int ret;

	p2pdma = rcu_dereference_protected(pdev->p2pdma, 1);
	if (p2pdma->pool)
		/* We already setup pools, do nothing, */
		return 0;

	p2pdma->pool = gen_pool_create(PAGE_SHIFT, dev_to_node(&pdev->dev));
	if (!p2pdma->pool)
		return -ENOMEM;

	ret = sysfs_create_group(&pdev->dev.kobj, &p2pmem_group);
	if (ret)
		goto out_pool_destroy;

	return 0;

out_pool_destroy:
	gen_pool_destroy(p2pdma->pool);
	p2pdma->pool = NULL;
	return ret;
}

static void pci_p2pdma_unmap_mappings(void *data)
{
	struct pci_p2pdma_pagemap *p2p_pgmap = data;

	/*
	 * Removing the alloc attribute from sysfs will call
	 * unmap_mapping_range() on the inode, teardown any existing userspace
	 * mappings and prevent new ones from being created.
	 */
	sysfs_remove_file_from_group(&p2p_pgmap->mem->owner->kobj,
				     &p2pmem_alloc_attr.attr,
				     p2pmem_group.name);
}

/**
 * pci_p2pdma_add_resource - add memory for use as p2p memory
 * @pdev: the device to add the memory to
 * @bar: PCI BAR to add
 * @size: size of the memory to add, may be zero to use the whole BAR
 * @offset: offset into the PCI BAR
 *
 * The memory will be given ZONE_DEVICE struct pages so that it may
 * be used with any DMA request.
 */
int pci_p2pdma_add_resource(struct pci_dev *pdev, int bar, size_t size,
			    u64 offset)
{
	struct pci_p2pdma_pagemap *p2p_pgmap;
	struct p2pdma_provider *mem;
	struct dev_pagemap *pgmap;
	struct pci_p2pdma *p2pdma;
	void *addr;
	int error;

	if (!(pci_resource_flags(pdev, bar) & IORESOURCE_MEM))
		return -EINVAL;

	if (offset >= pci_resource_len(pdev, bar))
		return -EINVAL;

	if (!size)
		size = pci_resource_len(pdev, bar) - offset;

	if (size + offset > pci_resource_len(pdev, bar))
		return -EINVAL;

	error = pcim_p2pdma_init(pdev);
	if (error)
		return error;

	error = pci_p2pdma_setup_pool(pdev);
	if (error)
		return error;

	mem = pcim_p2pdma_provider(pdev, bar);
	/*
	 * We checked validity of BAR prior to call
	 * to pcim_p2pdma_provider. It should never return NULL.
	 */
	if (WARN_ON(!mem))
		return -EINVAL;

	p2p_pgmap = devm_kzalloc(&pdev->dev, sizeof(*p2p_pgmap), GFP_KERNEL);
	if (!p2p_pgmap)
		return -ENOMEM;

	pgmap = &p2p_pgmap->pgmap;
	pgmap->range.start = pci_resource_start(pdev, bar) + offset;
	pgmap->range.end = pgmap->range.start + size - 1;
	pgmap->nr_range = 1;
	pgmap->type = MEMORY_DEVICE_PCI_P2PDMA;
	pgmap->ops = &p2pdma_pgmap_ops;
	p2p_pgmap->mem = mem;

	addr = devm_memremap_pages(&pdev->dev, pgmap);
	if (IS_ERR(addr)) {
		error = PTR_ERR(addr);
		goto pgmap_free;
	}

	error = devm_add_action(&pdev->dev, pci_p2pdma_unmap_mappings,
				p2p_pgmap);
	if (error)
		goto pages_free;

	p2pdma = rcu_dereference_protected(pdev->p2pdma, 1);
	error = gen_pool_add_owner(p2pdma->pool, (unsigned long)addr,
			pci_bus_address(pdev, bar) + offset,
			range_len(&pgmap->range), dev_to_node(&pdev->dev),
			&pgmap->ref);
	if (error)
		goto mappings_remove;

	pci_info(pdev, "added peer-to-peer DMA memory %#llx-%#llx\n",
		 pgmap->range.start, pgmap->range.end);

	return 0;

mappings_remove:
	devm_remove_action(&pdev->dev, pci_p2pdma_unmap_mappings, p2p_pgmap);
pages_free:
	devm_memunmap_pages(&pdev->dev, pgmap);
pgmap_free:
	devm_kfree(&pdev->dev, p2p_pgmap);
	return error;
}
EXPORT_SYMBOL_GPL(pci_p2pdma_add_resource);

/*
 * Note this function returns the parent PCI device with a
 * reference taken. It is the caller's responsibility to drop
 * the reference.
 */
static struct pci_dev *find_parent_pci_dev(struct device *dev)
{
	struct device *parent;

	dev = get_device(dev);

	while (dev) {
		if (dev_is_pci(dev))
			return to_pci_dev(dev);

		parent = get_device(dev->parent);
		put_device(dev);
		dev = parent;
	}

	return NULL;
}

/*
 * Decide how a peer-to-peer Request at an ACS-capable ingress port routes,
 * from that port's ACS Control register and the Request's Address Type.
 *
 * Linux does not read the Egress Control Vector, so Egress Control is treated
 * conservatively as a redirect. Per PCIe r7.0 Table 6-11 the outcomes it
 * selects are a direct route and an ACS Violation, and neither one lets peer
 * bus addressing be assumed.
 */
VISIBLE_IF_KUNIT enum pci_acs_p2pdma_state
pci_acs_p2pdma_request(u16 ctrl, unsigned int tlp_flags)
{
	if (tlp_flags & PCI_P2PDMA_TLP_TRANSLATED) {
		/*
		 * PCIe r7.0 sec 6.12.1.1: Translation Blocking makes every
		 * Upstream Memory Request whose Address Type is not
		 * Untranslated an ACS Violation, taking precedence over the
		 * P2P controls. Sec 7.7.12.5: Direct Translated P2P "is
		 * ignored if ACS Translation Blocking Enable is 1b".
		 */
		if (ctrl & PCI_ACS_TB)
			return PCI_ACS_P2PDMA_BLOCKED;

		/*
		 * PCIe r7.0 sec 6.12.3: ACS Direct Translated P2P routes a
		 * Request carrying a Translated address to the peer "without
		 * redirection, regardless of ACS P2P Request Redirect and ACS
		 * P2P Egress Control settings".
		 */
		if (ctrl & PCI_ACS_DT)
			return PCI_ACS_P2PDMA_DIRECT;
	}

	return ctrl & (PCI_ACS_RR | PCI_ACS_EC) ?
		PCI_ACS_P2PDMA_REDIRECT : PCI_ACS_P2PDMA_DIRECT;
}
EXPORT_SYMBOL_IF_KUNIT(pci_acs_p2pdma_request);

/*
 * Decide how a peer-to-peer Completion at an ACS-capable ingress port routes.
 * PCIe r7.0 sec 6.12.1.1: no ACS control other than P2P Completion Redirect
 * affects a Completion, and that one leaves Completions carrying the Relaxed
 * Ordering attribute alone.
 */
VISIBLE_IF_KUNIT enum pci_acs_p2pdma_state
pci_acs_p2pdma_completion(u16 ctrl, unsigned int tlp_flags)
{
	if (tlp_flags & PCI_P2PDMA_TLP_RELAXED_CPL)
		return PCI_ACS_P2PDMA_DIRECT;

	return ctrl & PCI_ACS_CR ? PCI_ACS_P2PDMA_REDIRECT :
				   PCI_ACS_P2PDMA_DIRECT;
}
EXPORT_SYMBOL_IF_KUNIT(pci_acs_p2pdma_completion);

static const char *pci_acs_p2pdma_state_name(enum pci_acs_p2pdma_state state)
{
	switch (state) {
	case PCI_ACS_P2PDMA_DIRECT:
		return "direct";
	case PCI_ACS_P2PDMA_REDIRECT:
		return "redirect";
	case PCI_ACS_P2PDMA_BLOCKED:
		return "blocked";
	case PCI_ACS_P2PDMA_NOT_SUPPORTED:
		return "not-supported";
	}

	return "invalid";
}

static const char *pci_p2pdma_map_type_name(enum pci_p2pdma_map_type type)
{
	switch (type) {
	case PCI_P2PDMA_MAP_UNKNOWN:
		return "unknown";
	case PCI_P2PDMA_MAP_NONE:
		return "none";
	case PCI_P2PDMA_MAP_NOT_SUPPORTED:
		return "not-supported";
	case PCI_P2PDMA_MAP_BUS_ADDR:
		return "bus-address";
	case PCI_P2PDMA_MAP_THRU_HOST_BRIDGE:
		return "through-host-bridge";
	}

	return "invalid";
}

/*
 * Read @pdev's ACS Control register. A device without an ACS capability has
 * no peer-to-peer controls at all, which routes the same as having them all
 * clear. Returns false when the register is present but cannot be read; @ctrl
 * is then meaningless.
 */
static bool pci_acs_p2pdma_ctrl(struct pci_dev *pdev, const char *what,
				u16 *ctrl, bool verbose)
{
	int pos, ret;

	pos = pdev->acs_cap;
	if (!pos) {
		if (verbose)
			pci_dbg(pdev,
				"P2PDMA ACS: %s has no ACS capability\n", what);
		*ctrl = 0;
		return true;
	}

	ret = pci_read_config_word(pdev, pos + PCI_ACS_CTRL, ctrl);
	if (ret) {
		if (verbose)
			pci_dbg(pdev,
				"P2PDMA ACS: %s ACS Control read failed at %#x: %#x\n",
				 what, pos + PCI_ACS_CTRL, ret);
		return false;
	}

	if (verbose) {
		pci_dbg(pdev,
			 "P2PDMA ACS: %s cap=%#x caps=%#06x ctrl=%#06x\n",
			 what, pos, pdev->acs_capabilities, *ctrl);
		pci_dbg(pdev,
			 "P2PDMA ACS: control bits SV=%u TB=%u RR=%u CR=%u UF=%u EC=%u DT=%u\n",
			 !!(*ctrl & PCI_ACS_SV), !!(*ctrl & PCI_ACS_TB),
			 !!(*ctrl & PCI_ACS_RR), !!(*ctrl & PCI_ACS_CR),
			 !!(*ctrl & PCI_ACS_UF), !!(*ctrl & PCI_ACS_EC),
			 !!(*ctrl & PCI_ACS_DT));
	}

	return true;
}

static void pci_p2pdma_log_path(const char *name, struct pci_dev *start,
				struct pci_dev *common)
{
	struct pci_dev *pdev, *upstream;
	int hop = 0, ret, type;
	u16 ctrl;

	for (pdev = start; pdev; pdev = upstream, hop++) {
		upstream = pci_upstream_bridge(pdev);
		type = pci_is_pcie(pdev) ? pci_pcie_type(pdev) : -1;
		pci_dbg(pdev,
			 "P2PDMA ACS: %s path hop=%d common=%u pcie=%u type=%d class=%#08x vendor=%04x device=%04x upstream=%s\n",
			 name, hop, pdev == common, pci_is_pcie(pdev), type,
			 pdev->class, pdev->vendor, pdev->device,
			 upstream ? pci_name(upstream) : "<none>");

		if (pdev->subordinate)
			pci_dbg(pdev,
				"P2PDMA ACS: bridge bus range=%02llx-%02llx\n",
				 (unsigned long long)pdev->subordinate->busn_res.start,
				 (unsigned long long)pdev->subordinate->busn_res.end);

		if (!pdev->acs_cap) {
			pci_dbg(pdev, "P2PDMA ACS: ACS capability absent\n");
			continue;
		}

		ret = pci_read_config_word(pdev, pdev->acs_cap + PCI_ACS_CTRL,
					   &ctrl);
		if (ret) {
			pci_dbg(pdev,
				"P2PDMA ACS: ACS cap=%#x caps=%#06x Control read failed: %#x\n",
				 pdev->acs_cap, pdev->acs_capabilities, ret);
			continue;
		}

		pci_dbg(pdev,
			"P2PDMA ACS: ACS cap=%#x caps=%#06x ctrl=%#06x SV=%u TB=%u RR=%u CR=%u UF=%u EC=%u DT=%u\n",
			 pdev->acs_cap, pdev->acs_capabilities, ctrl,
			 !!(ctrl & PCI_ACS_SV), !!(ctrl & PCI_ACS_TB),
			 !!(ctrl & PCI_ACS_RR), !!(ctrl & PCI_ACS_CR),
			 !!(ctrl & PCI_ACS_UF), !!(ctrl & PCI_ACS_EC),
			 !!(ctrl & PCI_ACS_DT));
	}
}

/*
 * Report whether any port between @client and @common rejects Translated
 * addresses. If @common is NULL, every port up to the host bridge is walked.
 * A port whose ACS Control cannot be read counts as blocking, which withdraws
 * only the Translated classes because an Untranslated Request is routed by the
 * redirect controls instead.
 */
static bool pci_p2pdma_path_blocks_translation(struct pci_dev *client,
					       struct pci_dev *common,
					       bool verbose)
{
	struct pci_dev *pdev;
	u16 ctrl;

	/*
	 * @common is @client itself when the provider is the client or sits
	 * below it. The Request never travels upstream then, so no port sees
	 * it and none can reject its Address Type.
	 */
	if (client == common)
		return false;

	for (pdev = pci_upstream_bridge(client); pdev && pdev != common;
	     pdev = pci_upstream_bridge(pdev)) {
		if (!pci_acs_p2pdma_ctrl(pdev, "path hop", &ctrl, verbose))
			return true;

		if (ctrl & PCI_ACS_TB) {
			if (verbose)
				pci_dbg(pdev,
					"P2PDMA ACS: Translation Blocking rejects Translated Requests on this path\n");
			return true;
		}
	}

	return false;
}

static void seq_buf_print_bus_devfn(struct seq_buf *buf, struct pci_dev *pdev)
{
	if (!buf)
		return;

	seq_buf_printf(buf, "%s;", pci_name(pdev));
}

/*
 * What the topology walk found out about one provider/client path. Producing
 * this costs a walk and one config read per divergence port, none of which
 * depends on the TLP being routed.
 *
 * @req_ctrl:	ACS Control of the Requester-side divergence port. That is the
 *		first port at which a Request can route toward the peer rather
 *		than upstream, so it is where the Request controls apply.
 * @cpl_ctrl:	ACS Control of the Completer-side divergence port, likewise for
 *		the Completions travelling back.
 * @tb_on_path:	A port below the divergence blocks Translated addresses.
 *		Every route out of @client passes those, so none carries them.
 * @tb_above_divergence: A port at or above the divergence blocks Translated
 *		addresses. Only a Request continuing to the host bridge passes
 *		those, so a direct route is still open to them.
 * @no_common_bridge: The two paths share no upstream bridge, so no direct
 *		route exists for ACS to gate.
 * @unreadable:	First port whose ACS Control could not be read, if any.
 */
struct pci_p2pdma_acs_path {
	u16 req_ctrl;
	u16 cpl_ctrl;
	bool tb_on_path;
	bool tb_above_divergence;
	bool no_common_bridge;
	struct pci_dev *unreadable;
};

/*
 * ACS Translation Blocking is not a routing control, so unlike the redirect
 * controls it is not decided at the divergence alone. PCIe r7.0 sec 6.12.1.1
 * has every Downstream Port check the Address Type of each Upstream Memory
 * Request it receives, ahead of "any applicable ACS P2P control mechanisms".
 * A port below the divergence cannot redirect the Request anywhere it was not
 * already going, but it can still reject a Translated address.
 */
static enum pci_acs_p2pdma_state
pci_p2pdma_request_state(const struct pci_p2pdma_acs_path *path,
			 unsigned int tlp_flags)
{
	if (tlp_flags & PCI_P2PDMA_TLP_TRANSLATED && path->tb_on_path)
		return PCI_ACS_P2PDMA_BLOCKED;

	return pci_acs_p2pdma_request(path->req_ctrl, tlp_flags);
}

/*
 * Combine both directions into a mapping type. Only a path that routes the
 * Request and the Completions it generates directly can be programmed with
 * the peer's bus addresses.
 */
static enum pci_p2pdma_map_type
pci_p2pdma_route(const struct pci_p2pdma_acs_path *path,
		 unsigned int tlp_flags)
{
	enum pci_acs_p2pdma_state req;

	if (path->unreadable)
		return PCI_P2PDMA_MAP_NOT_SUPPORTED;

	req = pci_p2pdma_request_state(path, tlp_flags);

	/*
	 * Translation Blocking rejects the Address Type rather than the
	 * target, so a blocked Request stays blocked however it is addressed.
	 * No host bridge fallback keeps a Translated address working; the
	 * caller has to issue a different kind of Request instead.
	 */
	if (req == PCI_ACS_P2PDMA_BLOCKED)
		return PCI_P2PDMA_MAP_NOT_SUPPORTED;

	if (!path->no_common_bridge && req == PCI_ACS_P2PDMA_DIRECT &&
	    pci_acs_p2pdma_completion(path->cpl_ctrl, tlp_flags) ==
		    PCI_ACS_P2PDMA_DIRECT)
		return PCI_P2PDMA_MAP_BUS_ADDR;

	/*
	 * A Request that turns around at the divergence never reaches the
	 * ports above it, but one that keeps climbing to the host bridge
	 * does, so that route has to clear their Translation Blocking too.
	 */
	if (tlp_flags & PCI_P2PDMA_TLP_TRANSLATED && path->tb_above_divergence)
		return PCI_P2PDMA_MAP_NOT_SUPPORTED;

	return PCI_P2PDMA_MAP_THRU_HOST_BRIDGE;
}

/*
 * Name the ports that keep this path off a direct route, so that the admin
 * can hand them to pci=disable_acs_redir=. That parameter clears the
 * redirect controls, which decide the default class, so that is the class
 * this reports on.
 */
static void pci_p2pdma_warn_path(struct pci_dev *client,
				 struct pci_dev *provider,
				 const struct pci_p2pdma_acs_path *path,
				 struct pci_dev *a_child,
				 struct pci_dev *b_child)
{
	struct seq_buf acs_list;
	char buf[128];

	if (path->unreadable) {
		pci_warn(client,
			 "ACS Control is unreadable for provider %s at %s\n",
			 pci_name(provider), pci_name(path->unreadable));
		return;
	}

	seq_buf_init(&acs_list, buf, sizeof(buf));
	if (pci_acs_p2pdma_completion(path->cpl_ctrl, 0) !=
	    PCI_ACS_P2PDMA_DIRECT)
		seq_buf_print_bus_devfn(&acs_list, a_child);
	if (pci_acs_p2pdma_request(path->req_ctrl, 0) != PCI_ACS_P2PDMA_DIRECT)
		seq_buf_print_bus_devfn(&acs_list, b_child);

	/* Drop the final semicolon; the list is not empty here */
	if (!seq_buf_has_overflowed(&acs_list))
		acs_list.buffer[acs_list.len - 1] = '\0';

	pci_warn(client,
		 "ACS redirect is set between the client and provider (%s)\n",
		 pci_name(provider));
	pci_warn(client,
		 "to disable ACS controls for this path, add the kernel parameter: pci=disable_acs_redir=%s\n",
		 seq_buf_str(&acs_list));
}

static bool cpu_supports_p2pdma(void)
{
#ifdef CONFIG_X86
	struct cpuinfo_x86 *c = &cpu_data(0);

	/* Any AMD CPU whose family ID is Zen or newer supports p2pdma */
	if (c->x86_vendor == X86_VENDOR_AMD && c->x86 >= 0x17)
		return true;
#endif

	return false;
}

static const struct pci_p2pdma_whitelist_entry {
	unsigned short vendor;
	int device;
	enum {
		REQ_SAME_HOST_BRIDGE	= 1 << 0,
	} flags;
} pci_p2pdma_whitelist[] = {
	/* Intel Xeon E5/Core i7 */
	{PCI_VENDOR_ID_INTEL,	0x3c00, REQ_SAME_HOST_BRIDGE},
	{PCI_VENDOR_ID_INTEL,	0x3c01, REQ_SAME_HOST_BRIDGE},
	/* Intel Xeon E7 v4/Xeon E5 v4/Xeon E3 v4/Xeon D */
	{PCI_VENDOR_ID_INTEL,	0x6f00, REQ_SAME_HOST_BRIDGE},
	/* Intel Xeon E7 v3/Xeon E5 v3/Core i7 */
	{PCI_VENDOR_ID_INTEL,	0x2f00, REQ_SAME_HOST_BRIDGE},
	{PCI_VENDOR_ID_INTEL,	0x2f01, REQ_SAME_HOST_BRIDGE},
	/* Intel Haswell (client) */
	{PCI_VENDOR_ID_INTEL,	0x0c08, REQ_SAME_HOST_BRIDGE},
	/* Intel Skylake-E */
	{PCI_VENDOR_ID_INTEL,	0x2030, 0},
	{PCI_VENDOR_ID_INTEL,	0x2031, 0},
	{PCI_VENDOR_ID_INTEL,	0x2032, 0},
	{PCI_VENDOR_ID_INTEL,	0x2033, 0},
	{PCI_VENDOR_ID_INTEL,	0x2020, 0},
	{PCI_VENDOR_ID_INTEL,	0x09a2, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_DSA_SPR0, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_IAX_SPR0, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_DSA_GNRD, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_DSA_DMR, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_IAA_DMR, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_QAT_4XXX, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_QAT_401XX, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_QAT_402XX, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_QAT_420XX, 0},
	{PCI_VENDOR_ID_INTEL,	PCI_DEVICE_ID_INTEL_QAT_6XXX, 0},
	/* Google SoCs. */
	{PCI_VENDOR_ID_GOOGLE,	PCI_ANY_ID, 0},
	/* Nvidia CPUs */
	{PCI_VENDOR_ID_NVIDIA, 0x2f95, 0},
	{PCI_VENDOR_ID_NVIDIA, 0x2f96, 0},
	{PCI_VENDOR_ID_NVIDIA, 0x2f97, 0},
	{PCI_VENDOR_ID_NVIDIA, 0x2f98, 0},
	/* Zhaoxin KX-6000/KH-40000/KX-6000G/KX-7000/KH-50000 */
	{PCI_VENDOR_ID_ZHAOXIN, 0x1003, REQ_SAME_HOST_BRIDGE},
	{PCI_VENDOR_ID_ZHAOXIN, 0x1005, REQ_SAME_HOST_BRIDGE},
	{PCI_VENDOR_ID_ZHAOXIN, 0x1006, REQ_SAME_HOST_BRIDGE},
	{PCI_VENDOR_ID_ZHAOXIN, 0x1007, REQ_SAME_HOST_BRIDGE},
	{PCI_VENDOR_ID_ZHAOXIN, 0x1008, 0},
	/* Alibaba T-HEAD Yitian 710 CPU */
	{PCI_VENDOR_ID_ALIBABA, 0x8000, 0},
	{}
};

/*
 * If the first device on host's root bus is either devfn 00.0 or a PCIe
 * Root Port, return it.  Otherwise return NULL.
 *
 * We often use a devfn 00.0 "host bridge" in the pci_p2pdma_whitelist[]
 * (though there is no PCI/PCIe requirement for such a device).  On some
 * platforms, e.g., Intel Skylake, there is no such host bridge device, and
 * pci_p2pdma_whitelist[] may contain a Root Port at any devfn.
 *
 * This function is similar to pci_get_slot(host->bus, 0), but it does
 * not take the pci_bus_sem lock since __host_bridge_whitelist() must not
 * sleep.
 *
 * For this to be safe, the caller should hold a reference to a device on the
 * bridge, which should ensure the host_bridge device will not be freed
 * or removed from the head of the devices list.
 */
static struct pci_dev *pci_host_bridge_dev(struct pci_host_bridge *host)
{
	struct pci_dev *root;

	root = list_first_entry_or_null(&host->bus->devices,
					struct pci_dev, bus_list);

	if (!root)
		return NULL;

	if (root->devfn == PCI_DEVFN(0, 0))
		return root;

	if (pci_pcie_type(root) == PCI_EXP_TYPE_ROOT_PORT)
		return root;

	return NULL;
}

static bool __host_bridge_whitelist(struct pci_host_bridge *host,
				    bool same_host_bridge, bool warn)
{
	struct pci_dev *root = pci_host_bridge_dev(host);
	const struct pci_p2pdma_whitelist_entry *entry;
	unsigned short vendor, device;

	if (!root)
		return false;

	vendor = root->vendor;
	device = root->device;

	for (entry = pci_p2pdma_whitelist; entry->vendor; entry++) {
		if (vendor != entry->vendor)
			continue;

		if (entry->device != PCI_ANY_ID && device != entry->device)
			continue;

		if (entry->flags & REQ_SAME_HOST_BRIDGE && !same_host_bridge)
			return false;

		return true;
	}

	if (warn)
		pci_warn(root, "Host bridge not in P2PDMA whitelist: %04x:%04x\n",
			 vendor, device);

	return false;
}

/*
 * If we can't find a common upstream bridge take a look at the root
 * complex and compare it to a whitelist of known good hardware.
 */
static bool host_bridge_whitelist(struct pci_dev *a, struct pci_dev *b,
				  bool warn)
{
	struct pci_host_bridge *host_a = pci_find_host_bridge(a->bus);
	struct pci_host_bridge *host_b = pci_find_host_bridge(b->bus);

	if (host_a == host_b)
		return __host_bridge_whitelist(host_a, true, warn);

	if (__host_bridge_whitelist(host_a, false, warn) &&
	    __host_bridge_whitelist(host_b, false, warn))
		return true;

	return false;
}

static unsigned long map_types_idx(struct pci_dev *client)
{
	return (pci_domain_nr(client->bus) << 16) | pci_dev_id(client);
}

/*
 * One cache entry holds the routing of every TLP class, four bits each,
 * indexed by the &enum pci_p2pdma_tlp_flags combination that selects it. An
 * absent entry reads back as PCI_P2PDMA_MAP_UNKNOWN in every class.
 */
static_assert(PCI_P2PDMA_MAP_THRU_HOST_BRIDGE < 16);

VISIBLE_IF_KUNIT unsigned long
pci_p2pdma_map_types_pack(const enum pci_p2pdma_map_type *type)
{
	unsigned long val = 0;
	unsigned int flags;

	for (flags = 0; flags < PCI_P2PDMA_TLP_CLASSES; flags++)
		val |= (unsigned long)type[flags] << (flags * 4);

	return val;
}
EXPORT_SYMBOL_IF_KUNIT(pci_p2pdma_map_types_pack);

VISIBLE_IF_KUNIT enum pci_p2pdma_map_type
pci_p2pdma_map_types_unpack(unsigned long val, unsigned int tlp_flags)
{
	return (val >> (tlp_flags * 4)) & 0xf;
}
EXPORT_SYMBOL_IF_KUNIT(pci_p2pdma_map_types_unpack);

/*
 * Calculate the P2PDMA mapping type and distance between two PCI devices.
 *
 * If the two devices are the same PCI function, return
 * PCI_P2PDMA_MAP_BUS_ADDR and a distance of 0.
 *
 * If they are two functions of the same device, return
 * PCI_P2PDMA_MAP_BUS_ADDR and a distance of 2 (one hop up to the bridge,
 * then one hop back down to another function of the same device).
 *
 * In the case where two devices are connected to the same PCIe switch,
 * return a distance of 4. This corresponds to the following PCI tree:
 *
 *     -+  Root Port
 *      \+ Switch Upstream Port
 *       +-+ Switch Downstream Port 0
 *       + \- Device A
 *       \-+ Switch Downstream Port 1
 *         \- Device B
 *
 * The distance is 4 because we traverse from Device A to Downstream Port 0
 * to the common Switch Upstream Port, back down to Downstream Port 1 and
 * then to Device B. The mapping type returned depends on the ACS
 * redirection setting of the ports along the path.
 *
 * The client is the Requester and the provider the Completer. At the path
 * divergence, check Request Redirect, Egress Control and Direct Translated
 * P2P on the Requester-side port, and Completion Redirect for read
 * Completions on the Completer-side port. Translation Blocking is checked on
 * every port the Request passes instead, because it rejects a Request rather
 * than routing it.
 *
 * Those controls apply to different TLPs, so every class named by &enum
 * pci_p2pdma_tlp_flags is decided from the one walk and cached together;
 * @tlp_flags selects which one is returned.
 *
 * If ACS redirects traffic at either divergence port, return
 * PCI_P2PDMA_MAP_THRU_HOST_BRIDGE. If the ACS Control register cannot be
 * read, or Translation Blocking rejects the class being asked about, return
 * PCI_P2PDMA_MAP_NOT_SUPPORTED. Otherwise, return PCI_P2PDMA_MAP_BUS_ADDR.
 *
 * Any two devices that have a data path that goes through the host bridge
 * will consult a whitelist. If the host bridge is in the whitelist, return
 * PCI_P2PDMA_MAP_THRU_HOST_BRIDGE with the distance set to the number of
 * ports per above. If the device is not in the whitelist, return
 * PCI_P2PDMA_MAP_NOT_SUPPORTED.
 */
VISIBLE_IF_KUNIT enum pci_p2pdma_map_type
calc_map_type_and_dist(struct pci_dev *provider, struct pci_dev *client,
		int *dist, unsigned int tlp_flags, bool verbose)
{
	enum pci_p2pdma_map_type map_type[PCI_P2PDMA_TLP_CLASSES];
	struct pci_dev *a = provider, *b = client, *bb;
	struct pci_dev *a_child = NULL, *b_child = NULL;
	struct pci_host_bridge *provider_host, *client_host;
	struct pci_p2pdma_acs_path path = {};
	struct pci_p2pdma *p2pdma;
	bool cpu_p2pdma, host_whitelisted = false;
	bool cache_store = false;
	bool host_fallback = false;
	unsigned int flags;
	int dist_a = 0;
	int dist_b = 0;

	if (verbose)
		pci_dbg(client,
			"P2PDMA ACS: begin provider=%s client=%s cache-index=%#lx\n",
			 pci_name(provider), pci_name(client),
			 map_types_idx(client));

	/*
	 * Note, we don't need to take references to devices returned by
	 * pci_upstream_bridge() seeing we hold a reference to a child
	 * device which will already hold a reference to the upstream bridge.
	 */
	while (a) {
		dist_b = 0;
		b_child = NULL;
		bb = b;

		while (bb) {
			if (a == bb)
				goto check_paths_acs;

			b_child = bb;
			bb = pci_upstream_bridge(bb);
			dist_b++;
		}

		a_child = a;
		a = pci_upstream_bridge(a);
		dist_a++;
	}

	/*
	 * The paths share no upstream bridge, so there is no direct path for
	 * ACS to gate: PCI_P2PDMA_MAP_BUS_ADDR is not reachable here and the
	 * request can only get to the peer through the host bridge.
	 */
	*dist = dist_a + dist_b;
	if (verbose) {
		pci_dbg(client,
			"P2PDMA ACS: no common upstream bridge provider-distance=%d client-distance=%d total=%d\n",
			 dist_a, dist_b, *dist);
		pci_p2pdma_log_path("provider", provider, NULL);
		pci_p2pdma_log_path("client", client, NULL);
	}
	path.no_common_bridge = true;
	path.tb_on_path = pci_p2pdma_path_blocks_translation(client, NULL,
							     verbose);
	for (flags = 0; flags < PCI_P2PDMA_TLP_CLASSES; flags++)
		map_type[flags] = pci_p2pdma_route(&path, flags);
	goto map_through_host_bridge;

check_paths_acs:
	*dist = dist_a + dist_b;
	if (verbose) {
		pci_dbg(client,
			"P2PDMA ACS: common=%s provider-divergence=%s client-divergence=%s provider-distance=%d client-distance=%d total=%d\n",
			 pci_name(a),
			 a_child ? pci_name(a_child) : "<none>",
			 b_child ? pci_name(b_child) : "<none>",
			 dist_a, dist_b, *dist);
		pci_p2pdma_log_path("provider", provider, a);
		pci_p2pdma_log_path("client", client, a);
	}

	/*
	 * ACS P2P routing controls apply where a TLP can route toward the peer
	 * or upstream. Below that divergence, its only route toward the other
	 * branch is upstream, so redirect controls do not affect the path.
	 */
	if (a_child && b_child) {
		if (!pci_acs_p2pdma_ctrl(a_child, "completion", &path.cpl_ctrl,
					 verbose))
			path.unreadable = a_child;
		if (!pci_acs_p2pdma_ctrl(b_child, "request", &path.req_ctrl,
					 verbose) && !path.unreadable)
			path.unreadable = b_child;
		if (verbose && !path.unreadable)
			pci_dbg(client,
				"P2PDMA ACS: request=%s at %s completion=%s at %s\n",
				 pci_acs_p2pdma_state_name(
					 pci_p2pdma_request_state(&path, 0)),
				 pci_name(b_child),
				 pci_acs_p2pdma_state_name(
					 pci_acs_p2pdma_completion(path.cpl_ctrl,
								   0)),
				 pci_name(a_child));
	} else if (verbose) {
		pci_dbg(client,
			"P2PDMA ACS: peer divergence is incomplete; no ACS peer-routing controls evaluated\n");
	}

	path.tb_on_path = pci_p2pdma_path_blocks_translation(client, a,
							     verbose);
	if (b_child)
		path.tb_above_divergence =
			pci_p2pdma_path_blocks_translation(b_child, NULL,
							   verbose);

	/*
	 * The walk and the config reads above serve every class; only the
	 * decision below depends on the kind of TLP being routed.
	 */
	for (flags = 0; flags < PCI_P2PDMA_TLP_CLASSES; flags++) {
		map_type[flags] = pci_p2pdma_route(&path, flags);
		if (map_type[flags] == PCI_P2PDMA_MAP_THRU_HOST_BRIDGE)
			host_fallback = true;
	}

	if (verbose && map_type[0] != PCI_P2PDMA_MAP_BUS_ADDR)
		pci_p2pdma_warn_path(client, provider, &path, a_child,
				     b_child);

	/*
	 * Nothing needs the host bridge: the classes that did not get a direct
	 * route have no fallback that would use it.
	 */
	if (!host_fallback)
		goto done;

map_through_host_bridge:
	cpu_p2pdma = cpu_supports_p2pdma();
	if (!cpu_p2pdma)
		host_whitelisted = host_bridge_whitelist(provider, client,
							  verbose);

	if (verbose) {
		provider_host = pci_find_host_bridge(provider->bus);
		client_host = pci_find_host_bridge(client->bus);
		pci_dbg(client,
			"P2PDMA ACS: host fallback cpu-support=%u whitelist=%s provider-host=%s client-host=%s same-host=%u\n",
			 cpu_p2pdma,
			 cpu_p2pdma ? "not-consulted" :
					(host_whitelisted ? "yes" : "no"),
			 provider_host ? dev_name(&provider_host->dev) : "<none>",
			 client_host ? dev_name(&client_host->dev) : "<none>",
			 provider_host && provider_host == client_host);
	}

	if (!cpu_p2pdma && !host_whitelisted) {
		if (verbose)
			pci_warn(client, "cannot be used for peer-to-peer DMA as the client and provider (%s) do not share an upstream bridge or whitelisted host bridge\n",
				 pci_name(provider));
		for (flags = 0; flags < PCI_P2PDMA_TLP_CLASSES; flags++)
			if (map_type[flags] == PCI_P2PDMA_MAP_THRU_HOST_BRIDGE)
				map_type[flags] = PCI_P2PDMA_MAP_NOT_SUPPORTED;
	}
done:
	rcu_read_lock();
	p2pdma = rcu_dereference(provider->p2pdma);
	if (p2pdma) {
		xa_store(&p2pdma->map_types, map_types_idx(client),
			 xa_mk_value(pci_p2pdma_map_types_pack(map_type)), GFP_ATOMIC);
		cache_store = true;
	}
	rcu_read_unlock();
	if (verbose) {
		pci_dbg(client,
			"P2PDMA ACS: final provider=%s result=%s(%d) tlp-flags=%#x distance=%d unreadable=%s cache-store=%u index=%#lx\n",
			 pci_name(provider),
			 pci_p2pdma_map_type_name(map_type[tlp_flags]),
			 map_type[tlp_flags], tlp_flags, *dist,
			 path.unreadable ? pci_name(path.unreadable) : "<none>",
			 cache_store, map_types_idx(client));
		pci_dbg(client,
			"P2PDMA ACS: classes strict=%s relaxed=%s translated=%s translated+relaxed=%s\n",
			 pci_p2pdma_map_type_name(map_type[0]),
			 pci_p2pdma_map_type_name(
				 map_type[PCI_P2PDMA_TLP_RELAXED_CPL]),
			 pci_p2pdma_map_type_name(
				 map_type[PCI_P2PDMA_TLP_TRANSLATED]),
			 pci_p2pdma_map_type_name(
				 map_type[PCI_P2PDMA_TLP_TRANSLATED |
					  PCI_P2PDMA_TLP_RELAXED_CPL]));
	}
	return map_type[tlp_flags];
}
EXPORT_SYMBOL_IF_KUNIT(calc_map_type_and_dist);

/**
 * pci_p2pdma_distance_many - Determine the cumulative distance between
 *	a p2pdma provider and the clients in use.
 * @provider: p2pdma provider to check against the client list
 * @clients: array of devices to check (NULL-terminated)
 * @num_clients: number of clients in the array
 * @verbose: if true, print warnings for devices when we return -1
 *
 * Returns -1 if any of the clients are not compatible, otherwise returns a
 * positive number where a lower number is the preferable choice. (If there's
 * one client that's the same as the provider it will return 0, which is best
 * choice).
 *
 * "compatible" means the provider and the clients are either all behind
 * the same PCI root port or the host bridges connected to each of the devices
 * are listed in the 'pci_p2pdma_whitelist'.
 */
int pci_p2pdma_distance_many(struct pci_dev *provider, struct device **clients,
			     int num_clients, bool verbose)
{
	enum pci_p2pdma_map_type map;
	bool not_supported = false;
	struct pci_dev *pci_client;
	int total_dist = 0;
	int i, distance;

	if (num_clients == 0)
		return -1;

	for (i = 0; i < num_clients; i++) {
		pci_client = find_parent_pci_dev(clients[i]);
		if (!pci_client) {
			if (verbose)
				dev_warn(clients[i],
					 "cannot be used for peer-to-peer DMA as it is not a PCI device\n");
			return -1;
		}

		map = calc_map_type_and_dist(provider, pci_client, &distance, 0,
					     verbose);

		pci_dev_put(pci_client);

		if (map == PCI_P2PDMA_MAP_NOT_SUPPORTED)
			not_supported = true;

		if (not_supported && !verbose)
			break;

		total_dist += distance;
	}

	if (not_supported)
		return -1;

	return total_dist;
}
EXPORT_SYMBOL_GPL(pci_p2pdma_distance_many);

/**
 * pci_has_p2pmem - check if a given PCI device has published any p2pmem
 * @pdev: PCI device to check
 */
static bool pci_has_p2pmem(struct pci_dev *pdev)
{
	struct pci_p2pdma *p2pdma;
	bool res;

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);

	/*
	 * The callers hand the result to pci_alloc_p2pmem(), so only a
	 * provider backed by a pool is of any use here. pcim_p2pdma_init()
	 * creates providers without one.
	 */
	res = p2pdma && p2pdma->pool && p2pdma->p2pmem_published;
	rcu_read_unlock();

	return res;
}

/**
 * pci_p2pmem_find_many - find a peer-to-peer DMA memory device compatible with
 *	the specified list of clients and shortest distance
 * @clients: array of devices to check (NULL-terminated)
 * @num_clients: number of client devices in the list
 *
 * If multiple devices are behind the same switch, the one "closest" to the
 * client devices in use will be chosen first. (So if one of the providers is
 * the same as one of the clients, that provider will be used ahead of any
 * other providers that are unrelated). If multiple providers are an equal
 * distance away, one will be chosen at random.
 *
 * Returns a pointer to the PCI device with a reference taken (use pci_dev_put
 * to return the reference) or NULL if no compatible device is found. The
 * found provider will also be assigned to the client list.
 */
struct pci_dev *pci_p2pmem_find_many(struct device **clients, int num_clients)
{
	struct pci_dev *pdev = NULL;
	int distance;
	int closest_distance = INT_MAX;
	struct pci_dev **closest_pdevs;
	int dev_cnt = 0;
	const int max_devs = PAGE_SIZE / sizeof(*closest_pdevs);
	int i;

	closest_pdevs = kmalloc(PAGE_SIZE, GFP_KERNEL);
	if (!closest_pdevs)
		return NULL;

	for_each_pci_dev(pdev) {
		if (!pci_has_p2pmem(pdev))
			continue;

		distance = pci_p2pdma_distance_many(pdev, clients,
						    num_clients, false);
		if (distance < 0 || distance > closest_distance)
			continue;

		if (distance == closest_distance && dev_cnt >= max_devs)
			continue;

		if (distance < closest_distance) {
			for (i = 0; i < dev_cnt; i++)
				pci_dev_put(closest_pdevs[i]);

			dev_cnt = 0;
			closest_distance = distance;
		}

		closest_pdevs[dev_cnt++] = pci_dev_get(pdev);
	}

	if (dev_cnt)
		pdev = pci_dev_get(closest_pdevs[get_random_u32_below(dev_cnt)]);

	for (i = 0; i < dev_cnt; i++)
		pci_dev_put(closest_pdevs[i]);

	kfree(closest_pdevs);
	return pdev;
}
EXPORT_SYMBOL_GPL(pci_p2pmem_find_many);

/**
 * pci_alloc_p2pmem - allocate peer-to-peer DMA memory
 * @pdev: the device to allocate memory from
 * @size: number of bytes to allocate
 *
 * Returns the allocated memory or NULL on error.
 */
void *pci_alloc_p2pmem(struct pci_dev *pdev, size_t size)
{
	void *ret = NULL;
	struct percpu_ref *ref;
	struct pci_p2pdma *p2pdma;

	/*
	 * Pairs with synchronize_rcu() in pci_p2pdma_release() to
	 * ensure pdev->p2pdma is non-NULL for the duration of the
	 * read-lock.
	 */
	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);
	if (unlikely(!p2pdma))
		goto out;

	ret = (void *)gen_pool_alloc_owner(p2pdma->pool, size, (void **) &ref);
	if (!ret)
		goto out;

	if (unlikely(!percpu_ref_tryget_live_rcu(ref))) {
		gen_pool_free(p2pdma->pool, (unsigned long) ret, size);
		ret = NULL;
	}
out:
	rcu_read_unlock();
	return ret;
}
EXPORT_SYMBOL_GPL(pci_alloc_p2pmem);

/**
 * pci_free_p2pmem - free peer-to-peer DMA memory
 * @pdev: the device the memory was allocated from
 * @addr: address of the memory that was allocated
 * @size: number of bytes that were allocated
 */
void pci_free_p2pmem(struct pci_dev *pdev, void *addr, size_t size)
{
	struct percpu_ref *ref;
	struct pci_p2pdma *p2pdma = rcu_dereference_protected(pdev->p2pdma, 1);

	gen_pool_free_owner(p2pdma->pool, (uintptr_t)addr, size,
			(void **) &ref);
	percpu_ref_put(ref);
}
EXPORT_SYMBOL_GPL(pci_free_p2pmem);

/**
 * pci_p2pmem_virt_to_bus - return the PCI bus address for a given virtual
 *	address obtained with pci_alloc_p2pmem()
 * @pdev: the device the memory was allocated from
 * @addr: address of the memory that was allocated
 */
pci_bus_addr_t pci_p2pmem_virt_to_bus(struct pci_dev *pdev, void *addr)
{
	struct pci_p2pdma *p2pdma;

	if (!addr)
		return 0;

	p2pdma = rcu_dereference_protected(pdev->p2pdma, 1);
	if (!p2pdma)
		return 0;

	/*
	 * Note: when we added the memory to the pool we used the PCI
	 * bus address as the physical address. So gen_pool_virt_to_phys()
	 * actually returns the bus address despite the misleading name.
	 */
	return gen_pool_virt_to_phys(p2pdma->pool, (unsigned long)addr);
}
EXPORT_SYMBOL_GPL(pci_p2pmem_virt_to_bus);

/**
 * pci_p2pmem_alloc_sgl - allocate peer-to-peer DMA memory in a scatterlist
 * @pdev: the device to allocate memory from
 * @nents: the number of SG entries in the list
 * @length: number of bytes to allocate
 *
 * Return: %NULL on error or &struct scatterlist pointer and @nents on success
 */
struct scatterlist *pci_p2pmem_alloc_sgl(struct pci_dev *pdev,
					 unsigned int *nents, u32 length)
{
	struct scatterlist *sg;
	void *addr;

	sg = kmalloc_obj(*sg);
	if (!sg)
		return NULL;

	sg_init_table(sg, 1);

	addr = pci_alloc_p2pmem(pdev, length);
	if (!addr)
		goto out_free_sg;

	sg_set_buf(sg, addr, length);
	*nents = 1;
	return sg;

out_free_sg:
	kfree(sg);
	return NULL;
}
EXPORT_SYMBOL_GPL(pci_p2pmem_alloc_sgl);

/**
 * pci_p2pmem_free_sgl - free a scatterlist allocated by pci_p2pmem_alloc_sgl()
 * @pdev: the device to allocate memory from
 * @sgl: the allocated scatterlist
 */
void pci_p2pmem_free_sgl(struct pci_dev *pdev, struct scatterlist *sgl)
{
	struct scatterlist *sg;
	int count;

	for_each_sg(sgl, sg, INT_MAX, count) {
		if (!sg)
			break;

		pci_free_p2pmem(pdev, sg_virt(sg), sg->length);
	}
	kfree(sgl);
}
EXPORT_SYMBOL_GPL(pci_p2pmem_free_sgl);

/**
 * pci_p2pmem_publish - publish the peer-to-peer DMA memory for use by
 *	other devices with pci_p2pmem_find()
 * @pdev: the device with peer-to-peer DMA memory to publish
 * @publish: set to true to publish the memory, false to unpublish it
 *
 * Published memory can be used by other PCI device drivers for
 * peer-2-peer DMA operations. Non-published memory is reserved for
 * exclusive use of the device driver that registers the peer-to-peer
 * memory.
 */
void pci_p2pmem_publish(struct pci_dev *pdev, bool publish)
{
	struct pci_p2pdma *p2pdma;

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);
	if (p2pdma)
		p2pdma->p2pmem_published = publish;
	rcu_read_unlock();
}
EXPORT_SYMBOL_GPL(pci_p2pmem_publish);

/**
 * pcim_p2pdma_set_ats_per_mapping - Declare per-mapping ATS for a client
 * @pdev: PCI device that initiates peer-to-peer DMA
 *
 * Declare that @pdev issues Translated Requests only for the DMA mappings its
 * driver sets up to use ATS, rather than for any address once ATS is enabled.
 * P2PDMA then routes this client's Requests with the Address Type each query
 * asks about, rather than the one its ATS Enable bit implies.
 */
void pcim_p2pdma_set_ats_per_mapping(struct pci_dev *pdev)
{
	struct pci_p2pdma *p2p;

	p2p = rcu_dereference_protected(pdev->p2pdma, 1);
	if (!p2p)
		/*
		 * ats_per_mapping is a performance optimization,
		 * if pcim_p2pdma_init() didn't set pdev->p2pdma pointer
		 * for some reason, let's simply use ATS global settings.
		 */
		return;

	p2p->ats_per_mapping = true;
}
EXPORT_SYMBOL_GPL(pcim_p2pdma_set_ats_per_mapping);

/**
 * pci_p2pdma_map_type_tlp - Determine the mapping type for P2PDMA transfers
 * @provider: P2PDMA provider structure
 * @dev: Client device that initiates the transfer
 * @tlp_flags: &enum pci_p2pdma_tlp_flags describing the TLPs @dev will issue
 *
 * Determines how peer-to-peer DMA transfers should be mapped between
 * the provider and the client device. The mapping type indicates whether
 * the transfer can be done directly through PCI switches or must go
 * through the host bridge.
 *
 * ACS routes a peer-to-peer transaction by the attributes its TLPs carry, so
 * the answer depends on @tlp_flags. A caller that passes flags its traffic
 * does not match gets a mapping the fabric will not deliver.
 */
static enum pci_p2pdma_map_type
pci_p2pdma_map_type_tlp(struct p2pdma_provider *provider, struct device *dev,
			unsigned int tlp_flags)
{
	struct pci_dev *pdev = to_pci_dev(provider->owner);
	unsigned long cache_index, cached = 0;
	enum pci_p2pdma_map_type type;
	struct pci_p2pdma *p2pdma;
	struct pci_dev *client;
	bool provider_state;
	int dist;

	if (!pdev->p2pdma) {
		pci_dbg(pdev,
			"P2PDMA ACS: map lookup rejected; provider state is absent\n");
		return PCI_P2PDMA_MAP_NOT_SUPPORTED;
	}

	if (!dev_is_pci(dev)) {
		dev_dbg(dev,
			"P2PDMA ACS: provider=%s map lookup rejected; client is not PCI\n",
			 pci_name(pdev));
		return PCI_P2PDMA_MAP_NOT_SUPPORTED;
	}

	client = to_pci_dev(dev);
	cache_index = map_types_idx(client);

	rcu_read_lock();
	p2pdma = rcu_dereference(pdev->p2pdma);

	if (p2pdma)
		cached = xa_to_value(xa_load(&p2pdma->map_types,
					     cache_index));
	provider_state = !!p2pdma;
	rcu_read_unlock();
	type = pci_p2pdma_map_types_unpack(cached, tlp_flags);
	pci_dbg(client,
		 "P2PDMA ACS: map lookup provider=%s index=%#lx tlp-flags=%#x cached=%s(%d) provider-state=%u\n",
		 pci_name(pdev), cache_index, tlp_flags,
		 pci_p2pdma_map_type_name(type), type, provider_state);

	if (type == PCI_P2PDMA_MAP_UNKNOWN)
		return calc_map_type_and_dist(pdev, client, &dist, tlp_flags,
					      true);

	return type;
}

/**
 * pci_p2pdma_map_type - Determine the mapping type for P2PDMA transfers
 * @provider: P2PDMA provider structure
 * @dev: Client device that initiates the transfer
 *
 * Same as pci_p2pdma_map_type_tlp() for a client issuing strictly ordered
 * Requests that carry an Untranslated address.
 */
enum pci_p2pdma_map_type pci_p2pdma_map_type(struct p2pdma_provider *provider,
					     struct device *dev)
{
	return pci_p2pdma_map_type_tlp(provider, dev, 0);
}

void __pci_p2pdma_update_state(struct pci_p2pdma_map_state *state,
		struct device *dev, struct page *page)
{
	struct pci_p2pdma_pagemap *p2p_pgmap = to_p2p_pgmap(page_pgmap(page));

	if (state->mem == p2p_pgmap->mem)
		return;

	state->mem = p2p_pgmap->mem;
	state->map = pci_p2pdma_map_type(p2p_pgmap->mem, dev);
}

/**
 * pci_p2pdma_enable_store - parse a configfs/sysfs attribute store
 *		to enable p2pdma
 * @page: contents of the value to be stored
 * @p2p_dev: returns the PCI device that was selected to be used
 *		(if one was specified in the stored value)
 * @use_p2pdma: returns whether to enable p2pdma or not
 *
 * Parses an attribute value to decide whether to enable p2pdma.
 * The value can select a PCI device (using its full BDF device
 * name) or a boolean (in any format kstrtobool() accepts). A false
 * value disables p2pdma, a true value expects the caller
 * to automatically find a compatible device and specifying a PCI device
 * expects the caller to use the specific provider.
 *
 * pci_p2pdma_enable_show() should be used as the show operation for
 * the attribute.
 *
 * Returns 0 on success
 */
int pci_p2pdma_enable_store(const char *page, struct pci_dev **p2p_dev,
			    bool *use_p2pdma)
{
	struct device *dev;

	dev = bus_find_device_by_name(&pci_bus_type, NULL, page);
	if (dev) {
		*use_p2pdma = true;
		*p2p_dev = to_pci_dev(dev);

		if (!pci_has_p2pmem(*p2p_dev)) {
			pci_err(*p2p_dev,
				"PCI device has no peer-to-peer memory: %s\n",
				page);
			pci_dev_put(*p2p_dev);
			return -ENODEV;
		}

		return 0;
	} else if ((page[0] == '0' || page[0] == '1') && !iscntrl(page[1])) {
		/*
		 * If the user enters a PCI device that  doesn't exist
		 * like "0000:01:00.1", we don't want kstrtobool to think
		 * it's a '0' when it's clearly not what the user wanted.
		 * So we require 0's and 1's to be exactly one character.
		 */
	} else if (!kstrtobool(page, use_p2pdma)) {
		return 0;
	}

	pr_err("No such PCI device: %.*s\n", (int)strcspn(page, "\n"), page);
	return -ENODEV;
}
EXPORT_SYMBOL_GPL(pci_p2pdma_enable_store);

/**
 * pci_p2pdma_enable_show - show a configfs/sysfs attribute indicating
 *		whether p2pdma is enabled
 * @page: contents of the stored value
 * @p2p_dev: the selected p2p device (NULL if no device is selected)
 * @use_p2pdma: whether p2pdma has been enabled
 *
 * Attributes that use pci_p2pdma_enable_store() should use this function
 * to show the value of the attribute.
 *
 * Returns 0 on success
 */
ssize_t pci_p2pdma_enable_show(char *page, struct pci_dev *p2p_dev,
			       bool use_p2pdma)
{
	if (!use_p2pdma)
		return sprintf(page, "0\n");

	if (!p2p_dev)
		return sprintf(page, "1\n");

	return sprintf(page, "%s\n", pci_name(p2p_dev));
}
EXPORT_SYMBOL_GPL(pci_p2pdma_enable_show);

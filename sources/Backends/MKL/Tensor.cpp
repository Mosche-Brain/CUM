//
// Created by jaro on 6/28/26.
//

#include <cstdint>
#include <new>
#include <print>

#include <oneapi/dnnl/dnnl.hpp>
#include <oneapi/dnnl/dnnl.h>

#include "cum/Core.hpp"
#include "cum/memory.hpp"
#include "cum/runtime.hpp"
#include "cum/datatypes.hpp"
#include "cum/functions.hpp"
#include "cum/neural_primitives/Memory.hpp"
#include "cum/neural_primitives/Descriptor.hpp"
#include "cum/neural_primitives/elementwise.hpp"
#include "cum/neural_primitives/reductions.hpp"
#include "cum/detail/vendor/oneapi/opaque_types.hpp"
#include "cum/neural_primitives/elementwise_diffs.hpp"
#include "cum/neural_primitives/tensor_operations.hpp"
#include "cum/detail/vendor/oneapi/conversion_helpers.hpp"
#include "cum/detail/vendor/oneapi/dtype_dispatch.hpp"

#include "../../../include/cum/detail/vendor/oneapi/context.hpp"


#include "cum/Tensor.hpp"

#include <ranges>

/*
 * This implementation has a lot of redundant code.
 * We plan to move significant part to other .cpp files
 */


namespace cum
{
	using namespace neural_primitives::handles;
	using neural_primitives::Descriptor;
	using neural_primitives::Memory;
	// using namespace neural_primitives;
	layout default_layout_from_rank(dim_t rank)
	{
		switch(rank)
		{
			case 0:
			case 1: return layout::A;
			case 2: return layout::AB;
			case 3: return layout::ABC;
			case 4: return layout::ABCD;
			case 5: return layout::ABCDE;
			case 6: return layout::ABCDEF;
			case 7: return layout::ABCDEFG;
			default: return layout::ANY;
		}
	}

	layout concrete_layout(std::size_t rank, layout requested)
	{
		if(requested != layout::ANY)
			return requested;
		switch(rank)
		{
			case 1: return layout::A;
			case 2: return layout::AB;
			case 3: return layout::ABC;
			case 4: return layout::ABCD;
			case 5: return layout::ABCDE;
			default: throw std::invalid_argument("unsupported tensor rank");
		}
	}

	/**------------------------------------------------------------------------------------------------
	 *                                         Constructors
	 *------------------------------------------------------------------------------------------------**/

	Tensor::Tensor(const Shape& shape, datatype dtype, layout layout)
		: _desc_(std::make_unique<Descriptor>(shape, dtype, layout == layout::ANY ? default_layout_from_rank(shape.size()) : layout)),
		  _data(sycl::malloc_shared<byte>(_desc_->size(), internal::device(), internal::sycl_context()))
	{
		if(_data == nullptr)
		{
			std::println("sex: {}", _desc_->size());
			throw std::bad_alloc();
		}
		_memr_ = std::make_unique<Memory>(*_desc_, _data);
	}

	Tensor::Tensor( Descriptor& descriptor)
		: _desc_(std::make_unique<Descriptor>(descriptor)),
		  _data(sycl::malloc_shared<byte>(_desc_->size(), internal::device(), internal::sycl_context()))
	{
		if(_data == nullptr)
		{
			std::println("sex: {}", _desc_->size());
			throw std::bad_alloc();
		}
		_memr_ = std::make_unique<Memory>(*_desc_, _data);
	}

	Tensor::Tensor(const Tensor& tensor)
		: _desc_(std::make_unique<Descriptor>(
			tensor.shape(), tensor.type(),
			concrete_layout(tensor.rank(), tensor.format()))),
		  _data(sycl::malloc_shared<std::byte>(
			  _desc_->size(), internal::device(), internal::sycl_context()))
	{
		if (!_data)
			throw std::bad_alloc();

		_memr_ = std::make_unique<Memory>(*_desc_, _data);

		dnnl::reorder(
			tensor.memory()->handle().memory,
			_memr_->handle().memory
		).execute(
			internal::stream(),
			tensor.memory()->handle().memory,
			_memr_->handle().memory
		);

		internal::stream().wait();
	}

	Tensor::Tensor(Tensor&& tensor) noexcept
		: _desc_(std::move(tensor._desc_)),
		  _memr_(std::move(tensor._memr_)),
		  _data(tensor._data),
		  _owns_data(tensor._owns_data)
	{
		tensor._data = nullptr;
		tensor._owns_data = false;
	}


	Tensor::Tensor(const cumeric_t value, datatype dtype, layout layout) : Tensor(Shape{1}, dtype, layout)
	{
		fill(value);
	}

	Tensor::Tensor(dim_t lenght, datatype dtype, layout layout) : Tensor(Shape{lenght}, dtype, layout)
	{
	}

	Tensor::Tensor(dim_t rows, dim_t cols, datatype dtype , layout layout) : Tensor(Shape{rows, cols}, dtype, layout)
	{
	}

	Tensor::Tensor(dim_t axis0, dim_t axis1, dim_t axis2, datatype dtype, layout layout) : Tensor(Shape{axis0, axis1, axis2}, dtype, layout)
	{
	}

	Tensor::Tensor(dim_t axis0, dim_t axis1, dim_t axis2, dim_t axis3, datatype dtype, layout layout) : Tensor(Shape{axis0, axis1, axis2, axis3}, dtype, layout)
	{

	}

	Tensor::Tensor(dim_t axis0, dim_t axis1, dim_t axis2, dim_t axis3, dim_t axis4, datatype dtype, layout layout) : Tensor(Shape{axis0, axis1, axis2, axis3, axis4}, dtype, layout)
	{

	}

	Tensor::~Tensor()
	{
		if(_owns_data && _data != nullptr)
			sycl::free(_data, internal::sycl_context());
	}

	/**------------------------------------------------------------------------------------------------
	 *                                         Fabriques
	 *------------------------------------------------------------------------------------------------**/

	Tensor Tensor::take_memory(const Shape& shape, void* data, datatype dtype, layout layout)
	{
		if(data == nullptr)
			throw std::invalid_argument("take_memory requires a non-null data pointer");

		Tensor tensor(shape, dtype, layout);
		internal::queue().memcpy(tensor._data, data, static_cast<std::size_t>(tensor.size())).wait();
		return tensor;
	}

	Tensor Tensor::copy_memory(const Shape& shape, void* data, datatype dtype, layout layout)
	{
		if(data == nullptr)
			throw std::invalid_argument("take_memory requires a non-null data pointer");

		Tensor tensor(shape, dtype, layout);
		internal::queue().memcpy(tensor._data, data, static_cast<std::size_t>(tensor.size())).wait();
		return tensor;
	}

	Tensor Tensor::Random(const Shape& shape, cumeric_t min, cumeric_t max, datatype dtype, layout layout)
	{
		Tensor tensor;
		tensor._desc_ = std::make_unique<neural_primitives::Descriptor>(shape, dtype, layout);
		tensor._data = sycl::malloc_shared<std::byte>(
			tensor._desc_->size(), internal::device(), internal::sycl_context());
		if(tensor._data == nullptr)
			throw std::bad_alloc();
		tensor._memr_ = std::make_unique<neural_primitives::Memory>(*tensor._desc_, tensor._data);
		dim_t count = tensor.lenght();

		float* temp = sycl::malloc_shared<float>(count, internal::device(), internal::sycl_context());

		float f_min = static_cast<float>(min);
		float f_max = static_cast<float>(max);

		oneapi::mkl::rng::philox4x32x10 engine(internal::queue(), 2137);
		oneapi::mkl::rng::uniform<float> dist(f_min, f_max);
		sycl::event rng_event = oneapi::mkl::rng::generate(dist, engine, count, temp);

		sycl::event kernel_event;
		void* data = tensor._data;

		internal::dispatch_sycl_datatype(tensor.type(), [&]<typename T>(){
			kernel_event = internal::queue().submit([&](sycl::handler& cgh) {
				cgh.depends_on(rng_event);
				cgh.parallel_for(sycl::range<1>(count), [=](sycl::id<1> idx) {
					static_cast<T*>(data)[idx] = static_cast<T>(temp[idx]);
				});
			});
		});

		kernel_event.wait();

		sycl::free(temp, internal::sycl_context());

		return tensor;
	}

	Tensor Tensor::Linspace(cumeric_t start, const cumeric_t end, dim_t num)
	{
		if(num <= 0)
			throw std::invalid_argument("Linspace requires a positive number of elements");

		Tensor tensor(cum::Shape{num}, default_type, layout::X);
		void* values = tensor.data();
		const cumeric_t step = num == 1 ? cumeric_t(0) : (end - start) / static_cast<cumeric_t>(num - 1);


		internal::dispatch_sycl_datatype(tensor.type(), [&]<typename T>() -> void
		{
			internal::queue().submit([&](sycl::handler& cgh) -> void
			{
				cgh.parallel_for(sycl::range<1>(num), [=](sycl::id<1> idx) -> void {
					static_cast<T*>(values)[idx] = static_cast<T>(start) + static_cast<cumeric_t>(idx) * step;
				});
			});
		});

		return tensor;
	}

	Tensor Tensor::Zeros(const Shape& shape, datatype dtype, layout layout)
	{
		Tensor tensor(shape, dtype, layout);
		tensor.fill(0);
		return tensor;
	}

	Tensor Tensor::Ones(const Shape& shape, datatype dtype, layout layout)
	{
		Tensor tensor(shape, dtype, layout);
		tensor.fill(1);
		return tensor;
	}

	Tensor Tensor::make_cube(dim_t width, dim_t height, dim_t deepth, datatype dtype, layout layout)
	{
		const auto cube_layout = layout == cum::layout::OI ? cum::layout::ANY : layout;
		return Tensor({deepth, height, width}, dtype, cube_layout);
	}

	Tensor Tensor::make_matrix(dim_t rows, dim_t cols, datatype dtype, layout layout)
	{
		return Tensor({rows, cols}, dtype, layout);
	}

	Tensor Tensor::make_vector(dim_t lenght, datatype dtype, layout layout)
	{
		return Tensor(Shape{lenght}, dtype, layout);
	}

	Tensor Tensor::make_scalar(datatype dtype, layout layout)
	{
		return Tensor(Shape{1}, dtype, layout);
	}


	/**------------------------------------------------------------------------------------------------
	 *                                         Memory
	 *------------------------------------------------------------------------------------------------**/

	Tensor& Tensor::cast(datatype dtype)
	{
		return *this;
	}

	Tensor& Tensor::prefetch()
	{
		memory::prefetch(data(), this->size());
		return *this;
	}

	Tensor& Tensor::to_host()
	{

	}

	Tensor& Tensor::to_device()
	{
		memory::prefetch(data(), this->size());
		return *this;
	}

	/**------------------------------------------------------------------------------------------------
	 *                                         Getters
	 *------------------------------------------------------------------------------------------------**/

	const std::unique_ptr<neural_primitives::Descriptor>& Tensor::descriptor() const
	{
		return _desc_;
	}

	const std::unique_ptr<neural_primitives::Memory>& Tensor::memory() const
	{
		return _memr_;
	}

	dim_t Tensor::size() const
	{
		return _desc_->size();
	}

	dim_t Tensor::rank() const
	{
		return _desc_->ndims();
	}

	dim_t Tensor::dims() const
    {
		return _desc_->ndims();
    }

	dim_t Tensor::lenght() const
    {
		return _desc_->size() / datatype_size(_desc_->type());
    }


	dim_t Tensor::elements() const
	{
		return lenght();
	}

	Shape Tensor::shape() const
    {
	    return _desc_->shape();
    }

	layout Tensor::format() const
    {
	    return _desc_->format();
    }

	datatype Tensor::type() const
    {
	    return _desc_->type();
    }

	bool Tensor::is_scalar() const
	{
		return _desc_->size() == dnnl::memory::data_type_size(dnnl_data_type(type()));
	}


	dim_t Tensor::rows() const
    {
		if (rank() != 2)
			throw std::runtime_error("Tensor::rows() called on not 2'nd rank tensor");

	    return shape()[0];
    }

	dim_t Tensor::cols() const
    {
		if (rank() != 2)
			throw std::runtime_error("Tensor::cols() called on not 2'nd rank tensor");

	    return shape()[1];
    }

	std::unique_ptr<neural_primitives::Descriptor>& Tensor::descriptor()
	{
		return _desc_;
	}

	std::unique_ptr<neural_primitives::Memory>& Tensor::memory() // Should this be in accessors section
	{
		return _memr_;
	}

	Tensor Tensor::clone() const
	{
		return *this;
	}

	/**-----------------------------------------------------------------------------------------------------------------------
	 *                                                    Accessors
	 *-----------------------------------------------------------------------------------------------------------------------**/

	dim_t Tensor::compute_index(const Shape& indices) const
	{
		dnnl::memory::desc& md = _desc_->handle().desc;

		const Shape& strides = md.get_strides(); 
		const Shape& shape = this->shape();
	
		dim_t offset = 0;
		for(dim_t _ = 0 ; _ < shape.size() ; _++)
		{
			offset += indices[_] * strides[_];
		}

    	return offset;
	}

	void* Tensor::compute_address(const Shape& indices)
	{
		

	}


	cumeric_t& Tensor::at(const Shape& indices)
	{
		// Tensor element = slice(indices, Shape(rank(), 1));
		//
		// void* element_data = element.data();
		// cumeric_t result;
		// dispatch_datatype(this->type(), [&]<typename T>() -> void
		// {
		// 	result = static_cast<cumeric_t>(static_cast<const T*>(element_data)[0]);
		// });

		return at<cumeric_t>(indices);
	}

	const cumeric_t& Tensor::at(const Shape& indices) const
	{
		// Tensor element = slice(indices, Shape(rank(), 1));
		//
		// void* element_data = element.data();
		// cumeric_t result;
		// dispatch_datatype(this->type(), [&]<typename T>() -> void
		// {
		// 	result = static_cast<cumeric_t>(static_cast<const T*>(element_data)[0]);
		// });

		return at<cumeric_t>(indices);
	}

	// cumeric_t Tensor::at(const Shape& indices) const
	// {
	// 	// dim_t idx = compute_index(indices);
	// 	Tensor element = slice(indices, Shape(rank(), 1));
	//
	// 	void* element_data = element.data();
	// 	cumeric_t result;
	// 	dispatch_datatype(this->type(), [&]<typename T>() -> void
	// 	{
	// 		T value = static_cast<const T*>(element_data)[0];
	// 		result = static_cast<cumeric_t>(value);
	// 	});
	//
	// 	return result;
	// }


	const void* Tensor::data() const
    {
	    return static_cast<const void*>(
		    static_cast<const std::byte*>(_data)
		    + _desc_->offset() * datatype_size(type())
	    );
    }

	void* Tensor::data()
    {
	    return static_cast<void*>(
		    static_cast<std::byte*>(_data)
		    + _desc_->offset() * datatype_size(type())
	    );
    }

	cumeric_t Tensor::get_value(const Shape& indices) const
	{
		cumeric_t value;

		auto *device_ptr = data<cumeric_t>();

		internal::queue().memcpy(
			&value,
			device_ptr + compute_index(indices),
			sizeof(cumeric_t)
		).wait();

		return value;
	}


	cumeric_t Tensor::operator ()(const dim_t row, const dim_t col) const
	{
		return this->at(Shape{row, col});
	}

	cumeric_t Tensor::operator ()(const dim_t idx0, const dim_t idx1, const dim_t idx2) const
	{
		return this->at(Shape{idx0, idx1, idx2});
	}

	cumeric_t Tensor::operator ()(const dim_t idx0, const dim_t idx1, const dim_t idx2, const dim_t idx3) const
	{
		return this->at(Shape{idx0, idx1, idx2, idx3});
	}

	cumeric_t Tensor::operator ()(const dim_t idx0, const dim_t idx1, const dim_t idx2, const dim_t idx3, const dim_t idx4) const
	{
		return this->at(Shape{idx0, idx1, idx2, idx3, idx4});
	}


	Tensor Tensor::batch(dim_t index) const
	{
	}

	Tensor Tensor::channel(dim_t index) const
	{
	}

	Tensor Tensor::row(dim_t index) const
	{
		if (this->rank() != 2)
			throw std::runtime_error("Tensor::row(): rank != 2");

		return slice({index, 0}, {1, cols()});
	}

	Tensor Tensor::col(dim_t index) const
	{
		if (this->rank() != 2)
			throw std::runtime_error("Tensor::col(): rank != 2");

		return slice({0, index}, {rows(), 1});

		// return select_axis(*this, Axis::Cols, index);
	}

	/**------------------------------------------------------------------------------------------------
	*                                         Reshaping
	*------------------------------------------------------------------------------------------------**/

	Tensor Tensor::reshape(const Shape& shape) const
	{

	}

	Tensor& Tensor::reshape_in_place(const Shape& shape)
	{
		return *this;
	}


	Tensor::Tensor(neural_primitives::Descriptor&& desc, const neural_primitives::Memory& source)
		: _desc_(std::make_unique<neural_primitives::Descriptor>(std::move(desc))),
		  _memr_(std::make_unique<neural_primitives::Memory>(*_desc_, source)),
		  _data(const_cast<void*>(source.data())),
		  _owns_data(false)
	{
	}

	Tensor Tensor::slice(const Shape& offset, const Shape& shape) const
	{
		if (offset.size() != shape.size())
			throw std::invalid_argument("offset and shape must have the same size");

		if(offset.size() != this->rank())
		{
			std::println("offset rank: {}, tensor rank: {}", offset.size(), this->rank());
			throw std::invalid_argument("offset and shape must have the same rank");
		}
		for(dim_t i = 0; i < shape.size(); i++)
			if(offset[i] + shape[i] > this->shape()[i])
				throw std::invalid_argument("offset + shape > tensor size");

		const dnnl::memory::desc& md = _desc_->handle().desc;

		const dnnl::memory::desc sub_md = md.submemory_desc(shape, offset);

		return Tensor(Descriptor({sub_md}), *_memr_);
    }


	Tensor Tensor::transpose() const
	{
		if (this->is_scalar())
			return *this;

		if (this->rank() < 2)
			throw std::invalid_argument("transpose requires at least two-dimensional tensor");

		Shape transposed_shape = this->shape();
		auto shape_rev = transposed_shape | std::views::reverse;
		std::swap(shape_rev[0], shape_rev[1]);

		std::vector<int> perm(this->rank());
		std::iota(perm.begin(), perm.end(), 0);

		auto perm_rev = perm | std::views::reverse;
		std::swap(perm_rev[0], perm_rev[1]);

		Tensor result(transposed_shape, type(), format());

		dnnl::memory::desc permuted_src_md = _desc_->handle().desc.permute_axes(perm);
		dnnl::memory::desc& dst_md = result._desc_->handle().desc;

		dnnl::reorder::primitive_desc primitive_desc(
			internal::engine(),
			permuted_src_md,
			internal::engine(),
			dst_md
		);

		dnnl::memory src_mem(permuted_src_md, internal::engine(), _memr_->handle().memory.get_data_handle());
		dnnl::memory& dst_mem = result._memr_->handle().memory;

		dnnl::reorder(primitive_desc).execute(
			internal::stream(),
			{
				{ DNNL_ARG_SRC, src_mem },
				{ DNNL_ARG_DST, dst_mem }
			}
		);

		internal::stream().wait();

		return result;
    }

	Tensor& Tensor::transpose_in_place() // this function may not work properly due to obvious problem with in place permutations
	{
		if (is_scalar())
		{
			// std::println("is_scalar");
			return *this;
		}

		if(dims() != 2)
			throw std::invalid_argument("transposition requires a two-dimensional tensor");

		layout format = this->format() == layout::BA ? layout::AB : layout::BA;


		Descriptor desc(this->shape(), this->type(), format);
		dnnl::reorder::primitive_desc primitive_desc(
			internal::engine(),
			_desc_->handle().desc,
			internal::engine(),
			desc.handle().desc
		);

		Memory memr(desc, *_memr_);

		dnnl::reorder(primitive_desc).execute(
			internal::stream(),
	{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, _memr_->handle().memory}
			}
		);

		internal::stream().wait();

		std::make_unique<neural_primitives::Descriptor>(desc);

		Shape new_shape = _desc_->shape();


		std::swap(new_shape[0], new_shape[1]);

		// std::println("new: [{}, {}]", new_shape[0], new_shape[1]);
		// std::println("old: [{}, {}]", _desc_->shape()[0], _desc_->shape()[1]);

		_desc_->reshape_in_place(new_shape);

		// *this = this->transpose();
		// this may work properly, I will check it later

		return *this;
    }

	/**------------------------------------------------------------------------------------------------
	 *                                         Reductions
	 *------------------------------------------------------------------------------------------------**/

	cumeric_t Tensor::sum() const
    {
		if (is_scalar())
			return at(Shape(rank(), 0));

		cumeric_t* sum_buff = sycl::malloc_shared<cumeric_t>(1, internal::device(), internal::sycl_context());
    	sum_buff[0] = 0;

    	dnnl::memory::desc sum_desc {
    		Shape(this->dims(), 1), dnnl_data_type(default_type), dnnl_format_tag(format())
    	};

    	dnnl::memory sum_memory = dnnl::sycl_interop::make_memory(
    		sum_desc, internal::engine(), dnnl::sycl_interop::memory_kind::usm, sum_buff
    	);

    	dnnl::reduction::primitive_desc pd(
			internal::engine(),
			dnnl::algorithm::reduction_sum,
			_desc_->handle().desc,
			sum_desc,
			0.0f,   // p
			0.0f  // eps
		);

    	dnnl::reduction(pd).execute(
			internal::stream(),
	{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, sum_memory}
			}
		);

    	internal::stream().wait();

    	cumeric_t result = sum_buff[0];
    	memory::free(sum_buff);

    	return result;
    }

	cumeric_t Tensor::mean() const
	{
		return this->sum() / this->lenght();
	}

	cumeric_t Tensor::amean() const
	{

	}


	cumeric_t Tensor::squaredNorm() const
	{
		return this->squared_norm();
	}

	cumeric_t Tensor::norm() const
	{
		return static_cast<cumeric_t>(std::sqrt(static_cast<double>(squared_norm())));
	}



	cumeric_t Tensor::squared_norm() const
	{
		Tensor square_tensor(this->shape(), this->type(), this->format());
		dnnl::eltwise_forward::primitive_desc square_desc(
			internal::engine(),
			dnnl::prop_kind::forward,
			dnnl::algorithm::eltwise_square,
			_desc_->handle().desc,
			square_tensor._desc_->handle().desc
		);
		dnnl::eltwise_forward(square_desc).execute(
			internal::stream(),
			{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, square_tensor._memr_->handle().memory}
			}
		);

		const Shape reduced_shape(shape().size(), 1);
		layout reduced_layout = default_layout_from_rank(rank());

		dnnl::memory::desc result_desc(
			reduced_shape,
			dnnl_data_type(default_type),
			dnnl_format_tag(reduced_layout)
		);


		cumeric_t* result = sycl::malloc_shared<cumeric_t>(
			1,
			internal::device(),
			internal::sycl_context()
		);

		dnnl::memory result_memory = dnnl::sycl_interop::make_memory(
			result_desc,
			internal::engine(),
			dnnl::sycl_interop::memory_kind::usm,
			result
		);
		if (lenght() == 1)
		{
			const cumeric_t value = square_tensor.get_value(Shape(square_tensor.rank(), 0));
			runtime::sync(); // global synchronization ⚠️
			sycl::free(result, internal::sycl_context());
			return value;
		}

		dnnl::reduction::primitive_desc reduction_desc(
			internal::engine(),
			dnnl::algorithm::reduction_sum,
			square_tensor._desc_->handle().desc,
			result_desc,
			0.0f,
			0.0f
		);

		dnnl::reduction(reduction_desc).execute(
			internal::stream(),
			{
				{DNNL_ARG_SRC, square_tensor._memr_->handle().memory},
				{DNNL_ARG_DST, result_memory}
			}
		);
		internal::stream().wait();

		const cumeric_t value = *result;
		sycl::free(result, internal::sycl_context());
		return value;
	}

	Tensor Tensor::colwise_sum()
	{
		if(dims() != 2)
			throw std::invalid_argument("colwise_sum requires a two-dimensional tensor");

		const Shape source_shape = shape();
		Tensor result({source_shape[0], 1}, type(), layout::IO);
		dnnl::reduction::primitive_desc primitive_desc(
			internal::engine(),
			dnnl::algorithm::reduction_sum,
			_desc_->handle().desc,
			result._desc_->handle().desc,
			0.0f,
			0.0f
		);

		dnnl::reduction(primitive_desc).execute(
			internal::stream(),
			{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, result._memr_->handle().memory}
			}
		);
		internal::stream().wait();
		return result;
	}

	Tensor Tensor::sum(dim_t axis, bool keep_dims) const
	{
		// if(axis < 0) axis += rank();
		axis < 0 ? axis = this->rank() - 1 : NULL;

		if(axis > this->rank())
			throw std::invalid_argument("Tensor::sum(): provided axis argument is higher than tensor rank");

		Shape new_shape = this->shape();
		new_shape[axis] = 1;

		Tensor result(new_shape, this->type(), this->format());

		const dnnl::memory::desc& src_desc = _desc_->handle().desc;
		const dnnl::memory::desc& dst_desc = result.descriptor()->handle().desc;

		dnnl::reduction::primitive_desc primitive_desc(
			internal::engine(),
			dnnl::algorithm::reduction_sum,
			src_desc,
			dst_desc,
			0.0f,
			0.0f
		);

		dnnl::reduction(primitive_desc).execute(
			internal::stream(),
	{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, result._memr_->handle().memory}
			}
		);
		internal::stream().wait();

		if(!keep_dims)
		{
			Shape squeezed = new_shape;
			squeezed.erase(squeezed.begin() + axis);
			return result.reshape(squeezed);
		}
		else
		{
			return result;
		}
	}

	Tensor Tensor::softmax(dim_t axis) const
	{
		// Tensor result(this->shape(), this->type(), this->format());
		Tensor result(this->shape(), this->type(), default_layout_from_rank(this->rank()));

		neural_primitives::softmax(result, *this, axis);

		return result;
	}

	Tensor Tensor::rowwise_sum()
	{
		if(dims() != 2)
			throw std::invalid_argument("rowwise_sum requires a two-dimensional tensor");

		Shape new_shape = shape();
		new_shape[1] = 1;

		Tensor result(new_shape, type(), format());

		dnnl::reduction::primitive_desc primitive_desc(
			internal::engine(),
			dnnl::algorithm::reduction_sum,
			_desc_->handle().desc,
			result._desc_->handle().desc,
			0.0f,
			0.0f
		);

		dnnl::reduction(primitive_desc).execute(
			internal::stream(),
	{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, result._memr_->handle().memory}
			}
		);
		internal::stream().wait();
		return result;
	}

	Tensor Tensor::channelwise_sum()
	{
		if(dims() != 3)
			throw std::invalid_argument("channelwise_sum requires a tree-dimensional tensor");

		const Shape source_shape = shape();
		Tensor result({1, source_shape[0]}, type(), layout::IO);
		dnnl::reduction::primitive_desc primitive_desc(
			internal::engine(),
			dnnl::algorithm::reduction_sum,
			_desc_->handle().desc,
			result._desc_->handle().desc,
			0.0f,
			0.0f
		);

		dnnl::reduction(primitive_desc).execute(
			internal::stream(),
			{
				{DNNL_ARG_SRC, _memr_->handle().memory},
				{DNNL_ARG_DST, result._memr_->handle().memory}
			}
		);
		internal::stream().wait();
		return result;
	}

	/**------------------------------------------------------------------------------------------------
	 *                                         Elementwise
	 *------------------------------------------------------------------------------------------------**/

	Tensor Tensor::elementwise(functions::function_id function) const
	{
		Tensor result = Tensor(shape(), type(), format());
		neural_primitives::eltwise(result, *this, function, neural_primitives::prop_kind::forward);
		return result;
	}


	Tensor& Tensor::elementwise_in_place(functions::function_id function)
	{
		neural_primitives::eltwise(_memr_->handle(), _desc_->handle(), function, neural_primitives::prop_kind::forward);
		return *this;
	}

	Tensor Tensor::elementwise_diff(functions::function_id function) const
	{
		Tensor result = Tensor(shape(), type(), format());
		result.fill(1);
		neural_primitives::eltwise_diff(result, *this, function, neural_primitives::prop_kind::backward);
		return result;
	}

	Tensor& Tensor::elementwise_diff_in_place(functions::function_id function)
	{
		neural_primitives::eltwise_diff(_memr_->handle(), _desc_->handle(), function, neural_primitives::prop_kind::forward);
		return *this;
	}

	Tensor& Tensor::fill(cumeric_t scalar)
	{
    	void* ptr = static_cast<cumeric_t*>(
			_memr_->handle().memory.get_data_handle()
		);

    	const dim_t count = _desc_->handle().desc.get_size() / sizeof(cumeric_t);

		// functions::various::fill(ptr, scalar, count);

		internal::dispatch_sycl_datatype(type(), [&]<typename T>()
		{
			internal::queue().fill(
				static_cast<T*>(ptr),
				static_cast<T>(scalar),
				lenght()
			).wait();
		});

    	runtime::sync();

    	return *this;
	}

	Tensor Tensor::multiply(const Tensor& tensor) const
    {
    	Tensor C(shape(), type(), format());

    	dnnl::binary::primitive_desc primitive_desc {
    		internal::engine(),
			dnnl::algorithm::binary_mul,
			_desc_->handle().desc,
			tensor._desc_->handle().desc,
			C._desc_->handle().desc,
		};

    	dnnl::binary(primitive_desc).execute(
			internal::stream(),
			{
				{ DNNL_ARG_SRC_0, _memr_->handle().memory },
				{ DNNL_ARG_SRC_1, tensor._memr_->handle().memory },
				{ DNNL_ARG_DST, C._memr_->handle().memory }
			}
		);

    	internal::stream().wait();
    	return C;
    }

	Tensor& Tensor::scale(cumeric_t scalar)
	{
		*this *= scalar;

		return *this;
	}

	Tensor Tensor::cwiseProduct(const Tensor& tensor) const
	{
		return this->multiply(tensor);
	}

	Tensor& Tensor::cwise_product_in_place(const Tensor& other)
	{

		dnnl::binary::primitive_desc primitive_desc {
			internal::engine(),
			dnnl::algorithm::binary_mul,
			_desc_->handle().desc,
			other._desc_->handle().desc,
			_desc_->handle().desc,
		};

		dnnl::binary(primitive_desc).execute(
			internal::stream(),
			{
				{ DNNL_ARG_SRC_0, _memr_->handle().memory },
				{ DNNL_ARG_SRC_1, other._memr_->handle().memory },
				{ DNNL_ARG_DST, _memr_->handle().memory }
			}
		);

		internal::stream().wait();
		return *this;
	}

	Tensor Tensor::sqrt() const
	{
		Tensor result = *this;

    	neural_primitives::sqrt(result._memr_->handle(), _memr_->handle(), result._desc_->handle(), _desc_->handle());

    	return result;
	}

	Tensor& Tensor::sqrt_in_place()
	{
    	neural_primitives::sqrt(_memr_->handle(), _desc_->handle());
    	return *this;
	}

	Tensor Tensor::square() const
	{
		Tensor result = *this;

    	neural_primitives::square(result._memr_->handle(), _memr_->handle(), result._desc_->handle(), _desc_->handle());

    	return result;
	}

	Tensor& Tensor::square_in_place()
	{
    	neural_primitives::square(_memr_->handle(), _desc_->handle());
    	return *this;
	}

	Tensor Tensor::abs() const
	{
		Tensor result = *this;

    	neural_primitives::abs(result._memr_->handle(), _memr_->handle(), result._desc_->handle(), _desc_->handle());

    	return result;
	}

	Tensor& Tensor::abs_in_place()
	{
    	neural_primitives::abs(_memr_->handle(), _desc_->handle());
    	return *this;
	}

	Tensor Tensor::log() const
	{
		Tensor result = *this;

		neural_primitives::log(result, *this);

		return result;
	}

	Tensor& Tensor::log_in_place()
	{
		neural_primitives::log(*this);
		return *this;
	}

	Tensor Tensor::clamp(cumeric_t min, cumeric_t max) const
	{
		Tensor result = *this;

		neural_primitives::clamp(result, *this, min, max);

		return result;
	}

	Tensor& Tensor::clamp_in_place(cumeric_t min, cumeric_t max)
	{
		neural_primitives::clamp(*this, min, max);
		return *this;
	}


	/**------------------------------------------------------------------------------------------------
	 *                                        Matrix multiplication
	 *------------------------------------------------------------------------------------------------**/

	Tensor Tensor::matmul(const Tensor& other) const
	{
		auto reversed_shape_a = this->shape() | std::views::reverse;
		auto reversed_shape_b = other.shape() | std::views::reverse;
		if (*reversed_shape_a.begin() != *std::next(reversed_shape_b.begin()))
		{
			throw std::invalid_argument("Tensor::matmul(): A cols != B rows");
		}

		Shape result_shape = this->shape();
		result_shape[this->rank() - 2] = this->rows();
		result_shape[this->rank() - 1] = other.cols();

		Tensor C(result_shape, type(), format());

		neural_primitives::matmul(C, *this, other);

		return C;
	}

	/**------------------------------------------------------------------------------------------------
	 *                                         Operator overloads
	 *------------------------------------------------------------------------------------------------**/

	Tensor operator + (const Tensor& A, const Tensor& B)
    {
    	Tensor C(A.shape(), A.type(), A.format());

	    neural_primitives::add(C, A, B);

    	internal::stream().wait();
    	return C;
    }

	Tensor operator - (const Tensor& A, const Tensor& B)
    {
    	Tensor C(A.shape(), A.type(), A.format());

		neural_primitives::sub(C, A, B);

    	internal::stream().wait();
    	return C;
    }

	Tensor operator * (const Tensor& A, const Tensor& B)
    {
		return A.matmul(B);
    }

	Tensor operator / (const Tensor& A, const Tensor& B)
    {
    	Tensor C(A.shape(), A.type(), A.format());

	    dnnl::binary::primitive_desc primitive_desc {
			internal::engine(),
	    	dnnl::algorithm::binary_div,
	    	A._desc_->handle().desc,
	    	B._desc_->handle().desc,
	    	C._desc_->handle().desc,
	    };

    	dnnl::binary(primitive_desc).execute(
    		internal::stream(),
    		{
				{ DNNL_ARG_SRC_0, A._memr_->handle().memory },
				{ DNNL_ARG_SRC_1, B._memr_->handle().memory },
				{ DNNL_ARG_DST, C._memr_->handle().memory }
    		}
    	);

    	internal::stream().wait();
    	return C;
    }

	Tensor operator + (const Tensor& tensor, cumeric_t scalar)
    {
    	Tensor C(tensor.shape(), tensor.type(), tensor.format());

    	cumeric_t* scalar_buff = memory::allocate(1);
    	scalar_buff[0] = scalar;

    	dnnl::memory::desc scalar_desc {
    		Shape(tensor.rank(), 1), dnnl_data_type(default_type),
			tensor.dims() == 1 ? dnnl::memory::format_tag::x : dnnl_format_tag(default_layout_from_rank(tensor.rank()))
    	};

    	dnnl::memory scalar_memory = dnnl::sycl_interop::make_memory(
    		scalar_desc, internal::engine(), dnnl::sycl_interop::memory_kind::usm, scalar_buff
    	);

    	dnnl::binary::primitive_desc primitive_desc {
    		internal::engine(),
			dnnl::algorithm::binary_add,
			tensor._desc_->handle().desc,
			scalar_desc,
			C._desc_->handle().desc,
		};

    	dnnl::binary(primitive_desc).execute(
			internal::stream(),
			{
				{ DNNL_ARG_SRC_0, tensor._memr_->handle().memory },
				{ DNNL_ARG_SRC_1, scalar_memory },
				{ DNNL_ARG_DST, C._memr_->handle().memory }
			}
		);

    	internal::stream().wait();
    	memory::free(scalar_buff);

    	return C;
    }

	Tensor operator + (const cumeric_t scalar, const Tensor& tensor)
    {
	    return tensor + scalar;
    }

	Tensor operator - (const Tensor& tensor, cumeric_t scalar)
    {
    	Tensor C(tensor.shape(), tensor.type(), tensor.format());

    	cumeric_t* scalar_buff = memory::allocate(1);
    	scalar_buff[0] = scalar;

    	dnnl::memory::desc scalar_desc {
    		Shape(tensor.rank(), 1), dnnl_data_type(default_type),
			tensor.dims() == 1 ? dnnl::memory::format_tag::x : dnnl_format_tag(default_layout_from_rank(tensor.rank()))
    	};

    	dnnl::memory scalar_memory = dnnl::sycl_interop::make_memory(
    		scalar_desc, internal::engine(), dnnl::sycl_interop::memory_kind::usm, scalar_buff
    	);

    	dnnl::binary::primitive_desc primitive_desc {
    		internal::engine(),
			dnnl::algorithm::binary_sub,
			tensor._desc_->handle().desc,
			scalar_desc,
			C._desc_->handle().desc,
		};

    	dnnl::binary(primitive_desc).execute(
			internal::stream(),
			{
				{ DNNL_ARG_SRC_0, tensor._memr_->handle().memory },
				{ DNNL_ARG_SRC_1, scalar_memory },
				{ DNNL_ARG_DST, C._memr_->handle().memory }
			}
		);

    	internal::stream().wait();
    	memory::free(scalar_buff);

    	return C;
    }

	Tensor operator - (const cumeric_t scalar, const Tensor& tensor)
    {
    	Tensor sex(tensor.shape(), tensor.type(), tensor.format());

    	sex.fill(scalar);

    	return sex - tensor;
    }


	Tensor operator * (const Tensor& tensor, cumeric_t scalar)
    {
    	Tensor C(tensor.shape(), tensor.type(), tensor.format());

    	cumeric_t* scalar_buff = memory::allocate(1);
    	scalar_buff[0] = scalar;

    	dnnl::memory::desc scalar_desc {
    		Shape(tensor.rank(), 1), dnnl_data_type(default_type),
			tensor.dims() == 1 ? dnnl::memory::format_tag::x : dnnl_format_tag(default_layout_from_rank(tensor.rank()))
    	};

    	dnnl::memory scalar_memory = dnnl::sycl_interop::make_memory(
    		scalar_desc, internal::engine(), dnnl::sycl_interop::memory_kind::usm, scalar_buff
    	);

    	dnnl::binary::primitive_desc primitive_desc {
    		internal::engine(),
			dnnl::algorithm::binary_mul,
			tensor._desc_->handle().desc,
			scalar_desc,
			C._desc_->handle().desc,
		};

    	dnnl::binary(primitive_desc).execute(
			internal::stream(),
			{
				{ DNNL_ARG_SRC_0, tensor._memr_->handle().memory },
				{ DNNL_ARG_SRC_1, scalar_memory },
				{ DNNL_ARG_DST, C._memr_->handle().memory }
			}
		);

    	internal::stream().wait();
    	memory::free(scalar_buff);

    	return C;
    }

	Tensor operator * (const cumeric_t scalar, const Tensor& tensor)
    {
    	return tensor * scalar;
    }

	Tensor operator / (const Tensor& tensor, cumeric_t scalar)
    {
    	Tensor result(tensor.shape(), tensor.type(), tensor.format());

    	cumeric_t* scalar_buff = memory::allocate(1);
    	scalar_buff[0] = scalar;

		neural_primitives::Descriptor scalar_descriptor(Shape(tensor.rank(), 1), tensor.type(), tensor.format());

		neural_primitives::Memory scalar_memory(scalar_descriptor, scalar_buff);

		neural_primitives::div(
			*result.memory(),
			*tensor.memory(),
			scalar_memory,
			*result.descriptor(),
			*tensor.descriptor(),
			scalar_descriptor
		);

    	memory::free(scalar_buff);

    	return result;
    }

	Tensor operator / (const cumeric_t scalar, const Tensor& tensor)
    {
    	Tensor sex(tensor.shape(), tensor.type(), tensor.format());

    	sex.fill(scalar);

    	return sex / tensor;
    }

	Tensor Tensor::operator + ()
	{
		return *this;
	}

	Tensor Tensor::operator - () const
	{
		return *this * -1;
	}

	Tensor& Tensor::operator += (const Tensor& other)
    {
	    neural_primitives::add(*_memr_, *other._memr_, *_desc_, *other._desc_);
        return *this;
    }

	Tensor& Tensor::operator -= (const Tensor& other)
    {
	    neural_primitives::sub(*_memr_, *other._memr_, *_desc_, *other._desc_);
        return *this;
    }

	Tensor& Tensor::operator *= (const Tensor& other)
    {
	    neural_primitives::mul(*_memr_, *other._memr_, *_desc_, *other._desc_);
        return *this;
    }

	Tensor& Tensor::operator /= (const Tensor& other)
    {
	    neural_primitives::div(*_memr_, *other._memr_, *_desc_, *other._desc_);
        return *this;
    }

	Tensor& Tensor::operator /= (const cumeric_t scalar)
    {
		cumeric_t* scalar_buff = memory::allocate(1);
		scalar_buff[0] = scalar;

		Descriptor scalar_descriptor(Shape(this->rank(), 1), this->type(), this->format());

		Memory scalar_memory(scalar_descriptor, scalar_buff);

		neural_primitives::div(
			*memory(),
			*this->memory(),
			scalar_memory,
			*this->descriptor(),
			*this->descriptor(),
			scalar_descriptor
		);

		memory::free(scalar_buff);

		return *this;
    }

	Tensor& Tensor::operator = (const Tensor& other)
    {
    	if(this == &other)
    		return *this;

		auto desc = std::make_unique<neural_primitives::Descriptor>(
			other.shape(), other.type(),
			concrete_layout(other.rank(), other.format()));
		void* data = sycl::malloc_shared<std::byte>(
			desc->size(), internal::device(), internal::sycl_context());
		if(data == nullptr)
			throw std::bad_alloc();

		auto memr = std::make_unique<neural_primitives::Memory>(*desc, data);
		internal::queue().memcpy(
			data,
			other.data(),
			static_cast<std::size_t>(other.size())
		).wait();

		if(_owns_data && _data != nullptr)
			sycl::free(_data, internal::sycl_context());

		_desc_ = std::move(desc);
		_memr_ = std::move(memr);
		_data = data;
		_owns_data = true;
    	return *this;
    }

	Tensor& Tensor::operator = (Tensor&& other) noexcept
	{
		if(this == &other)
			return *this;

		if(_owns_data && _data != nullptr)
			sycl::free(_data, internal::sycl_context());

		_desc_ = std::move(other._desc_);
		_memr_ = std::move(other._memr_);
		_data = other._data;
		_owns_data = other._owns_data;

		other._data = nullptr;
		other._owns_data = false;
		return *this;
	}


	bool operator != (const Tensor& A, const Tensor& B)
	{

	}

	bool operator == (const Tensor& A, const Tensor& B)
	{
		if (&A == &B)
			return true;

		if (A.type() != B.type() || A.shape() != B.shape())
			return false;

		runtime::sync(); // dane w USM mogą być jeszcze zapisywane przez kernele

		const Shape shape = A.shape();
		const dim_t rank = static_cast<dim_t>(shape.size());

		dim_t count = 1;
		for (const dim_t extent : shape)
			count *= extent;

		bool equal = true;

		internal::dispatch_sycl_datatype(A.type(), [&]<typename T>()
		{
			const T* a = static_cast<const T*>(A.data());
			const T* b = static_cast<const T*>(B.data());

			Shape indices(rank, 0);
			for (dim_t i = 0; i < count && equal; i++)
			{
				if (a[A.compute_index(indices)] != b[B.compute_index(indices)])
					equal = false;

				for (dim_t axis = rank; axis-- > 0; )
				{
					if (++indices[axis] < shape[axis])
						break;
					indices[axis] = 0;
				}
			}
		});

		return equal;
	}


} // cum
